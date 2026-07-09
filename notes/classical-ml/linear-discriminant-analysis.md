---
title: "Linear Discriminant Analysis (LDA)"
slug: "linear-discriminant-analysis"
description: "Derive LDA from Gaussian class-conditional distributions, understand Fisher's discriminant as a projection maximising class separability, compare LDA vs QDA vs logistic regression, and use LDA for dimensionality reduction."
tags: ["supervised-learning", "classical-ml"]
topic: "classical-ml"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"Linear Discriminant Analysis (LDA) assumes that each class generates data from a multivariate Gaussian distribution with class-specific mean but a shared covariance matrix: p(x|y=k) = N(μₖ, Σ). Applying Bayes\u0027 theorem and taking log-ratios, the decision boundary becomes linear in x because the quadratic terms in xᵀΣ⁻¹x cancel (shared Σ). LDA is both a classifier and a dimensionality reduction method: it finds at most K-1 directions that maximally separate K classes while minimising within-class spread."},{"type":"heading","level":2,"content":"Discriminant Function Derivation"},{"type":"text","content":"With class-conditional Gaussians and shared covariance, the log posterior is: log p(y=k|x) ∝ log πₖ - (1/2)(x-μₖ)ᵀΣ⁻¹(x-μₖ). Expanding: = log πₖ - (1/2)μₖᵀΣ⁻¹μₖ + xᵀΣ⁻¹μₖ - (1/2)xᵀΣ⁻¹x. The term -(1/2)xᵀΣ⁻¹x is the same for all classes and cancels in argmax. The linear discriminant function for class k is: δₖ(x) = xᵀΣ⁻¹μₖ - (1/2)μₖᵀΣ⁻¹μₖ + log πₖ. Classify x to argmax_k δₖ(x). The decision boundary between classes k and l is the set of x where δₖ(x) = δₗ(x), which is a hyperplane (linear in x) — hence \u0027Linear\u0027 Discriminant Analysis."},{"type":"heading","level":2,"content":"Within-Class and Between-Class Scatter Matrices"},{"type":"text","content":"The shared covariance (pooled within-class scatter) is SW = Σₖ Σᵢ∈Cₖ (xᵢ-μₖ)(xᵢ-μₖ)ᵀ / (n-K). The between-class scatter is SB = Σₖ nₖ(μₖ-μ)(μₖ-μ)ᵀ where μ is the global mean. Fisher\u0027s criterion maximises J(w) = wᵀSBw / wᵀSWw — the ratio of between-class to within-class projected variance. The solution is the generalised eigenvalue problem SW⁻¹SBw = λw, whose eigenvectors are the LDA directions. Since SB has rank at most K-1, there are at most K-1 nonzero eigenvalues and therefore at most K-1 useful discriminant dimensions. For binary classification, the single direction is w = SW⁻¹(μ₁-μ₂) — the Mahalanobis direction between class means."},{"type":"code","language":"python","content":"import numpy as np\nfrom sklearn.datasets import load_iris\nfrom sklearn.model_selection import train_test_split\nfrom sklearn.metrics import accuracy_score\n\nclass LDAFromScratch:\n    def fit(self, X, y):\n        self.classes_ = np.unique(y)\n        n, p = X.shape\n        self.priors_, self.means_ = {}, {}\n        Sw = np.zeros((p, p))\n        for c in self.classes_:\n            Xc = X[y == c]\n            self.priors_[c] = len(Xc) / n\n            self.means_[c]  = Xc.mean(axis=0)\n            diff = Xc - self.means_[c]\n            Sw += diff.T @ diff\n        self.Sigma_ = Sw / (n - len(self.classes_))  # pooled covariance\n        self.Sigma_inv_ = np.linalg.pinv(self.Sigma_)\n        return self\n\n    def _discriminant(self, x, c):\n        mu = self.means_[c]\n        return (x @ self.Sigma_inv_ @ mu\n                - 0.5 * mu @ self.Sigma_inv_ @ mu\n                + np.log(self.priors_[c]))\n\n    def predict(self, X):\n        scores = np.array([[self._discriminant(x, c) for c in self.classes_]\n                           for x in X])\n        return self.classes_[np.argmax(scores, axis=1)]\n\nX, y = load_iris(return_X_y=True)\nX_tr, X_te, y_tr, y_te = train_test_split(X, y, test_size=0.3, random_state=42)\nlda_s = LDAFromScratch().fit(X_tr, y_tr)\nprint(f\u0027LDA scratch: {accuracy_score(y_te, lda_s.predict(X_te)):.4f}\u0027)"},{"type":"heading","level":2,"content":"Fisher\u0027s Discriminant and Dimensionality Reduction"},{"type":"text","content":"LDA as dimensionality reduction projects K-class data onto K-1 discriminant dimensions that maximise class separability. For the Iris dataset (K=3 classes, p=4 features), LDA finds exactly 2 discriminant directions, compressing 4D data into 2D while preserving most of the class separation. This is far more useful for classification than PCA\u0027s 2D projection, which maximises total variance regardless of class labels. After projecting to LDA space, a simple classifier (linear, kNN) applied to the low-dimensional representation often achieves near-optimal accuracy."},{"type":"code","language":"python","content":"import numpy as np\nfrom sklearn.discriminant_analysis import LinearDiscriminantAnalysis\nfrom sklearn.datasets import load_iris\nfrom sklearn.model_selection import train_test_split\nfrom sklearn.metrics import accuracy_score\n\nX, y = load_iris(return_X_y=True)\nX_tr, X_te, y_tr, y_te = train_test_split(X, y, test_size=0.3, random_state=42)\n\nlda = LinearDiscriminantAnalysis(solver=\u0027svd\u0027, store_covariance=True)\nlda.fit(X_tr, y_tr)\nprint(f\u0027LDA classifier accuracy: {accuracy_score(y_te, lda.predict(X_te)):.4f}\u0027)\nprint(f\u0027Explained variance ratio: {lda.explained_variance_ratio_}\u0027)\n\n# LDA for dimensionality reduction (K-1 = 2 dims for 3-class problem)\nX_lda_tr = lda.transform(X_tr)\nX_lda_te = lda.transform(X_te)\nprint(f\u0027Projected shape: {X_lda_tr.shape}  (from {X_tr.shape[1]} -\u003e {X_lda_tr.shape[1]} dims)\u0027)\nfor c in np.unique(y_tr):\n    mean_proj = X_lda_tr[y_tr == c].mean(axis=0)\n    print(f\u0027  Class {c} mean in LDA space: {mean_proj.round(3)}\u0027)"},{"type":"code","language":"python","content":"import numpy as np\nfrom sklearn.decomposition import PCA\nfrom sklearn.discriminant_analysis import LinearDiscriminantAnalysis\nfrom sklearn.datasets import load_wine\nfrom sklearn.model_selection import train_test_split\nfrom sklearn.linear_model import LogisticRegression\nfrom sklearn.metrics import accuracy_score\n\nX, y = load_wine(return_X_y=True)\nX_tr, X_te, y_tr, y_te = train_test_split(X, y, test_size=0.3, random_state=42)\n\n# PCA to 2D then classify\npca = PCA(n_components=2)\nX_pca_tr = pca.fit_transform(X_tr)\nX_pca_te = pca.transform(X_te)\nlr_pca = LogisticRegression(max_iter=500).fit(X_pca_tr, y_tr)\n\n# LDA to K-1=2D then classify\nlda = LinearDiscriminantAnalysis(n_components=2)\nX_lda_tr = lda.fit_transform(X_tr, y_tr)\nX_lda_te = lda.transform(X_te)\nlr_lda = LogisticRegression(max_iter=500).fit(X_lda_tr, y_tr)\n\n# Full LDA classifier\nlda_full = LinearDiscriminantAnalysis().fit(X_tr, y_tr)\n\nprint(f\u0027LR on 2 PCA dims:      {accuracy_score(y_te, lr_pca.predict(X_pca_te)):.4f}\u0027)\nprint(f\u0027LR on 2 LDA dims:      {accuracy_score(y_te, lr_lda.predict(X_lda_te)):.4f}\u0027)\nprint(f\u0027Full LDA classifier:   {accuracy_score(y_te, lda_full.predict(X_te)):.4f}\u0027)"},{"type":"callout","variant":"info","title":"LDA vs PCA — Same Goal, Different Criterion","content":"PCA finds directions of maximum variance in X, ignoring class labels. LDA finds directions of maximum class separability — between-class variance relative to within-class variance. When classes are well-separated but not aligned with the highest-variance directions (common in real datasets), LDA projections are dramatically better for classification. Use PCA when the goal is compression or unsupervised structure; use LDA when you have class labels and want discriminative dimensionality reduction."},{"type":"code","language":"python","content":"import numpy as np\nfrom sklearn.discriminant_analysis import LinearDiscriminantAnalysis, QuadraticDiscriminantAnalysis\nfrom sklearn.linear_model import LogisticRegression\nfrom sklearn.model_selection import cross_val_score\n\nnp.random.seed(42)\n# Case 1: same covariance — LDA assumption satisfied\nfrom sklearn.datasets import make_classification\nX1, y1 = make_classification(n_samples=500, n_features=10, n_informative=5, random_state=42)\n\n# Case 2: class-specific covariance — LDA assumption violated, QDA should win\nX2_0 = np.random.multivariate_normal([0]*6, np.eye(6)*0.5, 250)\nX2_1 = np.random.multivariate_normal([2]*6, np.diag([2, 3, 1, 0.5, 4, 1]), 250)\nX2, y2 = np.vstack([X2_0, X2_1]), np.array([0]*250 + [1]*250)\n\nfor dname, Xd, yd in [(\u0027Equal covariance\u0027, X1, y1), (\u0027Different covariance\u0027, X2, y2)]:\n    print(f\u0027\\n{dname}:\u0027)\n    for name, clf in [(\u0027LDA\u0027, LinearDiscriminantAnalysis()),\n                       (\u0027QDA\u0027, QuadraticDiscriminantAnalysis()),\n                       (\u0027LR\u0027,  LogisticRegression(max_iter=500))]:\n        score = cross_val_score(clf, Xd, yd, cv=5, scoring=\u0027accuracy\u0027).mean()\n        print(f\u0027  {name}: {score:.4f}\u0027)"},{"type":"heading","level":2,"content":"Regularised LDA for Small Sample Sizes"},{"type":"text","content":"When n \u003c p (more features than samples), the pooled within-class scatter matrix SW is singular and cannot be inverted. Regularised LDA replaces SW with (1-γ)SW + γ·(trace(SW)/p)·I for γ ∈ [0,1]. When γ=1, the result is a scaled identity — equivalent to assuming all features are uncorrelated with equal variance (identical to Gaussian Naive Bayes). sklearn\u0027s LinearDiscriminantAnalysis with solver=\u0027lsqr\u0027 and shrinkage=\u0027auto\u0027 uses the analytically optimal Ledoit-Wolf shrinkage estimator, which chooses γ to minimise the Frobenius norm of the estimation error."},{"type":"table","headers":["Method","Assumption","Decision Boundary","Small n?","Best Use Case"],"rows":[["LDA","Shared Gaussian covariance Σ","Linear hyperplane","Yes — use regularised LDA","Well-separated classes, p moderate"],["QDA","Class-specific Gaussian covariance Σₖ","Quadratic surface","No — needs n \u003e\u003e p·K","Classes with different spread/orientation"],["Logistic Regression","None — discriminative","Linear hyperplane","Yes with L2 regularisation","General binary/multiclass, no distributional assumption"],["Gaussian Naive Bayes","Diagonal covariance (independence)","Quadratic or linear","Yes — fewest parameters","High-d, small n, streaming, online"]]},{"type":"list","ordered":false,"items":["LDA requires n \u003e p for a full-rank pooled covariance matrix; use shrinkage=\u0027auto\u0027 for high-d data.","For K classes, LDA produces at most K-1 discriminant directions — use for dimensionality reduction first.","When class covariances differ substantially, QDA produces better boundaries but needs more data.","LDA is equivalent to Gaussian Naive Bayes with equal, non-diagonal covariance across classes.","Check LDA assumptions: plot class-conditional distributions and test for normality with Shapiro-Wilk.","For imbalanced classes, adjust priors_=class_frequencies to avoid majority-class bias."]},{"type":"text","content":"LDA remains a powerful baseline for multi-class classification when Gaussian assumptions hold approximately. Its closed-form solution, lack of hyperparameters (beyond regularisation strength), and natural dimensionality reduction capability make it a valuable first step in any classification pipeline. When LDA performs well, it suggests the data is approximately Gaussian with shared covariance — a result worth knowing before reaching for more complex models."},{"type":"callout","variant":"warning","title":"LDA Normality Assumption in Practice","content":"LDA assumes class-conditional Gaussian distributions. Common violations: skewed features (apply log transform), heavy tails (trim outliers), multimodal within-class distributions (consider mixture models). However, like Naive Bayes, LDA is often robust to mild normality violations in classification tasks because the argmax of the discriminant function can still be correct. For severely non-Gaussian data, logistic regression (discriminative, no distributional assumption) is the safer choice."},{"type":"text","content":"Multi-class LDA with K classes finds at most K-1 discriminant directions because the between-class scatter matrix SB has rank at most K-1. For K=2 the single direction is w = SW^{-1}(mu_1 - mu_2). For K=10 (digit recognition), LDA provides a 9D subspace capturing all class-discriminative information. Projecting to this subspace and applying a nearest-centroid classifier is a competitive baseline for moderate-dimensional multi-class problems and is used in face recognition (Fisherfaces)."},{"type":"text","content":"LDA has a deep connection to logistic regression: both produce linear decision boundaries but via different estimation principles. LDA estimates the joint distribution p(x,y) and derives the boundary analytically (generative); logistic regression maximises the conditional likelihood p(y|x) directly (discriminative). When the Gaussian assumption holds, LDA is more statistically efficient. When it does not hold, logistic regression is more robust. Always try both as baselines before reaching for more complex models."},{"type":"text","content":"Shrinkage LDA (using the Ledoit-Wolf optimal estimator for the covariance matrix) is essential in high-dimensional settings where p \u003e\u003e n. With LinearDiscriminantAnalysis(solver=\u0027lsqr\u0027, shrinkage=\u0027auto\u0027), the optimal shrinkage parameter gamma is computed analytically from the data — no cross-validation needed. This makes regularised LDA a practical default for genomics, neuroimaging, and text where the standard pooled covariance would be singular. The result interpolates between the full pooled covariance (gamma=0) and a scaled identity (gamma=1, equivalent to Gaussian Naive Bayes)."},{"type":"divider"}]"
---
# Linear Discriminant Analysis (LDA)

