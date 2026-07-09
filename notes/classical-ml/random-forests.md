---
title: "Random Forests — Bagging and Feature Subsampling"
slug: "random-forests"
description: "How Random Forests reduce variance through bootstrap aggregation and feature subsampling, OOB error as free validation, Gini vs permutation importance, and Extra-Trees as a faster variant."
tags: ["supervised-learning", "classical-ml"]
topic: "classical-ml"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"heading","level":2,"content":"Bagging — Bootstrap Aggregating"},{"type":"text","content":"Bagging (bootstrap aggregating) trains B models on B bootstrap samples drawn with replacement from the training set. Each bootstrap sample contains ~63.2% unique examples (the rest are duplicates). Predictions are aggregated by majority vote (classification) or mean (regression). The variance of the average of B correlated estimators is σ²((1-ρ)/B + ρ) — when ρ=0 (perfectly uncorrelated), variance shrinks as 1/B; when ρ=1 (identical models), no reduction. Decorrelation is therefore essential."},{"type":"code","language":"python","content":"import numpy as np\nfrom sklearn.tree import DecisionTreeClassifier\nfrom sklearn.datasets import load_iris\nfrom sklearn.model_selection import train_test_split\n\nclass BaggingClassifier:\n    def __init__(self, n_estimators=50, max_depth=5, random_state=42):\n        self.n_estimators = n_estimators\n        self.max_depth = max_depth\n        self.random_state = random_state\n        self.trees = []\n\n    def fit(self, X, y):\n        rng = np.random.RandomState(self.random_state)\n        n = len(y)\n        for i in range(self.n_estimators):\n            idx = rng.choice(n, size=n, replace=True)   # bootstrap\n            tree = DecisionTreeClassifier(max_depth=self.max_depth, random_state=i)\n            tree.fit(X[idx], y[idx])\n            self.trees.append(tree)\n        return self\n\n    def predict(self, X):\n        preds = np.array([t.predict(X) for t in self.trees])\n        return np.apply_along_axis(\n            lambda x: np.bincount(x.astype(int)).argmax(), axis=0, arr=preds)\n\nX, y = load_iris(return_X_y=True)\nX_tr, X_te, y_tr, y_te = train_test_split(X, y, test_size=0.2, random_state=42)\nmodel = BaggingClassifier(n_estimators=100, max_depth=5).fit(X_tr, y_tr)\npreds = model.predict(X_te)\nprint(f\u0027Bagging accuracy: {(preds == y_te).mean():.4f}\u0027)"},{"type":"heading","level":2,"content":"Feature Subsampling and Decorrelation"},{"type":"text","content":"Random Forests add a second source of randomness: at each split only a random subset of m features is considered (not all p). This decorrelates the trees even when one feature dominates, breaking the correlation ρ in the variance formula. Standard choices: m = √p for classification, m = p/3 for regression. Smaller m → more decorrelation → more variance reduction, but each individual tree is weaker (higher bias). The bias-variance sweet spot is typically √p."},{"type":"callout","variant":"info","title":"Why 63.2% Unique Samples per Bootstrap","content":"With n draws from n samples with replacement, the probability a specific sample is never chosen is (1 − 1/n)^n → 1/e ≈ 36.8% as n → ∞. So each bootstrap sample contains roughly 63.2% unique training examples, leaving ~36.8% as the out-of-bag (OOB) set for free validation."},{"type":"heading","level":2,"content":"Out-of-Bag Error and sklearn Implementation"},{"type":"text","content":"The ~36.8% of samples not included in each tree\u0027s bootstrap sample form its out-of-bag set. Each sample\u0027s OOB prediction is the aggregate of trees that did not train on it. OOB error is a nearly unbiased estimate of test error — essentially a free cross-validation — valid when the forest is large enough (≥200 trees). Enable with oob_score=True."},{"type":"code","language":"python","content":"from sklearn.ensemble import RandomForestClassifier\nfrom sklearn.datasets import load_breast_cancer\nfrom sklearn.model_selection import train_test_split\n\nX, y = load_breast_cancer(return_X_y=True)\nX_tr, X_te, y_tr, y_te = train_test_split(X, y, test_size=0.2, random_state=42)\n\nrf = RandomForestClassifier(\n    n_estimators=300,\n    max_features=\u0027sqrt\u0027,       # sqrt(p) features per split\n    max_depth=None,\n    min_samples_leaf=3,\n    oob_score=True,            # free validation from ~36.8% OOB samples\n    n_jobs=-1,\n    random_state=42\n)\nrf.fit(X_tr, y_tr)\n\nprint(f\u0027OOB score:      {rf.oob_score_:.4f}\u0027)\nprint(f\u0027Test score:     {rf.score(X_te, y_te):.4f}\u0027)\nprint(f\u0027Features/split: {rf.max_features_} of {X.shape[1]}\u0027)"},{"type":"heading","level":2,"content":"Feature Importance — Gini vs Permutation"},{"type":"text","content":"Gini importance (MDI) sums impurity reductions weighted by sample fraction across all trees. It is fast but biased toward high-cardinality and continuous features. Permutation importance measures the drop in model accuracy when a feature\u0027s values are randomly shuffled on the test set — it is model-agnostic and unbiased. Run k=10-30 repetitions for stable estimates. SHAP gives local explanations on top of global importance."},{"type":"table","headers":["Method","Bias (cardinality)","Correlated Features","Cost","Global / Local"],"rows":[["Gini / MDI","Yes — high-cardinality inflated","Inflates both features","Negligible (computed during training)","Global only"],["Permutation","None","Splits importance between correlated","Moderate (k × n predictions)","Global only"],["SHAP","None","Distributes fairly","High (O(TLD²) TreeSHAP)","Both global and local"],["LIME","None","Unstable","Moderate","Local only"]]},{"type":"code","language":"python","content":"import numpy as np\nimport matplotlib.pyplot as plt\nfrom sklearn.ensemble import RandomForestClassifier\nfrom sklearn.inspection import permutation_importance\nfrom sklearn.datasets import make_classification\nfrom sklearn.model_selection import train_test_split\n\n# Correlated features highlight MDI bias\nX, y = make_classification(n_samples=1000, n_features=10, n_informative=3,\n                            n_redundant=5, random_state=42)\nX_tr, X_te, y_tr, y_te = train_test_split(X, y, test_size=0.2, random_state=42)\n\nrf = RandomForestClassifier(n_estimators=200, random_state=42)\nrf.fit(X_tr, y_tr)\n\ngini_imp = rf.feature_importances_\nperm = permutation_importance(rf, X_te, y_te, n_repeats=15, random_state=42)\n\nfig, axes = plt.subplots(1, 2, figsize=(13, 5))\naxes[0].bar(range(10), gini_imp); axes[0].set_title(\u0027Gini (MDI) Importance\u0027)\naxes[1].bar(range(10), perm.importances_mean); axes[1].set_title(\u0027Permutation Importance\u0027)\nfor ax in axes:\n    ax.set_xlabel(\u0027Feature index\u0027); ax.set_ylabel(\u0027Importance\u0027)\nplt.tight_layout(); plt.show()\nprint(\u0027Pearson r (Gini vs Perm):\u0027,\n      round(np.corrcoef(gini_imp, perm.importances_mean)[0, 1], 3))"},{"type":"heading","level":2,"content":"Extra-Trees — Random Threshold Selection"},{"type":"text","content":"Extremely Randomised Trees (Extra-Trees) push randomisation further: instead of finding the optimal threshold for each candidate feature, they draw a random threshold and pick the best among random (feature, threshold) pairs. This eliminates the threshold-optimisation step entirely, making each tree much faster to train. Extra-Trees typically match Random Forest accuracy on most datasets while training significantly faster."},{"type":"code","language":"python","content":"from sklearn.ensemble import RandomForestClassifier, ExtraTreesClassifier\nfrom sklearn.datasets import make_classification\nfrom sklearn.model_selection import cross_val_score\nimport time\n\nX, y = make_classification(n_samples=5000, n_features=20, n_informative=10,\n                            n_redundant=5, random_state=42)\n\nresults = {}\nfor name, clf in [\n    (\u0027RandomForest\u0027, RandomForestClassifier(n_estimators=200, random_state=42)),\n    (\u0027ExtraTrees\u0027,   ExtraTreesClassifier(n_estimators=200, random_state=42))\n]:\n    t0 = time.time()\n    scores = cross_val_score(clf, X, y, cv=5, scoring=\u0027accuracy\u0027, n_jobs=-1)\n    elapsed = time.time() - t0\n    results[name] = {\u0027mean\u0027: scores.mean(), \u0027std\u0027: scores.std(), \u0027time\u0027: elapsed}\n    print(f\u0027{name:\u003c14} acc={scores.mean():.4f}±{scores.std():.4f}  time={elapsed:.2f}s\u0027)\n\nratio = results[\u0027RandomForest\u0027][\u0027time\u0027] / results[\u0027ExtraTrees\u0027][\u0027time\u0027]\nprint(f\u0027ExtraTrees is {ratio:.1f}x faster than RandomForest\u0027)"},{"type":"heading","level":2,"content":"Bias-Variance and Parallel Training"},{"type":"text","content":"Unlike boosting (which reduces bias), bagging primarily reduces variance. Each tree is a high-variance, low-bias estimator (deep, unconstrained). Averaging B such trees reduces variance by a factor approaching 1/B as tree correlation ρ → 0. Bias stays the same as a single tree. This means Random Forests work best when individual trees are accurate but unstable — which is exactly why deep, unconstrained trees are preferred inside forests."},{"type":"list","ordered":false,"items":["Each tree is trained independently — trivially parallelisable with n_jobs=-1","n_estimators: more trees always helps until OOB error plateaus (~200-500 sufficient)","max_features: key diversity lever — smaller value = more decorrelation but weaker trees","max_depth=None (default) is fine inside forests — depth is regularised by averaging","min_samples_leaf=3-5 prevents very small leaves without harming much","oob_score=True gives free validation — compare with held-out test accuracy"]},{"type":"callout","variant":"warning","title":"Gini Importance Bias in High-Cardinality Settings","content":"On datasets with mixed feature types (continuous + categorical with many categories), Gini importance systematically overestimates continuous features. Always cross-check with permutation importance on a held-out set, especially before reporting feature rankings to stakeholders."},{"type":"callout","variant":"tip","title":"Random Forest vs Extra-Trees Rule of Thumb","content":"Start with RandomForest. If training time is a bottleneck and accuracy is similar on your validation set, switch to ExtraTreesClassifier — it trains 2-5x faster with identical accuracy on most real-world datasets."},{"type":"divider"}]"
---
# Random Forests — Bagging and Feature Subsampling

