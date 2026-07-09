---
title: "Logistic Regression"
slug: "logistic-regression"
description: "Derive logistic regression via Bernoulli MLE, implement gradient descent and Newton-Raphson (IRLS), interpret coefficients as log-odds ratios, calibrate probabilities with Platt scaling, and extend to multinomial via softmax."
tags: ["supervised-learning", "classical-ml"]
topic: "classical-ml"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"Logistic regression models the probability of a binary outcome by passing a linear function through the sigmoid: P(y=1|x) = σ(θᵀx) = 1/(1+e^{−θᵀx}). Unlike linear regression, it outputs valid probabilities in [0,1] and its decision boundary is linear in feature space. Despite its simplicity, logistic regression remains one of the most widely deployed classifiers in medicine, finance, and industry because its coefficients are directly interpretable as log-odds ratios."},{"type":"heading","level":2,"content":"The Sigmoid Function and Logit Link"},{"type":"text","content":"The sigmoid σ(z) = 1/(1+e^{−z}) maps ℝ → (0,1) with σ(0)=0.5 and gradient σ\u0027(z) = σ(z)(1−σ(z)). The logit (log-odds) is its inverse: logit(p) = log(p/(1−p)) = θᵀx. This is the canonical link function for the Bernoulli GLM. The odds ratio P(y=1)/P(y=0) = e^{θᵀx}, so each unit increase in feature j multiplies the odds by e^{θⱼ}. The decision boundary P(y=1|x) = 0.5 ⟺ θᵀx = 0, which is a hyperplane in feature space."},{"type":"heading","level":2,"content":"Maximum Likelihood Estimation"},{"type":"text","content":"Assuming y_i ~ Bernoulli(σ(θᵀxᵢ)), the log-likelihood is ℓ(θ) = Σ [yᵢ log σ(θᵀxᵢ) + (1−yᵢ) log(1−σ(θᵀxᵢ))]. This equals the negative cross-entropy loss. ℓ(θ) is concave in θ, so any local maximum is global. The gradient is ∂ℓ/∂θ = Xᵀ(y − ŷ) where ŷᵢ = σ(θᵀxᵢ). There is no closed form for the MLE because σ is nonlinear — iterative methods (gradient ascent, Newton-Raphson) are required."},{"type":"code","language":"python","content":"import numpy as np\nfrom sklearn.datasets import make_classification\n\ndef sigmoid(z):\n    return 1.0 / (1.0 + np.exp(-np.clip(z, -250, 250)))\n\ndef logistic_gd(X, y, lr=0.1, n_iter=1000, tol=1e-6):\n    n, p = X.shape\n    X_b = np.hstack([np.ones((n, 1)), X])\n    theta = np.zeros(X_b.shape[1])\n    for i in range(n_iter):\n        y_hat = sigmoid(X_b @ theta)\n        grad = X_b.T @ (y - y_hat)     # gradient of log-likelihood\n        theta += lr * grad\n        if np.linalg.norm(grad) \u003c tol:\n            print(f\u0027Converged at iteration {i}\u0027)\n            break\n    return theta\n\nnp.random.seed(42)\nX, y = make_classification(n_samples=300, n_features=4,\n                             n_informative=3, random_state=42)\ntheta = logistic_gd(X, y, lr=0.05, n_iter=2000)\n\nX_b = np.hstack([np.ones((len(X), 1)), X])\nacc = ((sigmoid(X_b @ theta) \u003e= 0.5) == y).mean()\nprint(f\u0027Intercept: {theta[0]:.4f}\u0027)\nprint(f\u0027Coefficients: {np.round(theta[1:], 4)}\u0027)\nprint(f\u0027Training accuracy: {acc:.4f}\u0027)"},{"type":"heading","level":2,"content":"Newton-Raphson and IRLS"},{"type":"text","content":"Newton-Raphson updates θ using the Hessian: θ ← θ − H⁻¹∇ℓ. For logistic regression, the Hessian is H = −XᵀWX where W = diag(ŷᵢ(1−ŷᵢ)) is the weight matrix. This is the Iteratively Reweighted Least Squares (IRLS) algorithm: at each step, solve a weighted least-squares problem. Newton-Raphson converges quadratically near the optimum (typically 5–10 iterations vs hundreds for gradient descent) but requires O(p³) per step for the matrix inverse."},{"type":"code","language":"python","content":"import numpy as np\nfrom sklearn.datasets import make_classification\nfrom sklearn.linear_model import LogisticRegression\n\ndef sigmoid(z):\n    return 1.0 / (1.0 + np.exp(-np.clip(z, -250, 250)))\n\ndef irls(X, y, n_iter=20, tol=1e-8):\n    n, p = X.shape\n    X_b = np.hstack([np.ones((n, 1)), X])\n    theta = np.zeros(X_b.shape[1])\n    for i in range(n_iter):\n        y_hat = sigmoid(X_b @ theta)\n        W = y_hat * (1 - y_hat)                  # Bernoulli weights\n        grad = X_b.T @ (y - y_hat)               # gradient\n        H = -(X_b.T * W) @ X_b                   # Hessian\n        step = np.linalg.solve(-H, grad)          # Newton step\n        theta += step\n        if np.linalg.norm(grad) \u003c tol:\n            print(f\u0027IRLS converged at step {i+1}\u0027)\n            break\n    return theta\n\nnp.random.seed(42)\nX, y = make_classification(n_samples=300, n_features=4,\n                             n_informative=3, random_state=42)\ntheta_irls = irls(X, y)\nlr_ref = LogisticRegression(C=1e6, solver=\u0027lbfgs\u0027, max_iter=1000).fit(X, y)\nprint(\u0027IRLS coefs:   \u0027, np.round(theta_irls[1:], 4))\nprint(\u0027sklearn coefs:\u0027, np.round(lr_ref.coef_[0], 4))\nprint(\u0027Max diff: {:.2e}\u0027.format(np.abs(theta_irls[1:] - lr_ref.coef_[0]).max()))"},{"type":"heading","level":2,"content":"Coefficient Interpretation and Confidence Intervals"},{"type":"text","content":"The coefficient θⱼ represents the change in log-odds per unit increase in feature j, holding all others fixed. The odds ratio for feature j is e^{θⱼ}: if θⱼ = 0.5, a one-unit increase multiplies the odds of the positive class by e^{0.5} ≈ 1.65. Approximate 95% confidence intervals for θⱼ use the diagonal of the inverse Fisher information matrix (−H)⁻¹, giving θⱼ ± 1.96 × SE_j, which maps to CI on the odds ratio by exponentiating."},{"type":"code","language":"python","content":"import numpy as np\nfrom sklearn.datasets import load_breast_cancer\nfrom sklearn.linear_model import LogisticRegression\nfrom sklearn.preprocessing import StandardScaler\n\ndata = load_breast_cancer()\nX = StandardScaler().fit_transform(data.data[:, :6])\ny = data.target\nfeature_names = data.feature_names[:6]\n\nlr = LogisticRegression(C=1.0, solver=\u0027lbfgs\u0027, max_iter=1000).fit(X, y)\ncoefs = lr.coef_[0]\n\n# Fisher information-based SEs\nfrom sklearn.linear_model import LogisticRegression\nX_b = np.hstack([np.ones((len(X), 1)), X])\ny_hat = lr.predict_proba(X)[:, 1]\nW = y_hat * (1 - y_hat)\nH_inv = np.linalg.inv((X_b.T * W) @ X_b)\nSEs = np.sqrt(np.diag(H_inv))[1:]  # skip intercept SE\n\nprint(f\u0027{\"Feature\":\u003e30} {\"Coef\":\u003e8} {\"OR\":\u003e8} {\"95% CI\"}\u0027 )\nfor name, coef, se in zip(feature_names, coefs, SEs):\n    lo = np.exp(coef - 1.96 * se)\n    hi = np.exp(coef + 1.96 * se)\n    print(f\u0027{name:\u003e30} {coef:\u003e8.3f} {np.exp(coef):\u003e8.3f}  [{lo:.3f}, {hi:.3f}]\u0027)"},{"type":"heading","level":2,"content":"Calibration and Platt Scaling"},{"type":"text","content":"A model is well-calibrated if among all predictions ŷ ≈ 0.7, roughly 70% of true labels are positive. Reliability diagrams (calibration curves) plot mean predicted probability against observed positive rate across bins. Logistic regression is generally well-calibrated for in-distribution data. Platt scaling post-hoc fits a logistic regression on the model\u0027s raw scores using a held-out calibration set, mapping uncalibrated probabilities to calibrated ones."},{"type":"callout","variant":"info","title":"Calibration Matters in Production","content":"Even if a model has high AUC, poorly calibrated probabilities cause downstream failures: risk scores, expected-value decisions, and threshold tuning all require reliable probability estimates. Always plot a reliability diagram before deploying any probability-outputting model. Use isotonic regression (nonparametric) or Platt scaling (parametric) to recalibrate."},{"type":"code","language":"python","content":"import numpy as np\nfrom sklearn.datasets import make_classification\nfrom sklearn.linear_model import LogisticRegression\nfrom sklearn.calibration import CalibratedClassifierCV, calibration_curve\nfrom sklearn.model_selection import train_test_split\nfrom sklearn.svm import SVC\n\nnp.random.seed(42)\nX, y = make_classification(n_samples=2000, n_features=10,\n                             n_informative=5, random_state=42)\nX_tr, X_te, y_tr, y_te = train_test_split(X, y, test_size=0.4, random_state=42)\n\n# Uncalibrated SVM (decision-function scores, not probabilities)\nsvm = SVC(kernel=\u0027rbf\u0027, probability=False).fit(X_tr, y_tr)\n\n# Platt scaling via CalibratedClassifierCV\nplatt_svm = CalibratedClassifierCV(SVC(kernel=\u0027rbf\u0027), method=\u0027sigmoid\u0027, cv=5)\nplatt_svm.fit(X_tr, y_tr)\n\nlr_cal = LogisticRegression(max_iter=1000).fit(X_tr, y_tr)\n\nfor name, proba_fn in [(\u0027LR (reference)\u0027, lr_cal.predict_proba(X_te)[:, 1]),\n                        (\u0027SVM+Platt\u0027, platt_svm.predict_proba(X_te)[:, 1])]:\n    frac_pos, mean_pred = calibration_curve(y_te, proba_fn, n_bins=10)\n    cal_err = np.mean(np.abs(frac_pos - mean_pred))\n    print(f\u0027{name}: mean calibration error = {cal_err:.4f}\u0027)"},{"type":"heading","level":2,"content":"Multinomial Logistic Regression"},{"type":"text","content":"For K \u003e 2 classes, the softmax function generalises the sigmoid: P(y=k|x) = e^{θₖᵀx} / Σⱼ e^{θⱼᵀx}. One class is typically chosen as the reference (its weights are zero) for identifiability, reducing to K−1 independent sets of parameters. The log-likelihood is the negative categorical cross-entropy. Gradient and Newton updates extend analogously. Multi-label classification (multiple binary labels simultaneously) is solved by K independent binary logistic models."},{"type":"table","headers":["Link Function","Distribution","Range","Use Case"],"rows":[["Sigmoid: 1/(1+e^{-z})","Bernoulli","(0,1)","Binary classification"],["Softmax: e^{zk}/Σe^{zj}","Categorical/Multinomial","(0,1) summing to 1","Multiclass classification"],["Identity: z","Gaussian","(-∞,+∞)","Regression (OLS)"],["Log: e^z (or log link)","Poisson","(0,+∞)","Count data, Poisson regression"],["Probit: Φ(z)","Bernoulli","(0,1)","Binary, Gaussian latent variable interpretation"]]},{"type":"heading","level":2,"content":"Regularisation in Logistic Regression"},{"type":"text","content":"Without regularisation, logistic regression can overfit (especially with many features or perfectly separable data — the MLE is undefined for separable data since loss approaches zero only at ‖θ‖→∞). L2 regularisation (C=1/λ in sklearn) adds −λ‖θ‖² to the log-likelihood, shrinking all coefficients. L1 regularisation promotes sparsity — useful for feature selection with high-dimensional data. sklearn uses the \u0027saga\u0027 solver for both L1 and ElasticNet regularised logistic regression at scale."},{"type":"list","ordered":false,"items":["L2 (Ridge, default): adds −λ‖θ‖² term; all coefficients shrink but remain nonzero; always converges.","L1 (Lasso): promotes exact zeros; useful for high-dimensional data with many irrelevant features.","ElasticNet: L1+L2 combination; handles correlated features better than pure L1.","Perfectly separable data: L2/L1 regularisation is required to prevent divergence of MLE.","Multiclass: use \u0027multinomial\u0027 with \u0027lbfgs\u0027 or \u0027saga\u0027 solver; avoids one-vs-rest approximation.","Calibration: logistic regression is well-calibrated by default; SVMs and tree models typically need Platt scaling."]},{"type":"divider"}]"
---
# Logistic Regression