Linear Discriminant Analysis (LDA) assumes that each class generates data from a multivariate Gaussian distribution with class-specific mean but a shared covariance matrix: p(x|y=k) = N(μₖ, Σ). Applying Bayes' theorem and taking log-ratios, the decision boundary becomes linear in x because the quadratic terms in xᵀΣ⁻¹x cancel (shared Σ). LDA is both a classifier and a dimensionality reduction method: it finds at most K-1 directions that maximally separate K classes while minimising within-class spread.

## Discriminant Function Derivation

With class-conditional Gaussians and shared covariance, the log posterior is: log p(y=k|x) ∝ log πₖ - (1/2)(x-μₖ)ᵀΣ⁻¹(x-μₖ). Expanding: = log πₖ - (1/2)μₖᵀΣ⁻¹μₖ + xᵀΣ⁻¹μₖ - (1/2)xᵀΣ⁻¹x. The term -(1/2)xᵀΣ⁻¹x is the same for all classes and cancels in argmax. The linear discriminant function for class k is: δₖ(x) = xᵀΣ⁻¹μₖ - (1/2)μₖᵀΣ⁻¹μₖ + log πₖ. Classify x to argmax_k δₖ(x). The decision boundary between classes k and l is the set of x where δₖ(x) = δₗ(x), which is a hyperplane (linear in x) — hence 'Linear' Discriminant Analysis.

