---
title: "Bias-Variance Tradeoff"
slug: "bias-variance-tradeoff"
description: "Derive the bias-variance decomposition of expected test error, visualise the U-shaped error curve, demonstrate double descent in overparameterised models, and show how bagging and boosting each address one side of the tradeoff."
tags: ["supervised-learning", "classical-ml"]
topic: "classical-ml"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"Every supervised learning model makes an error that can be decomposed into three orthogonal components: bias (systematic error from model assumptions), variance (sensitivity to the specific training set drawn), and irreducible noise (inherent randomness in the data-generating process). Understanding this decomposition explains why simple models underfit, complex models overfit, and how regularisation, ensembles, and larger datasets help — each targeting a different component."},{"type":"heading","level":2,"content":"Deriving the Bias-Variance Decomposition"},{"type":"text","content":"Let f(x) be the true function, ŷ(x) the model prediction (a random variable over training sets), and ε ~ N(0,σ²) irreducible noise. The expected squared error at a point x decomposes as: E[(y − ŷ)²] = E[(f(x) + ε − ŷ)²]. Add and subtract E[ŷ]: = E[(f(x) − E[ŷ])²] + E[(E[ŷ] − ŷ)²] + σ² = Bias²(ŷ) + Var(ŷ) + σ². The cross terms vanish because ε is independent of ŷ and E[ε]=0."},{"type":"text","content":"Bias = E[ŷ] − f(x) is the average difference between model predictions and the true function — it is zero for a model flexible enough to represent f exactly. Variance = E[(ŷ − E[ŷ])²] measures how much the model fluctuates across different training sets of the same size. A high-capacity model (deep tree, high-degree polynomial) fits each training set closely: low bias, high variance. A simple model (constant, linear with few features): high bias, low variance."},{"type":"heading","level":2,"content":"Simulating the Decomposition via Bootstrap"},{"type":"text","content":"To empirically estimate bias and variance, repeatedly draw B training sets from the same distribution, train the model on each, and evaluate on a fixed test set. The average prediction over B models estimates E[ŷ]; the variance of predictions estimates Var(ŷ); the squared gap between the average prediction and the true function estimates Bias². This is computationally intensive but gives exact empirical estimates for any model class."},{"type":"code","language":"python","content":"import numpy as np\nfrom sklearn.tree import DecisionTreeRegressor\n\ndef bias_variance_decomp(max_depth, n_bootstraps=200, n_train=60,\n                          n_test=400, noise=0.5, seed=0):\n    rng = np.random.RandomState(seed)\n    X_test = np.linspace(-3, 3, n_test).reshape(-1, 1)\n    f_true = np.sin(X_test).ravel()\n    preds = np.zeros((n_bootstraps, n_test))\n    for b in range(n_bootstraps):\n        X_tr = rng.uniform(-3, 3, n_train).reshape(-1, 1)\n        y_tr = np.sin(X_tr).ravel() + rng.randn(n_train) * noise\n        model = DecisionTreeRegressor(max_depth=max_depth)\n        model.fit(X_tr, y_tr)\n        preds[b] = model.predict(X_test)\n    mean_pred = preds.mean(axis=0)\n    bias_sq  = np.mean((mean_pred - f_true) ** 2)\n    variance  = np.mean(preds.var(axis=0))\n    noise_sq  = noise ** 2\n    return bias_sq, variance, noise_sq\n\nprint(f\u0027{\"Depth\":\u003e6} {\"Bias^2\":\u003e8} {\"Var\":\u003e8} {\"Noise\":\u003e8} {\"Total\":\u003e8}\u0027)\nfor depth in [1, 2, 4, 8, 16]:\n    b2, v, n = bias_variance_decomp(depth)\n    print(f\u0027{depth:\u003e6} {b2:\u003e8.4f} {v:\u003e8.4f} {n:\u003e8.4f} {b2+v+n:\u003e8.4f}\u0027)"},{"type":"heading","level":2,"content":"Test Error Curve vs Model Complexity"},{"type":"text","content":"As model complexity increases (e.g., polynomial degree, tree depth, network width), training error monotonically decreases while test error follows a U-shape: high (underfitting) for simple models, minimum at optimal complexity, rising again (overfitting) for complex models. The gap between training and test error is approximately 2 × Variance / n for many model classes. Cross-validation estimates the test error curve without requiring a holdout set."},{"type":"code","language":"python","content":"import numpy as np\nfrom sklearn.pipeline import Pipeline\nfrom sklearn.preprocessing import PolynomialFeatures\nfrom sklearn.linear_model import LinearRegression\nfrom sklearn.model_selection import cross_val_score\n\nnp.random.seed(0)\nX = np.random.uniform(-3, 3, 120).reshape(-1, 1)\ny = np.sin(X).ravel() + 0.4 * np.random.randn(120)\n\ndegrees = range(1, 16)\ntrain_errs, cv_errs = [], []\nfor d in degrees:\n    pipe = Pipeline([\n        (\u0027poly\u0027, PolynomialFeatures(degree=d, include_bias=False)),\n        (\u0027lr\u0027,   LinearRegression())\n    ])\n    cv_scores = cross_val_score(\n        pipe, X, y, cv=5, scoring=\u0027neg_mean_squared_error\u0027\n    )\n    pipe.fit(X, y)\n    train_errs.append(np.mean((y - pipe.predict(X))**2))\n    cv_errs.append(-cv_scores.mean())\n\nbest_d = list(degrees)[np.argmin(cv_errs)]\nprint(f\u0027{\"Deg\":\u003e4} {\"Train MSE\":\u003e10} {\"CV MSE\":\u003e10}\u0027)\nfor d, tr, cv in zip(degrees, train_errs, cv_errs):\n    marker = \u0027 \u003c-- best\u0027 if d == best_d else \u0027\u0027\n    print(f\u0027{d:\u003e4} {tr:\u003e10.4f} {cv:\u003e10.4f}{marker}\u0027)"},{"type":"heading","level":2,"content":"Double Descent Phenomenon"},{"type":"text","content":"Classical statistical learning theory predicts a U-shaped bias-variance tradeoff. But modern overparameterised models (deep networks, random features, kernel machines) exhibit double descent: test error rises near the interpolation threshold (where model capacity ≈ n) and then decreases again as capacity continues to grow. The minimum-norm interpolating solution in the overparameterised regime implicitly regularises, achieving low variance despite zero training error."},{"type":"callout","variant":"info","title":"Why Double Descent Happens","content":"Near the interpolation threshold the model barely fits the data — small perturbations cause large coefficient swings (high variance). Beyond the threshold there are many solutions that fit perfectly; gradient descent or pseudoinverse selects the minimum-norm one, which is smooth and generalises well. This breaks the classical U-curve and challenges the bias-variance framing for modern models."},{"type":"code","language":"python","content":"import numpy as np\n\nnp.random.seed(42)\nn_train = 50\nrng = np.random.RandomState(42)\nX_full = rng.randn(n_train, 300)\ny_train = rng.randn(n_train)          # pure noise — no true signal\nX_test  = rng.randn(500, 300)\ny_test  = rng.randn(500)\n\np_values = list(range(5, 300, 5))\ntest_mse = []\nfor p in p_values:\n    Xtr = X_full[:, :p]\n    Xte = X_test[:, :p]\n    # Minimum-norm (pseudoinverse) solution\n    coef, _, _, _ = np.linalg.lstsq(Xtr, y_train, rcond=None)\n    pred = Xte @ coef\n    test_mse.append(np.mean((y_test - pred)**2))\n\npeak_p = p_values[int(np.argmax(test_mse))]\nprint(f\u0027Interpolation threshold n = {n_train}\u0027)\nprint(f\u0027Peak test MSE at p = {peak_p}: {max(test_mse):.2f}\u0027)\nprint(f\u0027Test MSE at p=5:   {test_mse[0]:.4f}\u0027)\nprint(f\u0027Test MSE at p=295: {test_mse[-1]:.4f}\u0027)\nprint(\u0027MSE rises near n=p, then falls again as p \u003e\u003e n (double descent).\u0027)"},{"type":"heading","level":2,"content":"Regularisation and Ensembles"},{"type":"text","content":"Regularisation (L1, L2, dropout, early stopping) adds bias to reduce variance — trading a slightly wrong answer for a much more stable one. Bagging (Bootstrap AGGregating) averages predictions over B models trained on bootstrap samples, reducing variance by ~1/B without increasing bias. Boosting fits models sequentially on residuals, reducing bias at the cost of some variance. Random forests combine bagging with feature randomisation for additional variance reduction."},{"type":"code","language":"python","content":"import numpy as np\nfrom sklearn.tree import DecisionTreeRegressor\n\nrng = np.random.RandomState(0)\nn_train, n_test = 60, 300\nn_bags, n_bootstraps = 50, 100\nX_test = np.linspace(-3, 3, n_test).reshape(-1, 1)\nf_true = np.sin(X_test).ravel()\nnoise = 0.5\n\nsingle_preds = np.zeros((n_bootstraps, n_test))\nbag_preds    = np.zeros((n_bootstraps, n_test))\n\nfor b in range(n_bootstraps):\n    X_tr = rng.uniform(-3, 3, n_train).reshape(-1, 1)\n    y_tr = np.sin(X_tr).ravel() + rng.randn(n_train) * noise\n    single_preds[b] = DecisionTreeRegressor().fit(X_tr, y_tr).predict(X_test)\n    bag_pred = np.zeros(n_test)\n    for _ in range(n_bags):\n        idx = rng.randint(0, n_train, n_train)\n        bag_pred += DecisionTreeRegressor().fit(X_tr[idx], y_tr[idx]).predict(X_test)\n    bag_preds[b] = bag_pred / n_bags\n\nfor name, preds in [(\u0027Single tree\u0027, single_preds), (\u0027Bagging\u0027, bag_preds)]:\n    v = np.mean(preds.var(axis=0))\n    b2 = np.mean((preds.mean(axis=0) - f_true)**2)\n    print(f\u0027{name:\u003e12}: Bias^2={b2:.4f}  Var={v:.4f}  Total≈{b2+v+noise**2:.4f}\u0027)"},{"type":"heading","level":2,"content":"Model Class Comparison"},{"type":"table","headers":["Model","Bias","Variance","Typical Fix"],"rows":[["Logistic regression (linear boundary)","High if true boundary is nonlinear","Low — few parameters","Add polynomial features or switch model"],["Shallow decision tree (depth 1–2)","High — can only split once","Low","Increase depth or use boosting"],["Deep decision tree (unpruned)","Low — fits complex shapes","High — sensitive to data","Prune, limit depth, or use bagging"],["Random forest","Low-moderate","Low — bagging reduces variance","Tune n_estimators and max_features"],["Deep neural network (no regularisation)","Low","Very high","Dropout, weight decay, early stopping"],["Kernel SVM (RBF, small γ)","High — smooth decision boundary","Low","Increase γ or use polynomial kernel"]]},{"type":"heading","level":2,"content":"Practical Implications"},{"type":"text","content":"To diagnose whether your model has a bias or variance problem: plot learning curves (training and validation error vs n). High bias: both curves plateau high and close together — collect more features or use a more complex model. High variance: large gap between training and validation curves — collect more data, regularise, or reduce model complexity. Reducing dataset noise (better labels, feature engineering) directly reduces the irreducible error floor."},{"type":"list","ordered":false,"items":["High bias signal: training error ≈ validation error, both unacceptably high.","High variance signal: training error ≪ validation error (large gap).","Bagging reduces variance without changing bias — good for high-variance models like deep trees.","Boosting reduces bias by sequentially correcting errors — good for high-bias weak learners.","Regularisation (L1/L2, dropout) shifts the bias-variance balance toward more bias, less variance.","More training data helps high-variance models most; it does not help high-bias models significantly."]},{"type":"divider"}]"
---
# Bias-Variance Tradeoff