## Bagging — Bootstrap Aggregating

Bagging (bootstrap aggregating) trains B models on B bootstrap samples drawn with replacement from the training set. Each bootstrap sample contains ~63.2% unique examples (the rest are duplicates). Predictions are aggregated by majority vote (classification) or mean (regression). The variance of the average of B correlated estimators is σ²((1-ρ)/B + ρ) — when ρ=0 (perfectly uncorrelated), variance shrinks as 1/B; when ρ=1 (identical models), no reduction. Decorrelation is therefore essential.

```python
import numpy as np
from sklearn.tree import DecisionTreeClassifier
from sklearn.datasets import load_iris
from sklearn.model_selection import train_test_split

class BaggingClassifier:
    def __init__(self, n_estimators=50, max_depth=5, random_state=42):
        self.n_estimators = n_estimators
        self.max_depth = max_depth
        self.random_state = random_state
        self.trees = []

    def fit(self, X, y):
        rng = np.random.RandomState(self.random_state)
        n = len(y)
        for i in range(self.n_estimators):
            idx = rng.choice(n, size=n, replace=True)   # bootstrap
            tree = DecisionTreeClassifier(max_depth=self.max_depth, random_state=i)
            tree.fit(X[idx], y[idx])
            self.trees.append(tree)
        return self

    def predict(self, X):
        preds = np.array([t.predict(X) for t in self.trees])
        return np.apply_along_axis(
            lambda x: np.bincount(x.astype(int)).argmax(), axis=0, arr=preds)

X, y = load_iris(return_X_y=True)
X_tr, X_te, y_tr, y_te = train_test_split(X, y, test_size=0.2, random_state=42)
model = BaggingClassifier(n_estimators=100, max_depth=5).fit(X_tr, y_tr)
preds = model.predict(X_te)
print(f'Bagging accuracy: {(preds == y_te).mean():.4f}')
```

