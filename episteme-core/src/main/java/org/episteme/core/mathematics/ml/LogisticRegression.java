/*
 * Episteme - Java(TM) Tools and Libraries for the Advancement of Sciences.
 * Copyright (C) 2025-2026 - Silvere Martin-Michiellot and Gemini AI (Google DeepMind)
 *
 * Permission is hereby granted, free of charge, to any person obtaining a copy
 * of this software and associated documentation files (the "Software"), to deal
 * in the Software without restriction, including without limitation the rights
 * to use, copy, modify, merge, publish, distribute, sublicense, and/or sell
 * copies of the Software, and to permit persons to whom the Software is
 * furnished to do so, subject to the following conditions:
 *
 * The above copyright notice and this permission notice shall be included in
 * all copies or substantial portions of the Software.
 *
 * THE SOFTWARE IS PROVIDED "AS IS", WITHOUT WARRANTY OF ANY KIND, EXPRESS OR
 * IMPLIED, INCLUDING BUT NOT LIMITED TO THE WARRANTIES OF MERCHANTABILITY,
 * FITNESS FOR A PARTICULAR PURPOSE AND NONINFRINGEMENT. IN NO EVENT SHALL THE
 * AUTHORS OR COPYRIGHT HOLDERS BE LIABLE FOR ANY CLAIM, DAMAGES OR OTHER
 * LIABILITY, WHETHER IN AN ACTION OF CONTRACT, TORT OR OTHERWISE, ARISING FROM,
 * OUT OF OR IN CONNECTION WITH THE SOFTWARE OR THE USE OR OTHER DEALINGS IN THE
 * SOFTWARE.
 */

package org.episteme.core.mathematics.ml;

import org.episteme.core.mathematics.numbers.real.Real;

/**
 * Logistic Regression - binary classification using sigmoid function.
 * <p>
 * Model: P(y=1|x) = 1/(1 + e^(-wÃ‚Â·x))
 * Training: Gradient descent on log-likelihood
 * Applications: Classification, probability estimation
 * </p>
 *
 * @author Silvere Martin-Michiellot
 * @author Gemini AI (Google DeepMind)
 * @since 1.0
 */
public class LogisticRegression {

    private Real[] weights;
    private Real bias;
    private Real learningRate = Real.of(0.01);
    private int maxIterations = 1000;

    /**
     * Trains logistic regression model.
     * 
     * @param X training data (n samples Ãƒâ€” d features)
     * @param y binary labels (0 or 1)
     */
    public void fit(Real[][] X, Real[] y) {
        int n = X.length;
        int d = X[0].length;

        // Initialize weights
        weights = new Real[d];
        for (int i = 0; i < d; i++) {
            weights[i] = Real.ZERO;
        }
        bias = Real.ZERO;

        // Gradient descent
        for (int iter = 0; iter < maxIterations; iter++) {
            // Compute gradients
            Real[] gradW = new Real[d];
            for (int i = 0; i < d; i++) {
                gradW[i] = Real.ZERO;
            }
            Real gradB = Real.ZERO;

            for (int i = 0; i < n; i++) {
                // Prediction
                Real z = bias;
                for (int j = 0; j < d; j++) {
                    z = z.add(weights[j].multiply(X[i][j]));
                }
                Real pred = sigmoid(z);

                // Error
                Real error = pred.subtract(y[i]);

                // Accumulate gradients
                gradB = gradB.add(error);
                for (int j = 0; j < d; j++) {
                    gradW[j] = gradW[j].add(error.multiply(X[i][j]));
                }
            }

            // Update weights
            for (int j = 0; j < d; j++) {
                weights[j] = weights[j].subtract(
                        learningRate.multiply(gradW[j]).divide(Real.of(n)));
            }
            bias = bias.subtract(learningRate.multiply(gradB).divide(Real.of(n)));

            // Optional: compute loss for monitoring
            if (iter % 100 == 0) {
                @SuppressWarnings("unused")
                Real loss = computeLoss(X, y);
                // Loss computed for monitoring purposes (can be logged if needed)
            }
        }
    }