Every supervised learning model makes an error that can be decomposed into three orthogonal components: bias (systematic error from model assumptions), variance (sensitivity to the specific training set drawn), and irreducible noise (inherent randomness in the data-generating process). Understanding this decomposition explains why simple models underfit, complex models overfit, and how regularisation, ensembles, and larger datasets help — each targeting a different component.

## Deriving the Bias-Variance Decomposition

Let f(x) be the true function, ŷ(x) the model prediction (a random variable over training sets), and ε ~ N(0,σ²) irreducible noise. The expected squared error at a point x decomposes as: E[(y − ŷ)²] = E[(f(x) + ε − ŷ)²]. Add and subtract E[ŷ]: = E[(f(x) − E[ŷ])²] + E[(E[ŷ] − ŷ)²] + σ² = Bias²(ŷ) + Var(ŷ) + σ². The cross terms vanish because ε is independent of ŷ and E[ε]=0.

Bias = E[ŷ] − f(x) is the average difference between model predictions and the true function — it is zero for a model flexible enough to represent f exactly. Variance = E[(ŷ − E[ŷ])²] measures how much the model fluctuates across different training sets of the same size. A high-capacity model (deep tree, high-degree polynomial) fits each training set closely: low bias, high variance. A simple model (constant, linear with few features): high bias, low variance.