Logistic regression models the probability of a binary outcome by passing a linear function through the sigmoid: P(y=1|x) = σ(θᵀx) = 1/(1+e^{−θᵀx}). Unlike linear regression, it outputs valid probabilities in [0,1] and its decision boundary is linear in feature space. Despite its simplicity, logistic regression remains one of the most widely deployed classifiers in medicine, finance, and industry because its coefficients are directly interpretable as log-odds ratios.

## The Sigmoid Function and Logit Link

The sigmoid σ(z) = 1/(1+e^{−z}) maps ℝ → (0,1) with σ(0)=0.5 and gradient σ'(z) = σ(z)(1−σ(z)). The logit (log-odds) is its inverse: logit(p) = log(p/(1−p)) = θᵀx. This is the canonical link function for the Bernoulli GLM. The odds ratio P(y=1)/P(y=0) = e^{θᵀx}, so each unit increase in feature j multiplies the odds by e^{θⱼ}. The decision boundary P(y=1|x) = 0.5 ⟺ θᵀx = 0, which is a hyperplane in feature space.

## Maximum Likelihood Estimation

Assuming y_i ~ Bernoulli(σ(θᵀxᵢ)), the log-likelihood is ℓ(θ) = Σ [yᵢ log σ(θᵀxᵢ) + (1−yᵢ) log(1−σ(θᵀxᵢ))]. This equals the negative cross-entropy loss. ℓ(θ) is concave in θ, so any local maximum is global. The gradient is ∂ℓ/∂θ = Xᵀ(y − ŷ) where ŷᵢ = σ(θᵀxᵢ). There is no closed form for the MLE because σ is nonlinear — iterative methods (gradient ascent, Newton-Raphson) are required.

