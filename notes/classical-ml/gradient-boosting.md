---
title: "Gradient Boosting — Additive Model and Stage-Wise Fitting"
slug: "gradient-boosting"
description: "How gradient boosting builds an additive model by fitting new trees to the negative gradient of the loss, functional gradient descent in function space, shrinkage, and the bias-variance contrast with bagging."
tags: ["supervised-learning", "classical-ml"]
topic: "classical-ml"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"heading","level":2,"content":"Additive Model and Stage-Wise Fitting"},{"type":"text","content":"Gradient boosting builds an additive model F_M(x) = F_0(x) + Σ_{m=1}^{M} η·h_m(x) where each h_m is a weak learner (typically a shallow tree) and η is the learning rate (shrinkage). Unlike neural networks that adjust all parameters simultaneously, stage-wise fitting is greedy — each new tree is added to minimise the current loss without modifying previous trees. This greedy, non-parametric approach is what makes gradient boosting so flexible: any differentiable loss function can be optimised."},{"type":"heading","level":2,"content":"Gradient Boosting as Functional Gradient Descent"},{"type":"text","content":"Standard gradient descent moves parameters θ in the direction −∇_θ L. Gradient boosting instead does gradient descent in function space: the negative gradient −∂L/∂F evaluated at the current predictions tells us the direction to move the function F. For MSE loss L = (1/2)(y − F)², the negative gradient is y − F — the residual. So residual boosting is a special case of gradient boosting. For log-loss (binary classification) L = −y log p − (1−y) log(1−p), the negative gradient is y − p where p = σ(F). Each new tree is fitted to these pseudo-residuals."},{"type":"code","language":"python","content":"import numpy as np\nfrom sklearn.tree import DecisionTreeRegressor\nfrom sklearn.datasets import make_regression\nfrom sklearn.model_selection import train_test_split\nfrom sklearn.metrics import mean_squared_error\n\nclass GradientBoostingMSE:\n    def __init__(self, n_estimators=100, learning_rate=0.1, max_depth=3):\n        self.n = n_estimators; self.lr = learning_rate\n        self.max_depth = max_depth; self.trees = []; self.F0 = None\n\n    def fit(self, X, y):\n        self.F0 = y.mean()           # initial prediction = global mean\n        F = np.full(len(y), self.F0)\n        for _ in range(self.n):\n            residuals = y - F        # negative gradient of MSE\n            tree = DecisionTreeRegressor(max_depth=self.max_depth)\n            tree.fit(X, residuals)\n            F += self.lr * tree.predict(X)\n            self.trees.append(tree)\n        return self\n\n    def predict(self, X):\n        pred = np.full(X.shape[0], self.F0)\n        for tree in self.trees:\n            pred += self.lr * tree.predict(X)\n        return pred\n\nX, y = make_regression(n_samples=600, n_features=10, noise=20, random_state=42)\nX_tr, X_te, y_tr, y_te = train_test_split(X, y, test_size=0.2, random_state=42)\ngb = GradientBoostingMSE(n_estimators=150, learning_rate=0.1, max_depth=3)\ngb.fit(X_tr, y_tr)\nrmse = np.sqrt(mean_squared_error(y_te, gb.predict(X_te)))\nprint(f\u0027Custom GB RMSE: {rmse:.4f}\u0027)"},{"type":"heading","level":2,"content":"Loss Functions and Their Gradients"},{"type":"text","content":"Gradient boosting\u0027s power comes from plugging in any differentiable loss. MSE loss gives gradient = y − F (residuals). Log-loss for binary classification gives gradient = y − σ(F) where σ is the sigmoid — trees are fitted to the difference between true labels and current predicted probabilities. Huber loss (robust regression) gives gradient that is linear for small residuals and bounded for outliers. Quantile loss enables prediction intervals."},{"type":"code","language":"python","content":"import numpy as np\nfrom sklearn.tree import DecisionTreeRegressor\nfrom sklearn.datasets import load_breast_cancer\nfrom sklearn.model_selection import train_test_split\nfrom sklearn.metrics import log_loss\n\ndef sigmoid(x):\n    return 1.0 / (1.0 + np.exp(-np.clip(x, -10, 10)))\n\nX, y = load_breast_cancer(return_X_y=True)\nX_tr, X_te, y_tr, y_te = train_test_split(X, y, test_size=0.2, random_state=42)\n\nF = np.zeros(len(y_tr))     # start at F=0 (sigmoid gives p=0.5)\ntrees, lr = [], 0.1\n\nfor m in range(100):\n    p = sigmoid(F)\n    gradient = y_tr - p       # negative gradient of log-loss\n    tree = DecisionTreeRegressor(max_depth=3)\n    tree.fit(X_tr, gradient)\n    F += lr * tree.predict(X_tr)\n    trees.append(tree)\n\n# Evaluate on test set\nF_te = np.zeros(len(y_te))\nfor tree in trees:\n    F_te += lr * tree.predict(X_te)\n\npreds = (sigmoid(F_te) \u003e 0.5).astype(int)\nprint(f\u0027Custom log-loss GB accuracy: {(preds == y_te).mean():.4f}\u0027)\nprint(f\u0027Log-loss on test set:        {log_loss(y_te, sigmoid(F_te)):.4f}\u0027)"},{"type":"callout","variant":"info","title":"Why Residuals Equal Negative Gradient for MSE","content":"MSE loss is L(y, F) = (1/2)(y − F)². Its derivative with respect to F is ∂L/∂F = F − y = −(y − F). So the negative gradient is y − F, which is exactly the residual. Fitting a tree to residuals and adding it to F is gradient descent in function space — residual boosting was invented before the gradient interpretation was formalised."},{"type":"heading","level":2,"content":"sklearn GradientBoostingClassifier"},{"type":"text","content":"sklearn\u0027s GradientBoostingClassifier implements the original Friedman (2001) stochastic gradient boosting algorithm. Key parameters: n_estimators (number of trees), learning_rate (shrinkage η), max_depth (typical 3-5 for boosting), subsample (stochastic GB — use 0.5-0.8 to add variance reduction alongside bias reduction). The deviance (log-loss) and exponential (AdaBoost) loss functions are both supported."},{"type":"code","language":"python","content":"from sklearn.ensemble import GradientBoostingClassifier\nfrom sklearn.datasets import load_breast_cancer\nfrom sklearn.model_selection import train_test_split, cross_val_score\nimport numpy as np\n\nX, y = load_breast_cancer(return_X_y=True)\nX_tr, X_te, y_tr, y_te = train_test_split(X, y, test_size=0.2, random_state=42)\n\ngb = GradientBoostingClassifier(\n    n_estimators=200,\n    learning_rate=0.05,    # shrinkage — smaller = more regularisation\n    max_depth=3,           # shallow trees preferred for boosting\n    subsample=0.8,         # stochastic GB: 80% of data per tree\n    min_samples_leaf=5,\n    random_state=42\n)\ngb.fit(X_tr, y_tr)\n\nprint(f\u0027Train: {gb.score(X_tr, y_tr):.4f}  Test: {gb.score(X_te, y_te):.4f}\u0027)\ncv = cross_val_score(gb, X, y, cv=5)\nprint(f\u00275-fold CV: {cv.mean():.4f} +/- {cv.std():.4f}\u0027)\ntop3 = gb.feature_importances_.argsort()[::-1][:3]\nprint(f\u0027Top-3 features by MDI: {top3}\u0027)"},{"type":"heading","level":2,"content":"Learning Rate vs n_estimators Trade-off"},{"type":"text","content":"Shrinkage (small learning rate η) is the most effective regulariser in gradient boosting. A smaller η requires more trees to fit the training data — the relationship is roughly n_estimators ∝ 1/η. This means a model with lr=0.05 and 400 trees tends to match lr=0.1 and 200 trees in accuracy while being more robust to overfitting. The computational cost is identical. Finding the right n_estimators for a given lr is best done with early stopping."},{"type":"code","language":"python","content":"import numpy as np\nimport matplotlib.pyplot as plt\nfrom sklearn.ensemble import GradientBoostingClassifier\nfrom sklearn.datasets import load_breast_cancer\nfrom sklearn.model_selection import train_test_split\n\nX, y = load_breast_cancer(return_X_y=True)\nX_tr, X_te, y_tr, y_te = train_test_split(X, y, test_size=0.2, random_state=42)\n\nconfigs = [(0.50, 50), (0.10, 200), (0.05, 400), (0.01, 1000)]\nresults = []\nfor lr, n_est in configs:\n    gb = GradientBoostingClassifier(\n        n_estimators=n_est, learning_rate=lr, max_depth=3, random_state=42)\n    gb.fit(X_tr, y_tr)\n    results.append({\u0027lr\u0027: lr, \u0027n\u0027: n_est,\n                    \u0027train\u0027: gb.score(X_tr, y_tr),\n                    \u0027test\u0027:  gb.score(X_te, y_te)})\n    print(f\u0027lr={lr:5.2f}  n={n_est:4d}  \u0027\n          f\u0027train={results[-1][\"train\"]:.4f}  test={results[-1][\"test\"]:.4f}\u0027)\n\nbest = max(results, key=lambda r: r[\u0027test\u0027])\nprint(f\u0027Best config: lr={best[\"lr\"]}, n_estimators={best[\"n\"]}, test={best[\"test\"]:.4f}\u0027)"},{"type":"heading","level":2,"content":"Bagging vs Boosting"},{"type":"table","headers":["Aspect","Bagging (Random Forest)","Boosting (Gradient Boosting)"],"rows":[["Primary effect","Reduces variance","Reduces bias"],["Tree depth","Deep (unconstrained)","Shallow (depth 3-5 typical)"],["Tree training","Parallel (independent)","Sequential (dependent)"],["Overfitting risk","Low (averaging regularises)","High if lr too large or too many trees"],["Noise sensitivity","Low (averaging dilutes outliers)","High (fits residuals including noise"],["Parallelisable","Yes (trivially)","No (each tree depends on previous)"],["Default use case","High-variance datasets","Low-bias requirement, structured data"]]},{"type":"list","ordered":false,"items":["Boosting reduces bias; bagging reduces variance — they are complementary strategies","Shallow trees (depth 3-5) work best for boosting; deep trees work best inside forests","Smaller learning rate + more trees is almost always better than large lr + few trees","Stochastic GB (subsample \u003c 1) adds variance reduction on top of bias reduction","Gradient boosting can fit any differentiable loss by changing the gradient target","Unlike neural networks, gradient boosting requires no feature normalisation"]},{"type":"callout","variant":"warning","title":"Gradient Boosting Overfits Without Shrinkage","content":"Without shrinkage (learning_rate=1.0), gradient boosting aggressively fits the training data and overfits quickly. Always use learning_rate \u003c 0.1 in production. Use early stopping on a validation set to automatically find the right n_estimators."},{"type":"callout","variant":"tip","title":"Starting Configuration for sklearn GB","content":"A reliable starting point: learning_rate=0.05, max_depth=4, n_estimators=300, subsample=0.8, min_samples_leaf=5. Then tune n_estimators with early stopping. This beats default settings on most tabular datasets."},{"type":"divider"}]"
---
# Gradient Boosting — Additive Model and Stage-Wise Fitting