## Simulating the Decomposition via Bootstrap

To empirically estimate bias and variance, repeatedly draw B training sets from the same distribution, train the model on each, and evaluate on a fixed test set. The average prediction over B models estimates E[ŷ]; the variance of predictions estimates Var(ŷ); the squared gap between the average prediction and the true function estimates Bias². This is computationally intensive but gives exact empirical estimates for any model class.

```python
import numpy as np
from sklearn.tree import DecisionTreeRegressor

def bias_variance_decomp(max_depth, n_bootstraps=200, n_train=60,
                          n_test=400, noise=0.5, seed=0):
    rng = np.random.RandomState(seed)
    X_test = np.linspace(-3, 3, n_test).reshape(-1, 1)
    f_true = np.sin(X_test).ravel()
    preds = np.zeros((n_bootstraps, n_test))
    for b in range(n_bootstraps):
        X_tr = rng.uniform(-3, 3, n_train).reshape(-1, 1)
        y_tr = np.sin(X_tr).ravel() + rng.randn(n_train) * noise
        model = DecisionTreeRegressor(max_depth=max_depth)
        model.fit(X_tr, y_tr)
        preds[b] = model.predict(X_test)
    mean_pred = preds.mean(axis=0)
    bias_sq  = np.mean((mean_pred - f_true) ** 2)
    variance  = np.mean(preds.var(axis=0))
    noise_sq  = noise ** 2
    return bias_sq, variance, noise_sq

print(f'{"Depth":>6} {"Bias^2":>8} {"Var":>8} {"Noise":>8} {"Total":>8}')
for depth in [1, 2, 4, 8, 16]:
    b2, v, n = bias_variance_decomp(depth)
    print(f'{depth:>6} {b2:>8.4f} {v:>8.4f} {n:>8.4f} {b2+v+n:>8.4f}')
```