```python
import numpy as np
from sklearn.datasets import make_classification

def sigmoid(z):
    return 1.0 / (1.0 + np.exp(-np.clip(z, -250, 250)))

def logistic_gd(X, y, lr=0.1, n_iter=1000, tol=1e-6):
    n, p = X.shape
    X_b = np.hstack([np.ones((n, 1)), X])
    theta = np.zeros(X_b.shape[1])
    for i in range(n_iter):
        y_hat = sigmoid(X_b @ theta)
        grad = X_b.T @ (y - y_hat)     # gradient of log-likelihood
        theta += lr * grad
        if np.linalg.norm(grad) < tol:
            print(f'Converged at iteration {i}')
            break
    return theta

np.random.seed(42)
X, y = make_classification(n_samples=300, n_features=4,
                             n_informative=3, random_state=42)
theta = logistic_gd(X, y, lr=0.05, n_iter=2000)

X_b = np.hstack([np.ones((len(X), 1)), X])
acc = ((sigmoid(X_b @ theta) >= 0.5) == y).mean()
print(f'Intercept: {theta[0]:.4f}')
print(f'Coefficients: {np.round(theta[1:], 4)}')
print(f'Training accuracy: {acc:.4f}')
```

## Newton-Raphson and IRLS

Newton-Raphson updates θ using the Hessian: θ ← θ − H⁻¹∇ℓ. For logistic regression, the Hessian is H = −XᵀWX where W = diag(ŷᵢ(1−ŷᵢ)) is the weight matrix. This is the Iteratively Reweighted Least Squares (IRLS) algorithm: at each step, solve a weighted least-squares problem. Newton-Raphson converges quadratically near the optimum (typically 5–10 iterations vs hundreds for gradient descent) but requires O(p³) per step for the matrix inverse.