## Within-Class and Between-Class Scatter Matrices

The shared covariance (pooled within-class scatter) is SW = Σₖ Σᵢ∈Cₖ (xᵢ-μₖ)(xᵢ-μₖ)ᵀ / (n-K). The between-class scatter is SB = Σₖ nₖ(μₖ-μ)(μₖ-μ)ᵀ where μ is the global mean. Fisher's criterion maximises J(w) = wᵀSBw / wᵀSWw — the ratio of between-class to within-class projected variance. The solution is the generalised eigenvalue problem SW⁻¹SBw = λw, whose eigenvectors are the LDA directions. Since SB has rank at most K-1, there are at most K-1 nonzero eigenvalues and therefore at most K-1 useful discriminant dimensions. For binary classification, the single direction is w = SW⁻¹(μ₁-μ₂) — the Mahalanobis direction between class means.

```python
import numpy as np
from sklearn.datasets import load_iris
from sklearn.model_selection import train_test_split
from sklearn.metrics import accuracy_score

class LDAFromScratch:
    def fit(self, X, y):
        self.classes_ = np.unique(y)
        n, p = X.shape
        self.priors_, self.means_ = {}, {}
        Sw = np.zeros((p, p))
        for c in self.classes_:
            Xc = X[y == c]
            self.priors_[c] = len(Xc) / n
            self.means_[c]  = Xc.mean(axis=0)
            diff = Xc - self.means_[c]
            Sw += diff.T @ diff
        self.Sigma_ = Sw / (n - len(self.classes_))  # pooled covariance
        self.Sigma_inv_ = np.linalg.pinv(self.Sigma_)
        return self

    def _discriminant(self, x, c):
        mu = self.means_[c]
        return (x @ self.Sigma_inv_ @ mu
                - 0.5 * mu @ self.Sigma_inv_ @ mu
                + np.log(self.priors_[c]))

    def predict(self, X):
        scores = np.array([[self._discriminant(x, c) for c in self.classes_]
                           for x in X])
        return self.classes_[np.argmax(scores, axis=1)]

X, y = load_iris(return_X_y=True)
X_tr, X_te, y_tr, y_te = train_test_split(X, y, test_size=0.3, random_state=42)
lda_s = LDAFromScratch().fit(X_tr, y_tr)
print(f'LDA scratch: {accuracy_score(y_te, lda_s.predict(X_te)):.4f}')
```