## Additive Model and Stage-Wise Fitting

Gradient boosting builds an additive model F_M(x) = F_0(x) + Σ_{m=1}^{M} η·h_m(x) where each h_m is a weak learner (typically a shallow tree) and η is the learning rate (shrinkage). Unlike neural networks that adjust all parameters simultaneously, stage-wise fitting is greedy — each new tree is added to minimise the current loss without modifying previous trees. This greedy, non-parametric approach is what makes gradient boosting so flexible: any differentiable loss function can be optimised.

## Gradient Boosting as Functional Gradient Descent

Standard gradient descent moves parameters θ in the direction −∇_θ L. Gradient boosting instead does gradient descent in function space: the negative gradient −∂L/∂F evaluated at the current predictions tells us the direction to move the function F. For MSE loss L = (1/2)(y − F)², the negative gradient is y − F — the residual. So residual boosting is a special case of gradient boosting. For log-loss (binary classification) L = −y log p − (1−y) log(1−p), the negative gradient is y − p where p = σ(F). Each new tree is fitted to these pseudo-residuals.

```python
import numpy as np
from sklearn.tree import DecisionTreeRegressor
from sklearn.datasets import make_regression
from sklearn.model_selection import train_test_split
from sklearn.metrics import mean_squared_error

class GradientBoostingMSE:
    def __init__(self, n_estimators=100, learning_rate=0.1, max_depth=3):
        self.n = n_estimators; self.lr = learning_rate
        self.max_depth = max_depth; self.trees = []; self.F0 = None

    def fit(self, X, y):
        self.F0 = y.mean()           # initial prediction = global mean
        F = np.full(len(y), self.F0)
        for _ in range(self.n):
            residuals = y - F        # negative gradient of MSE
            tree = DecisionTreeRegressor(max_depth=self.max_depth)
            tree.fit(X, residuals)
            F += self.lr * tree.predict(X)
            self.trees.append(tree)
        return self

    def predict(self, X):
        pred = np.full(X.shape[0], self.F0)
        for tree in self.trees:
            pred += self.lr * tree.predict(X)
        return pred

X, y = make_regression(n_samples=600, n_features=10, noise=20, random_state=42)
X_tr, X_te, y_tr, y_te = train_test_split(X, y, test_size=0.2, random_state=42)
gb = GradientBoostingMSE(n_estimators=150, learning_rate=0.1, max_depth=3)
gb.fit(X_tr, y_tr)
rmse = np.sqrt(mean_squared_error(y_te, gb.predict(X_te)))
print(f'Custom GB RMSE: {rmse:.4f}')
```