```python
import numpy as np
from sklearn.datasets import make_classification
from sklearn.linear_model import LogisticRegression

def sigmoid(z):
    return 1.0 / (1.0 + np.exp(-np.clip(z, -250, 250)))

def irls(X, y, n_iter=20, tol=1e-8):
    n, p = X.shape
    X_b = np.hstack([np.ones((n, 1)), X])
    theta = np.zeros(X_b.shape[1])
    for i in range(n_iter):
        y_hat = sigmoid(X_b @ theta)
        W = y_hat * (1 - y_hat)                  # Bernoulli weights
        grad = X_b.T @ (y - y_hat)               # gradient
        H = -(X_b.T * W) @ X_b                   # Hessian
        step = np.linalg.solve(-H, grad)          # Newton step
        theta += step
        if np.linalg.norm(grad) < tol:
            print(f'IRLS converged at step {i+1}')
            break
    return theta

np.random.seed(42)
X, y = make_classification(n_samples=300, n_features=4,
                             n_informative=3, random_state=42)
theta_irls = irls(X, y)
lr_ref = LogisticRegression(C=1e6, solver='lbfgs', max_iter=1000).fit(X, y)
print('IRLS coefs:   ', np.round(theta_irls[1:], 4))
print('sklearn coefs:', np.round(lr_ref.coef_[0], 4))
print('Max diff: {:.2e}'.format(np.abs(theta_irls[1:] - lr_ref.coef_[0]).max()))
```