    /**
     * Predicts probability P(y=1|x).
     */
    public Real predictProba(Real[] x) {
        Real z = bias;
        for (int i = 0; i < weights.length; i++) {
            z = z.add(weights[i].multiply(x[i]));
        }
        return sigmoid(z);
    }

    /**
     * Predicts class (0 or 1) using threshold 0.5.
     */
    public Real predict(Real[] x) {
        Real proba = predictProba(x);
        return proba.compareTo(Real.of(0.5)) >= 0 ? Real.ONE : Real.ZERO;
    }

    /**
     * Sigmoid function: ÃÆ’(z) = 1/(1 + e^(-z))
     */
    private Real sigmoid(Real z) {
        // ÃÆ’(z) = 1 / (1 + exp(-z))
        Real expNegZ = Real.of(Math.exp(-z.doubleValue()));
        return Real.ONE.divide(Real.ONE.add(expNegZ));
    }

    /**
     * Computes log-loss (cross-entropy).
     * <p>
     * Loss = -1/n ÃŽÂ£ [y log(Ã…Â·) + (1-y) log(1-Ã…Â·)]
     * </p>
     */
    private Real computeLoss(Real[][] X, Real[] y) {
        Real loss = Real.ZERO;
        int n = X.length;

        for (int i = 0; i < n; i++) {
            Real pred = predictProba(X[i]);

            // Avoid log(0)
            Real epsilon = Real.of(1e-15);
            pred = max(min(pred, Real.ONE.subtract(epsilon)), epsilon);

            Real term1 = y[i].multiply(pred.log());
            Real term2 = Real.ONE.subtract(y[i]).multiply(Real.ONE.subtract(pred).log());
            loss = loss.add(term1.add(term2));
        }

        return loss.negate().divide(Real.of(n));
    }

    /**
     * Computes accuracy on test set.
     */
    public Real score(Real[][] X, Real[] y) {
        int n = X.length;
        int correct = 0;

        for (int i = 0; i < n; i++) {
            Real pred = predict(X[i]);
            if (pred.equals(y[i])) {
                correct++;
            }
        }

        return Real.of(correct).divide(Real.of(n));
    }

    /**
     * L2 regularization (Ridge): adds ÃŽÂ»||w||Ã‚Â² to loss.
     */
    public void fitWithRegularization(Real[][] X, Real[] y, Real lambda) {
        int n = X.length;
        int d = X[0].length;

        weights = new Real[d];
        for (int i = 0; i < d; i++) {
            weights[i] = Real.ZERO;
        }
        bias = Real.ZERO;

        for (int iter = 0; iter < maxIterations; iter++) {
            Real[] gradW = new Real[d];
            for (int i = 0; i < d; i++) {
                gradW[i] = Real.ZERO;
            }
            Real gradB = Real.ZERO;

            // Data term
            for (int i = 0; i < n; i++) {
                Real z = bias;
                for (int j = 0; j < d; j++) {
                    z = z.add(weights[j].multiply(X[i][j]));
                }
                Real pred = sigmoid(z);
                Real error = pred.subtract(y[i]);

                gradB = gradB.add(error);
                for (int j = 0; j < d; j++) {
                    gradW[j] = gradW[j].add(error.multiply(X[i][j]));
                }
            }

            // Regularization term (not for bias)
            for (int j = 0; j < d; j++) {
                gradW[j] = gradW[j].add(lambda.multiply(weights[j]));
            }

            // Update
            for (int j = 0; j < d; j++) {
                weights[j] = weights[j].subtract(
                        learningRate.multiply(gradW[j]).divide(Real.of(n)));
            }
            bias = bias.subtract(learningRate.multiply(gradB).divide(Real.of(n)));
        }
    }

    // Setters
    public void setLearningRate(Real lr) {
        this.learningRate = lr;
    }

    public void setMaxIterations(int iter) {
        this.maxIterations = iter;
    }

    public Real[] getWeights() {
        return weights;
    }

    public Real getBias() {
        return bias;
    }

    private Real min(Real a, Real b) {
        return a.compareTo(b) < 0 ? a : b;
    }

    private Real max(Real a, Real b) {
        return a.compareTo(b) > 0 ? a : b;
    }
}