## Loss Functions and Their Gradients

Gradient boosting's power comes from plugging in any differentiable loss. MSE loss gives gradient = y − F (residuals). Log-loss for binary classification gives gradient = y − σ(F) where σ is the sigmoid — trees are fitted to the difference between true labels and current predicted probabilities. Huber loss (robust regression) gives gradient that is linear for small residuals and bounded for outliers. Quantile loss enables prediction intervals.

```python
import numpy as np
from sklearn.tree import DecisionTreeRegressor
from sklearn.datasets import load_breast_cancer
from sklearn.model_selection import train_test_split
from sklearn.metrics import log_loss

def sigmoid(x):
    return 1.0 / (1.0 + np.exp(-np.clip(x, -10, 10)))

X, y = load_breast_cancer(return_X_y=True)
X_tr, X_te, y_tr, y_te = train_test_split(X, y, test_size=0.2, random_state=42)

F = np.zeros(len(y_tr))     # start at F=0 (sigmoid gives p=0.5)
trees, lr = [], 0.1

for m in range(100):
    p = sigmoid(F)
    gradient = y_tr - p       # negative gradient of log-loss
    tree = DecisionTreeRegressor(max_depth=3)
    tree.fit(X_tr, gradient)
    F += lr * tree.predict(X_tr)
    trees.append(tree)

# Evaluate on test set
F_te = np.zeros(len(y_te))
for tree in trees:
    F_te += lr * tree.predict(X_te)

preds = (sigmoid(F_te) > 0.5).astype(int)
print(f'Custom log-loss GB accuracy: {(preds == y_te).mean():.4f}')
print(f'Log-loss on test set:        {log_loss(y_te, sigmoid(F_te)):.4f}')
```