## Feature Subsampling and Decorrelation

Random Forests add a second source of randomness: at each split only a random subset of m features is considered (not all p). This decorrelates the trees even when one feature dominates, breaking the correlation ρ in the variance formula. Standard choices: m = √p for classification, m = p/3 for regression. Smaller m → more decorrelation → more variance reduction, but each individual tree is weaker (higher bias). The bias-variance sweet spot is typically √p.

> **Why 63.2% Unique Samples per Bootstrap**: With n draws from n samples with replacement, the probability a specific sample is never chosen is (1 − 1/n)^n → 1/e ≈ 36.8% as n → ∞. So each bootstrap sample contains roughly 63.2% unique training examples, leaving ~36.8% as the out-of-bag (OOB) set for free validation.

## Out-of-Bag Error and sklearn Implementation

The ~36.8% of samples not included in each tree's bootstrap sample form its out-of-bag set. Each sample's OOB prediction is the aggregate of trees that did not train on it. OOB error is a nearly unbiased estimate of test error — essentially a free cross-validation — valid when the forest is large enough (≥200 trees). Enable with oob_score=True.

```python
from sklearn.ensemble import RandomForestClassifier
from sklearn.datasets import load_breast_cancer
from sklearn.model_selection import train_test_split

X, y = load_breast_cancer(return_X_y=True)
X_tr, X_te, y_tr, y_te = train_test_split(X, y, test_size=0.2, random_state=42)

rf = RandomForestClassifier(
    n_estimators=300,
    max_features='sqrt',       # sqrt(p) features per split
    max_depth=None,
    min_samples_leaf=3,
    oob_score=True,            # free validation from ~36.8% OOB samples
    n_jobs=-1,
    random_state=42
)
rf.fit(X_tr, y_tr)

print(f'OOB score:      {rf.oob_score_:.4f}')
print(f'Test score:     {rf.score(X_te, y_te):.4f}')
print(f'Features/split: {rf.max_features_} of {X.shape[1]}')
```