## Coefficient Interpretation and Confidence Intervals

The coefficient θⱼ represents the change in log-odds per unit increase in feature j, holding all others fixed. The odds ratio for feature j is e^{θⱼ}: if θⱼ = 0.5, a one-unit increase multiplies the odds of the positive class by e^{0.5} ≈ 1.65. Approximate 95% confidence intervals for θⱼ use the diagonal of the inverse Fisher information matrix (−H)⁻¹, giving θⱼ ± 1.96 × SE_j, which maps to CI on the odds ratio by exponentiating.

```python
import numpy as np
from sklearn.datasets import load_breast_cancer
from sklearn.linear_model import LogisticRegression
from sklearn.preprocessing import StandardScaler

data = load_breast_cancer()
X = StandardScaler().fit_transform(data.data[:, :6])
y = data.target
feature_names = data.feature_names[:6]

lr = LogisticRegression(C=1.0, solver='lbfgs', max_iter=1000).fit(X, y)
coefs = lr.coef_[0]

# Fisher information-based SEs
from sklearn.linear_model import LogisticRegression
X_b = np.hstack([np.ones((len(X), 1)), X])
y_hat = lr.predict_proba(X)[:, 1]
W = y_hat * (1 - y_hat)
H_inv = np.linalg.inv((X_b.T * W) @ X_b)
SEs = np.sqrt(np.diag(H_inv))[1:]  # skip intercept SE

print(f'{"Feature":>30} {"Coef":>8} {"OR":>8} {"95% CI"}' )
for name, coef, se in zip(feature_names, coefs, SEs):
    lo = np.exp(coef - 1.96 * se)
    hi = np.exp(coef + 1.96 * se)
    print(f'{name:>30} {coef:>8.3f} {np.exp(coef):>8.3f}  [{lo:.3f}, {hi:.3f}]')
```

## Calibration and Platt Scaling

A model is well-calibrated if among all predictions ŷ ≈ 0.7, roughly 70% of true labels are positive. Reliability diagrams (calibration curves) plot mean predicted probability against observed positive rate across bins. Logistic regression is generally well-calibrated for in-distribution data. Platt scaling post-hoc fits a logistic regression on the model's raw scores using a held-out calibration set, mapping uncalibrated probabilities to calibrated ones.