> **Why Residuals Equal Negative Gradient for MSE**: MSE loss is L(y, F) = (1/2)(y − F)². Its derivative with respect to F is ∂L/∂F = F − y = −(y − F). So the negative gradient is y − F, which is exactly the residual. Fitting a tree to residuals and adding it to F is gradient descent in function space — residual boosting was invented before the gradient interpretation was formalised.

## sklearn GradientBoostingClassifier

sklearn's GradientBoostingClassifier implements the original Friedman (2001) stochastic gradient boosting algorithm. Key parameters: n_estimators (number of trees), learning_rate (shrinkage η), max_depth (typical 3-5 for boosting), subsample (stochastic GB — use 0.5-0.8 to add variance reduction alongside bias reduction). The deviance (log-loss) and exponential (AdaBoost) loss functions are both supported.

```python
from sklearn.ensemble import GradientBoostingClassifier
from sklearn.datasets import load_breast_cancer
from sklearn.model_selection import train_test_split, cross_val_score
import numpy as np

X, y = load_breast_cancer(return_X_y=True)
X_tr, X_te, y_tr, y_te = train_test_split(X, y, test_size=0.2, random_state=42)

gb = GradientBoostingClassifier(
    n_estimators=200,
    learning_rate=0.05,    # shrinkage — smaller = more regularisation
    max_depth=3,           # shallow trees preferred for boosting
    subsample=0.8,         # stochastic GB: 80% of data per tree
    min_samples_leaf=5,
    random_state=42
)
gb.fit(X_tr, y_tr)

print(f'Train: {gb.score(X_tr, y_tr):.4f}  Test: {gb.score(X_te, y_te):.4f}')
cv = cross_val_score(gb, X, y, cv=5)
print(f'5-fold CV: {cv.mean():.4f} +/- {cv.std():.4f}')
top3 = gb.feature_importances_.argsort()[::-1][:3]
print(f'Top-3 features by MDI: {top3}')
```