## Feature Importance — Gini vs Permutation

Gini importance (MDI) sums impurity reductions weighted by sample fraction across all trees. It is fast but biased toward high-cardinality and continuous features. Permutation importance measures the drop in model accuracy when a feature's values are randomly shuffled on the test set — it is model-agnostic and unbiased. Run k=10-30 repetitions for stable estimates. SHAP gives local explanations on top of global importance.

| Method | Bias (cardinality) | Correlated Features | Cost | Global / Local |
| --- | --- | --- | --- | --- |
| Gini / MDI | Yes — high-cardinality inflated | Inflates both features | Negligible (computed during training) | Global only |
| Permutation | None | Splits importance between correlated | Moderate (k × n predictions) | Global only |
| SHAP | None | Distributes fairly | High (O(TLD²) TreeSHAP) | Both global and local |
| LIME | None | Unstable | Moderate | Local only |

```python
import numpy as np
import matplotlib.pyplot as plt
from sklearn.ensemble import RandomForestClassifier
from sklearn.inspection import permutation_importance
from sklearn.datasets import make_classification
from sklearn.model_selection import train_test_split

# Correlated features highlight MDI bias
X, y = make_classification(n_samples=1000, n_features=10, n_informative=3,
                            n_redundant=5, random_state=42)
X_tr, X_te, y_tr, y_te = train_test_split(X, y, test_size=0.2, random_state=42)

rf = RandomForestClassifier(n_estimators=200, random_state=42)
rf.fit(X_tr, y_tr)

gini_imp = rf.feature_importances_
perm = permutation_importance(rf, X_te, y_te, n_repeats=15, random_state=42)

fig, axes = plt.subplots(1, 2, figsize=(13, 5))
axes[0].bar(range(10), gini_imp); axes[0].set_title('Gini (MDI) Importance')
axes[1].bar(range(10), perm.importances_mean); axes[1].set_title('Permutation Importance')
for ax in axes:
    ax.set_xlabel('Feature index'); ax.set_ylabel('Importance')
plt.tight_layout(); plt.show()
print('Pearson r (Gini vs Perm):',
      round(np.corrcoef(gini_imp, perm.importances_mean)[0, 1], 3))
```