## Fisher's Discriminant and Dimensionality Reduction

LDA as dimensionality reduction projects K-class data onto K-1 discriminant dimensions that maximise class separability. For the Iris dataset (K=3 classes, p=4 features), LDA finds exactly 2 discriminant directions, compressing 4D data into 2D while preserving most of the class separation. This is far more useful for classification than PCA's 2D projection, which maximises total variance regardless of class labels. After projecting to LDA space, a simple classifier (linear, kNN) applied to the low-dimensional representation often achieves near-optimal accuracy.

```python
import numpy as np
from sklearn.discriminant_analysis import LinearDiscriminantAnalysis
from sklearn.datasets import load_iris
from sklearn.model_selection import train_test_split
from sklearn.metrics import accuracy_score

X, y = load_iris(return_X_y=True)
X_tr, X_te, y_tr, y_te = train_test_split(X, y, test_size=0.3, random_state=42)

lda = LinearDiscriminantAnalysis(solver='svd', store_covariance=True)
lda.fit(X_tr, y_tr)
print(f'LDA classifier accuracy: {accuracy_score(y_te, lda.predict(X_te)):.4f}')
print(f'Explained variance ratio: {lda.explained_variance_ratio_}')

# LDA for dimensionality reduction (K-1 = 2 dims for 3-class problem)
X_lda_tr = lda.transform(X_tr)
X_lda_te = lda.transform(X_te)
print(f'Projected shape: {X_lda_tr.shape}  (from {X_tr.shape[1]} -> {X_lda_tr.shape[1]} dims)')
for c in np.unique(y_tr):
    mean_proj = X_lda_tr[y_tr == c].mean(axis=0)
    print(f'  Class {c} mean in LDA space: {mean_proj.round(3)}')
```