## Learning Rate vs n_estimators Trade-off

Shrinkage (small learning rate η) is the most effective regulariser in gradient boosting. A smaller η requires more trees to fit the training data — the relationship is roughly n_estimators ∝ 1/η. This means a model with lr=0.05 and 400 trees tends to match lr=0.1 and 200 trees in accuracy while being more robust to overfitting. The computational cost is identical. Finding the right n_estimators for a given lr is best done with early stopping.

```python
import numpy as np
import matplotlib.pyplot as plt
from sklearn.ensemble import GradientBoostingClassifier
from sklearn.datasets import load_breast_cancer
from sklearn.model_selection import train_test_split

X, y = load_breast_cancer(return_X_y=True)
X_tr, X_te, y_tr, y_te = train_test_split(X, y, test_size=0.2, random_state=42)

configs = [(0.50, 50), (0.10, 200), (0.05, 400), (0.01, 1000)]
results = []
for lr, n_est in configs:
    gb = GradientBoostingClassifier(
        n_estimators=n_est, learning_rate=lr, max_depth=3, random_state=42)
    gb.fit(X_tr, y_tr)
    results.append({'lr': lr, 'n': n_est,
                    'train': gb.score(X_tr, y_tr),
                    'test':  gb.score(X_te, y_te)})
    print(f'lr={lr:5.2f}  n={n_est:4d}  '
          f'train={results[-1]["train"]:.4f}  test={results[-1]["test"]:.4f}')

best = max(results, key=lambda r: r['test'])
print(f'Best config: lr={best["lr"]}, n_estimators={best["n"]}, test={best["test"]:.4f}')
```

## Bagging vs Boosting

| Aspect | Bagging (Random Forest) | Boosting (Gradient Boosting) |
| --- | --- | --- |
| Primary effect | Reduces variance | Reduces bias |
| Tree depth | Deep (unconstrained) | Shallow (depth 3-5 typical) |
| Tree training | Parallel (independent) | Sequential (dependent) |
| Overfitting risk | Low (averaging regularises) | High if lr too large or too many trees |
| Noise sensitivity | Low (averaging dilutes outliers) | High (fits residuals including noise |
| Parallelisable | Yes (trivially) | No (each tree depends on previous) |
| Default use case | High-variance datasets | Low-bias requirement, structured data |

- Boosting reduces bias; bagging reduces variance — they are complementary strategies
- Shallow trees (depth 3-5) work best for boosting; deep trees work best inside forests
- Smaller learning rate + more trees is almost always better than large lr + few trees
- Stochastic GB (subsample < 1) adds variance reduction on top of bias reduction
- Gradient boosting can fit any differentiable loss by changing the gradient target
- Unlike neural networks, gradient boosting requires no feature normalisation

> **Gradient Boosting Overfits Without Shrinkage**: Without shrinkage (learning_rate=1.0), gradient boosting aggressively fits the training data and overfits quickly. Always use learning_rate < 0.1 in production. Use early stopping on a validation set to automatically find the right n_estimators.

> **Starting Configuration for sklearn GB**: A reliable starting point: learning_rate=0.05, max_depth=4, n_estimators=300, subsample=0.8, min_samples_leaf=5. Then tune n_estimators with early stopping. This beats default settings on most tabular datasets.

---