## Test Error Curve vs Model Complexity

As model complexity increases (e.g., polynomial degree, tree depth, network width), training error monotonically decreases while test error follows a U-shape: high (underfitting) for simple models, minimum at optimal complexity, rising again (overfitting) for complex models. The gap between training and test error is approximately 2 × Variance / n for many model classes. Cross-validation estimates the test error curve without requiring a holdout set.

```python
import numpy as np
from sklearn.pipeline import Pipeline
from sklearn.preprocessing import PolynomialFeatures
from sklearn.linear_model import LinearRegression
from sklearn.model_selection import cross_val_score

np.random.seed(0)
X = np.random.uniform(-3, 3, 120).reshape(-1, 1)
y = np.sin(X).ravel() + 0.4 * np.random.randn(120)

degrees = range(1, 16)
train_errs, cv_errs = [], []
for d in degrees:
    pipe = Pipeline([
        ('poly', PolynomialFeatures(degree=d, include_bias=False)),
        ('lr',   LinearRegression())
    ])
    cv_scores = cross_val_score(
        pipe, X, y, cv=5, scoring='neg_mean_squared_error'
    )
    pipe.fit(X, y)
    train_errs.append(np.mean((y - pipe.predict(X))**2))
    cv_errs.append(-cv_scores.mean())

best_d = list(degrees)[np.argmin(cv_errs)]
print(f'{"Deg":>4} {"Train MSE":>10} {"CV MSE":>10}')
for d, tr, cv in zip(degrees, train_errs, cv_errs):
    marker = ' <-- best' if d == best_d else ''
    print(f'{d:>4} {tr:>10.4f} {cv:>10.4f}{marker}')
```

## Double Descent Phenomenon

Classical statistical learning theory predicts a U-shaped bias-variance tradeoff. But modern overparameterised models (deep networks, random features, kernel machines) exhibit double descent: test error rises near the interpolation threshold (where model capacity ≈ n) and then decreases again as capacity continues to grow. The minimum-norm interpolating solution in the overparameterised regime implicitly regularises, achieving low variance despite zero training error.

> **Why Double Descent Happens**: Near the interpolation threshold the model barely fits the data — small perturbations cause large coefficient swings (high variance). Beyond the threshold there are many solutions that fit perfectly; gradient descent or pseudoinverse selects the minimum-norm one, which is smooth and generalises well. This breaks the classical U-curve and challenges the bias-variance framing for modern models.