```python
import numpy as np
from sklearn.decomposition import PCA
from sklearn.discriminant_analysis import LinearDiscriminantAnalysis
from sklearn.datasets import load_wine
from sklearn.model_selection import train_test_split
from sklearn.linear_model import LogisticRegression
from sklearn.metrics import accuracy_score

X, y = load_wine(return_X_y=True)
X_tr, X_te, y_tr, y_te = train_test_split(X, y, test_size=0.3, random_state=42)

# PCA to 2D then classify
pca = PCA(n_components=2)
X_pca_tr = pca.fit_transform(X_tr)
X_pca_te = pca.transform(X_te)
lr_pca = LogisticRegression(max_iter=500).fit(X_pca_tr, y_tr)

# LDA to K-1=2D then classify
lda = LinearDiscriminantAnalysis(n_components=2)
X_lda_tr = lda.fit_transform(X_tr, y_tr)
X_lda_te = lda.transform(X_te)
lr_lda = LogisticRegression(max_iter=500).fit(X_lda_tr, y_tr)

# Full LDA classifier
lda_full = LinearDiscriminantAnalysis().fit(X_tr, y_tr)

print(f'LR on 2 PCA dims:      {accuracy_score(y_te, lr_pca.predict(X_pca_te)):.4f}')
print(f'LR on 2 LDA dims:      {accuracy_score(y_te, lr_lda.predict(X_lda_te)):.4f}')
print(f'Full LDA classifier:   {accuracy_score(y_te, lda_full.predict(X_te)):.4f}')
```