> **Calibration Matters in Production**: Even if a model has high AUC, poorly calibrated probabilities cause downstream failures: risk scores, expected-value decisions, and threshold tuning all require reliable probability estimates. Always plot a reliability diagram before deploying any probability-outputting model. Use isotonic regression (nonparametric) or Platt scaling (parametric) to recalibrate.

```python
import numpy as np
from sklearn.datasets import make_classification
from sklearn.linear_model import LogisticRegression
from sklearn.calibration import CalibratedClassifierCV, calibration_curve
from sklearn.model_selection import train_test_split
from sklearn.svm import SVC

np.random.seed(42)
X, y = make_classification(n_samples=2000, n_features=10,
                             n_informative=5, random_state=42)
X_tr, X_te, y_tr, y_te = train_test_split(X, y, test_size=0.4, random_state=42)

# Uncalibrated SVM (decision-function scores, not probabilities)
svm = SVC(kernel='rbf', probability=False).fit(X_tr, y_tr)

# Platt scaling via CalibratedClassifierCV
platt_svm = CalibratedClassifierCV(SVC(kernel='rbf'), method='sigmoid', cv=5)
platt_svm.fit(X_tr, y_tr)

lr_cal = LogisticRegression(max_iter=1000).fit(X_tr, y_tr)

for name, proba_fn in [('LR (reference)', lr_cal.predict_proba(X_te)[:, 1]),
                        ('SVM+Platt', platt_svm.predict_proba(X_te)[:, 1])]:
    frac_pos, mean_pred = calibration_curve(y_te, proba_fn, n_bins=10)
    cal_err = np.mean(np.abs(frac_pos - mean_pred))
    print(f'{name}: mean calibration error = {cal_err:.4f}')
```

## Multinomial Logistic Regression

For K > 2 classes, the softmax function generalises the sigmoid: P(y=k|x) = e^{θₖᵀx} / Σⱼ e^{θⱼᵀx}. One class is typically chosen as the reference (its weights are zero) for identifiability, reducing to K−1 independent sets of parameters. The log-likelihood is the negative categorical cross-entropy. Gradient and Newton updates extend analogously. Multi-label classification (multiple binary labels simultaneously) is solved by K independent binary logistic models.

| Link Function | Distribution | Range | Use Case |
| --- | --- | --- | --- |
| Sigmoid: 1/(1+e^{-z}) | Bernoulli | (0,1) | Binary classification |
| Softmax: e^{zk}/Σe^{zj} | Categorical/Multinomial | (0,1) summing to 1 | Multiclass classification |
| Identity: z | Gaussian | (-∞,+∞) | Regression (OLS) |
| Log: e^z (or log link) | Poisson | (0,+∞) | Count data, Poisson regression |
| Probit: Φ(z) | Bernoulli | (0,1) | Binary, Gaussian latent variable interpretation |

## Regularisation in Logistic Regression

Without regularisation, logistic regression can overfit (especially with many features or perfectly separable data — the MLE is undefined for separable data since loss approaches zero only at ‖θ‖→∞). L2 regularisation (C=1/λ in sklearn) adds −λ‖θ‖² to the log-likelihood, shrinking all coefficients. L1 regularisation promotes sparsity — useful for feature selection with high-dimensional data. sklearn uses the 'saga' solver for both L1 and ElasticNet regularised logistic regression at scale.

- L2 (Ridge, default): adds −λ‖θ‖² term; all coefficients shrink but remain nonzero; always converges.
- L1 (Lasso): promotes exact zeros; useful for high-dimensional data with many irrelevant features.
- ElasticNet: L1+L2 combination; handles correlated features better than pure L1.
- Perfectly separable data: L2/L1 regularisation is required to prevent divergence of MLE.
- Multiclass: use 'multinomial' with 'lbfgs' or 'saga' solver; avoids one-vs-rest approximation.
- Calibration: logistic regression is well-calibrated by default; SVMs and tree models typically need Platt scaling.

---