## Extra-Trees — Random Threshold Selection

Extremely Randomised Trees (Extra-Trees) push randomisation further: instead of finding the optimal threshold for each candidate feature, they draw a random threshold and pick the best among random (feature, threshold) pairs. This eliminates the threshold-optimisation step entirely, making each tree much faster to train. Extra-Trees typically match Random Forest accuracy on most datasets while training significantly faster.

```python
from sklearn.ensemble import RandomForestClassifier, ExtraTreesClassifier
from sklearn.datasets import make_classification
from sklearn.model_selection import cross_val_score
import time

X, y = make_classification(n_samples=5000, n_features=20, n_informative=10,
                            n_redundant=5, random_state=42)

results = {}
for name, clf in [
    ('RandomForest', RandomForestClassifier(n_estimators=200, random_state=42)),
    ('ExtraTrees',   ExtraTreesClassifier(n_estimators=200, random_state=42))
]:
    t0 = time.time()
    scores = cross_val_score(clf, X, y, cv=5, scoring='accuracy', n_jobs=-1)
    elapsed = time.time() - t0
    results[name] = {'mean': scores.mean(), 'std': scores.std(), 'time': elapsed}
    print(f'{name:<14} acc={scores.mean():.4f}±{scores.std():.4f}  time={elapsed:.2f}s')

ratio = results['RandomForest']['time'] / results['ExtraTrees']['time']
print(f'ExtraTrees is {ratio:.1f}x faster than RandomForest')
```

## Bias-Variance and Parallel Training

Unlike boosting (which reduces bias), bagging primarily reduces variance. Each tree is a high-variance, low-bias estimator (deep, unconstrained). Averaging B such trees reduces variance by a factor approaching 1/B as tree correlation ρ → 0. Bias stays the same as a single tree. This means Random Forests work best when individual trees are accurate but unstable — which is exactly why deep, unconstrained trees are preferred inside forests.

- Each tree is trained independently — trivially parallelisable with n_jobs=-1
- n_estimators: more trees always helps until OOB error plateaus (~200-500 sufficient)
- max_features: key diversity lever — smaller value = more decorrelation but weaker trees
- max_depth=None (default) is fine inside forests — depth is regularised by averaging
- min_samples_leaf=3-5 prevents very small leaves without harming much
- oob_score=True gives free validation — compare with held-out test accuracy

> **Gini Importance Bias in High-Cardinality Settings**: On datasets with mixed feature types (continuous + categorical with many categories), Gini importance systematically overestimates continuous features. Always cross-check with permutation importance on a held-out set, especially before reporting feature rankings to stakeholders.

> **Random Forest vs Extra-Trees Rule of Thumb**: Start with RandomForest. If training time is a bottleneck and accuracy is similar on your validation set, switch to ExtraTreesClassifier — it trains 2-5x faster with identical accuracy on most real-world datasets.

---