> **LDA vs PCA — Same Goal, Different Criterion**: PCA finds directions of maximum variance in X, ignoring class labels. LDA finds directions of maximum class separability — between-class variance relative to within-class variance. When classes are well-separated but not aligned with the highest-variance directions (common in real datasets), LDA projections are dramatically better for classification. Use PCA when the goal is compression or unsupervised structure; use LDA when you have class labels and want discriminative dimensionality reduction.

```python
import numpy as np
from sklearn.discriminant_analysis import LinearDiscriminantAnalysis, QuadraticDiscriminantAnalysis
from sklearn.linear_model import LogisticRegression
from sklearn.model_selection import cross_val_score

np.random.seed(42)
# Case 1: same covariance — LDA assumption satisfied
from sklearn.datasets import make_classification
X1, y1 = make_classification(n_samples=500, n_features=10, n_informative=5, random_state=42)

# Case 2: class-specific covariance — LDA assumption violated, QDA should win
X2_0 = np.random.multivariate_normal([0]*6, np.eye(6)*0.5, 250)
X2_1 = np.random.multivariate_normal([2]*6, np.diag([2, 3, 1, 0.5, 4, 1]), 250)
X2, y2 = np.vstack([X2_0, X2_1]), np.array([0]*250 + [1]*250)

for dname, Xd, yd in [('Equal covariance', X1, y1), ('Different covariance', X2, y2)]:
    print(f'\n{dname}:')
    for name, clf in [('LDA', LinearDiscriminantAnalysis()),
                       ('QDA', QuadraticDiscriminantAnalysis()),
                       ('LR',  LogisticRegression(max_iter=500))]:
        score = cross_val_score(clf, Xd, yd, cv=5, scoring='accuracy').mean()
        print(f'  {name}: {score:.4f}')
```

## Regularised LDA for Small Sample Sizes