```python
import numpy as np

np.random.seed(42)
n_train = 50
rng = np.random.RandomState(42)
X_full = rng.randn(n_train, 300)
y_train = rng.randn(n_train)          # pure noise — no true signal
X_test  = rng.randn(500, 300)
y_test  = rng.randn(500)

p_values = list(range(5, 300, 5))
test_mse = []
for p in p_values:
    Xtr = X_full[:, :p]
    Xte = X_test[:, :p]
    # Minimum-norm (pseudoinverse) solution
    coef, _, _, _ = np.linalg.lstsq(Xtr, y_train, rcond=None)
    pred = Xte @ coef
    test_mse.append(np.mean((y_test - pred)**2))

peak_p = p_values[int(np.argmax(test_mse))]
print(f'Interpolation threshold n = {n_train}')
print(f'Peak test MSE at p = {peak_p}: {max(test_mse):.2f}')
print(f'Test MSE at p=5:   {test_mse[0]:.4f}')
print(f'Test MSE at p=295: {test_mse[-1]:.4f}')
print('MSE rises near n=p, then falls again as p >> n (double descent).')
```

## Regularisation and Ensembles

Regularisation (L1, L2, dropout, early stopping) adds bias to reduce variance — trading a slightly wrong answer for a much more stable one. Bagging (Bootstrap AGGregating) averages predictions over B models trained on bootstrap samples, reducing variance by ~1/B without increasing bias. Boosting fits models sequentially on residuals, reducing bias at the cost of some variance. Random forests combine bagging with feature randomisation for additional variance reduction.

```python
import numpy as np
from sklearn.tree import DecisionTreeRegressor

rng = np.random.RandomState(0)
n_train, n_test = 60, 300
n_bags, n_bootstraps = 50, 100
X_test = np.linspace(-3, 3, n_test).reshape(-1, 1)
f_true = np.sin(X_test).ravel()
noise = 0.5

single_preds = np.zeros((n_bootstraps, n_test))
bag_preds    = np.zeros((n_bootstraps, n_test))

for b in range(n_bootstraps):
    X_tr = rng.uniform(-3, 3, n_train).reshape(-1, 1)
    y_tr = np.sin(X_tr).ravel() + rng.randn(n_train) * noise
    single_preds[b] = DecisionTreeRegressor().fit(X_tr, y_tr).predict(X_test)
    bag_pred = np.zeros(n_test)
    for _ in range(n_bags):
        idx = rng.randint(0, n_train, n_train)
        bag_pred += DecisionTreeRegressor().fit(X_tr[idx], y_tr[idx]).predict(X_test)
    bag_preds[b] = bag_pred / n_bags

for name, preds in [('Single tree', single_preds), ('Bagging', bag_preds)]:
    v = np.mean(preds.var(axis=0))
    b2 = np.mean((preds.mean(axis=0) - f_true)**2)
    print(f'{name:>12}: Bias^2={b2:.4f}  Var={v:.4f}  Total≈{b2+v+noise**2:.4f}')
```

## Model Class Comparison

| Model | Bias | Variance | Typical Fix |
| --- | --- | --- | --- |
| Logistic regression (linear boundary) | High if true boundary is nonlinear | Low — few parameters | Add polynomial features or switch model |
| Shallow decision tree (depth 1–2) | High — can only split once | Low | Increase depth or use boosting |
| Deep decision tree (unpruned) | Low — fits complex shapes | High — sensitive to data | Prune, limit depth, or use bagging |
| Random forest | Low-moderate | Low — bagging reduces variance | Tune n_estimators and max_features |
| Deep neural network (no regularisation) | Low | Very high | Dropout, weight decay, early stopping |
| Kernel SVM (RBF, small γ) | High — smooth decision boundary | Low | Increase γ or use polynomial kernel |

## Practical Implications

To diagnose whether your model has a bias or variance problem: plot learning curves (training and validation error vs n). High bias: both curves plateau high and close together — collect more features or use a more complex model. High variance: large gap between training and validation curves — collect more data, regularise, or reduce model complexity. Reducing dataset noise (better labels, feature engineering) directly reduces the irreducible error floor.

- High bias signal: training error ≈ validation error, both unacceptably high.
- High variance signal: training error ≪ validation error (large gap).
- Bagging reduces variance without changing bias — good for high-variance models like deep trees.
- Boosting reduces bias by sequentially correcting errors — good for high-bias weak learners.
- Regularisation (L1/L2, dropout) shifts the bias-variance balance toward more bias, less variance.
- More training data helps high-variance models most; it does not help high-bias models significantly.

---