When n < p (more features than samples), the pooled within-class scatter matrix SW is singular and cannot be inverted. Regularised LDA replaces SW with (1-γ)SW + γ·(trace(SW)/p)·I for γ ∈ [0,1]. When γ=1, the result is a scaled identity — equivalent to assuming all features are uncorrelated with equal variance (identical to Gaussian Naive Bayes). sklearn's LinearDiscriminantAnalysis with solver='lsqr' and shrinkage='auto' uses the analytically optimal Ledoit-Wolf shrinkage estimator, which chooses γ to minimise the Frobenius norm of the estimation error.

| Method | Assumption | Decision Boundary | Small n? | Best Use Case |
| --- | --- | --- | --- | --- |
| LDA | Shared Gaussian covariance Σ | Linear hyperplane | Yes — use regularised LDA | Well-separated classes, p moderate |
| QDA | Class-specific Gaussian covariance Σₖ | Quadratic surface | No — needs n >> p·K | Classes with different spread/orientation |
| Logistic Regression | None — discriminative | Linear hyperplane | Yes with L2 regularisation | General binary/multiclass, no distributional assumption |
| Gaussian Naive Bayes | Diagonal covariance (independence) | Quadratic or linear | Yes — fewest parameters | High-d, small n, streaming, online |

- LDA requires n > p for a full-rank pooled covariance matrix; use shrinkage='auto' for high-d data.
- For K classes, LDA produces at most K-1 discriminant directions — use for dimensionality reduction first.
- When class covariances differ substantially, QDA produces better boundaries but needs more data.
- LDA is equivalent to Gaussian Naive Bayes with equal, non-diagonal covariance across classes.
- Check LDA assumptions: plot class-conditional distributions and test for normality with Shapiro-Wilk.
- For imbalanced classes, adjust priors_=class_frequencies to avoid majority-class bias.

LDA remains a powerful baseline for multi-class classification when Gaussian assumptions hold approximately. Its closed-form solution, lack of hyperparameters (beyond regularisation strength), and natural dimensionality reduction capability make it a valuable first step in any classification pipeline. When LDA performs well, it suggests the data is approximately Gaussian with shared covariance — a result worth knowing before reaching for more complex models.

> **LDA Normality Assumption in Practice**: LDA assumes class-conditional Gaussian distributions. Common violations: skewed features (apply log transform), heavy tails (trim outliers), multimodal within-class distributions (consider mixture models). However, like Naive Bayes, LDA is often robust to mild normality violations in classification tasks because the argmax of the discriminant function can still be correct. For severely non-Gaussian data, logistic regression (discriminative, no distributional assumption) is the safer choice.

Multi-class LDA with K classes finds at most K-1 discriminant directions because the between-class scatter matrix SB has rank at most K-1. For K=2 the single direction is w = SW^{-1}(mu_1 - mu_2). For K=10 (digit recognition), LDA provides a 9D subspace capturing all class-discriminative information. Projecting to this subspace and applying a nearest-centroid classifier is a competitive baseline for moderate-dimensional multi-class problems and is used in face recognition (Fisherfaces).

LDA has a deep connection to logistic regression: both produce linear decision boundaries but via different estimation principles. LDA estimates the joint distribution p(x,y) and derives the boundary analytically (generative); logistic regression maximises the conditional likelihood p(y|x) directly (discriminative). When the Gaussian assumption holds, LDA is more statistically efficient. When it does not hold, logistic regression is more robust. Always try both as baselines before reaching for more complex models.

Shrinkage LDA (using the Ledoit-Wolf optimal estimator for the covariance matrix) is essential in high-dimensional settings where p >> n. With LinearDiscriminantAnalysis(solver='lsqr', shrinkage='auto'), the optimal shrinkage parameter gamma is computed analytically from the data — no cross-validation needed. This makes regularised LDA a practical default for genomics, neuroimaging, and text where the standard pooled covariance would be singular. The result interpolates between the full pooled covariance (gamma=0) and a scaled identity (gamma=1, equivalent to Gaussian Naive Bayes).

---

