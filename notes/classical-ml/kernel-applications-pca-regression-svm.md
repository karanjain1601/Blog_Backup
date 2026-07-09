---
title: "Kernel PCA, Kernel Ridge Regression, and Kernel SVM"
slug: "kernel-applications-pca-regression-svm"
description: "How to kernelize classical linear methods using the dual formulation: kernel ridge regression, kernel PCA, and kernel SVM. Covers the kernelization recipe, O(n²) memory bottlenecks, and Nyström approximation for large-scale kernel methods."
tags: ["kernel-methods", "gaussian-processes", "classical-ml"]
topic: "classical-ml"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"The kernel trick enables any algorithm that can be written in terms of dot products to operate in an infinite-dimensional feature space at the cost of only n×n kernel matrix computations. This section covers three canonical kernelized algorithms — kernel ridge regression (KRR), kernel PCA, and kernel SVM — and explains the shared kernelization recipe that underlies all of them. The main practical bottleneck is the O(n²) memory for storing the kernel matrix, addressed by the Nyström approximation."},{"type":"heading","level":2,"content":"The Kernelization Recipe"},{"type":"text","content":"Every linear algorithm that operates on inner products can be kernelized in three steps: (1) derive the dual formulation in terms of ⟨xᵢ, xⱼ⟩; (2) replace every inner product ⟨xᵢ, xⱼ⟩ with k(xᵢ, xⱼ); (3) solve the dual problem in terms of the kernel matrix K. The resulting algorithm implicitly operates in the feature space defined by k — which can be infinite-dimensional — while the computation only requires evaluating n² kernel values. This is the kernel trick."},{"type":"math","display":true,"content":"\\langle \\phi(x_i), \\phi(x_j) \\rangle_{H_k} = k(x_i, x_j) \\quad \\Rightarrow \\quad \\text{replace } x_i^\\top x_j \\mapsto k(x_i, x_j) \\text{ in dual}"},{"type":"callout","variant":"info","title":"Why the Kernel Trick Is Powerful","content":"The RBF kernel corresponds to an infinite-dimensional feature map, yet computing k(x, z) = exp(−‖x−z‖²/2ℓ²) costs only O(d) operations (d = input dimension). Without the kernel trick, working with the infinite-dimensional feature map would be impossible. With it, you get the expressive power of an infinite feature space at O(d) cost per kernel evaluation."},{"type":"heading","level":2,"content":"Kernel Ridge Regression"},{"type":"text","content":"Ridge regression in primal form solves minw ‖Xw−y‖² + λ‖w‖². Using the representer theorem, the dual form is: find α such that f*(x) = Σᵢ αᵢ k(xᵢ, x). Substituting into the objective and differentiating gives α = (K+λI)⁻¹y. Prediction at new x* requires computing k(xᵢ, x*) for all training points: ŷ* = k*ᵀα where (k*)ᵢ = k(xᵢ, x*). Training cost is O(n³) for the matrix solve; prediction is O(n) kernel evaluations per test point."},{"type":"math","display":true,"content":"\\boldsymbol{\\alpha} = (K + \\lambda I)^{-1}\\mathbf{y}, \\qquad \\hat{y}(x^*) = \\mathbf{k}_*^\\top \\boldsymbol{\\alpha}, \\quad (\\mathbf{k}_*)_i = k(x_i, x^*)"},{"type":"heading","level":2,"content":"Kernel PCA"},{"type":"text","content":"Standard PCA finds a linear subspace of maximum variance. Kernel PCA applies PCA in the RKHS feature space φ(x), enabling nonlinear dimensionality reduction. The algorithm: (1) center the kernel matrix K̃ = K − 1ₙKᵀ − K1ₙ + 1ₙK1ₙᵀ; (2) eigendecompose K̃ = UΛUᵀ; (3) project new points using the eigenvectors. The resulting components capture nonlinear structure in the data — for example, kernel PCA with an RBF kernel can unfold a Swiss roll or separate concentric rings that linear PCA cannot."},{"type":"heading","level":2,"content":"Kernel SVM"},{"type":"text","content":"The SVM dual maximizes Σᵢ αᵢ − ½ Σᵢⱼ αᵢαⱼyᵢyⱼ k(xᵢ,xⱼ) subject to 0 ≤ αᵢ ≤ C and Σᵢ αᵢyᵢ = 0. Points with αᵢ \u003e 0 are support vectors. The decision function f(x) = Σᵢ αᵢyᵢk(xᵢ,x) + b only involves the support vectors (often sparse). Kernel SVM requires solving an n×n QP but the sparsity of the solution means prediction uses far fewer than n kernel evaluations. The C parameter trades off margin width against training error."},{"type":"math","display":true,"content":"f(x) = \\sum_{i \\in SV} \\alpha_i y_i\\, k(x_i, x) + b, \\quad \\alpha_i \u003e 0 \\text{ only for support vectors}"},{"type":"heading","level":2,"content":"Computational Bottlenecks"},{"type":"text","content":"All exact kernel methods share the same O(n²) memory bottleneck: storing the full n×n kernel matrix. For n=10,000 points with float64, this is 800 MB; for n=100,000 it is 80 GB — infeasible on a single machine. Training costs range from O(n²·d) for kernel evaluation to O(n³) for matrix solves and eigendecompositions. These costs make exact kernel methods suitable for n up to ~20,000 points and motivate approximation methods for larger datasets."},{"type":"heading","level":2,"content":"Nyström Approximation"},{"type":"text","content":"The Nyström method approximates the full kernel matrix K ≈ K_{nm} K_{mm}⁻¹ K_{mn} using only m ≪ n landmark points. The landmarks are selected randomly or by greedy selection. This reduces memory from O(n²) to O(nm) and training cost from O(n³) to O(nm²). The approximated kernel features can then be fed to any linear model. Nyström provides a principled low-rank approximation with a convergence guarantee: ‖K − K̃‖ → 0 as m → n."},{"type":"heading","level":2,"content":"Code Examples"},{"type":"code","language":"python","content":"import numpy as np\nfrom sklearn.kernel_ridge import KernelRidge\nfrom sklearn.datasets import make_regression\nfrom sklearn.preprocessing import StandardScaler\nfrom sklearn.metrics import mean_squared_error\n\ndef rbf_gram(X1, X2, gamma=1.0):\n    diff = X1[:, None, :] - X2[None, :, :]\n    return np.exp(-gamma * np.sum(diff**2, axis=-1))\n\ndef krr_from_scratch(X_train, y_train, X_test, gamma=1.0, lam=0.1):\n    K_train = rbf_gram(X_train, X_train, gamma)\n    alpha = np.linalg.solve(K_train + lam * np.eye(len(y_train)), y_train)\n    K_test = rbf_gram(X_test, X_train, gamma)\n    return K_test @ alpha\n\nX, y = make_regression(n_samples=200, n_features=10, noise=0.5, random_state=0)\nsc = StandardScaler()\nX = sc.fit_transform(X)\nX_tr, X_te = X[:150], X[150:]\ny_tr, y_te = y[:150], y[150:]\n\ny_scratch = krr_from_scratch(X_tr, y_tr, X_te, gamma=0.5, lam=0.1)\nkrr = KernelRidge(kernel=\u0027rbf\u0027, alpha=0.1, gamma=0.5)\nkrr.fit(X_tr, y_tr)\ny_sklearn = krr.predict(X_te)\n\nprint(f\u0027From-scratch KRR MSE: {mean_squared_error(y_te, y_scratch):.4f}\u0027)\nprint(f\u0027sklearn KRR      MSE: {mean_squared_error(y_te, y_sklearn):.4f}\u0027)\nprint(f\u0027Max diff: {np.abs(y_scratch - y_sklearn).max():.2e}\u0027)"},{"type":"code","language":"python","content":"import numpy as np\nimport matplotlib.pyplot as plt\nfrom sklearn.datasets import make_swiss_roll\nfrom sklearn.decomposition import KernelPCA, PCA\n\nX, color = make_swiss_roll(n_samples=1000, noise=0.1, random_state=42)\n\npca = PCA(n_components=2)\nX_pca = pca.fit_transform(X)\n\nkpca = KernelPCA(n_components=2, kernel=\u0027rbf\u0027, gamma=0.04)\nX_kpca = kpca.fit_transform(X)\n\nfig, axes = plt.subplots(1, 3, figsize=(15, 4))\naxes[0].scatter(X[:, 0], X[:, 2], c=color, cmap=\u0027rainbow\u0027, s=5)\naxes[0].set_title(\u0027Original Swiss Roll (x-z view)\u0027)\n\naxes[1].scatter(X_pca[:, 0], X_pca[:, 1], c=color, cmap=\u0027rainbow\u0027, s=5)\naxes[1].set_title(\u0027Linear PCA (fails to unfold)\u0027)\n\naxes[2].scatter(X_kpca[:, 0], X_kpca[:, 1], c=color, cmap=\u0027rainbow\u0027, s=5)\naxes[2].set_title(\u0027Kernel PCA RBF (unfolds manifold)\u0027)\n\nplt.tight_layout()\nplt.savefig(\u0027kernel_pca.png\u0027, dpi=100)\nprint(\u0027Saved kernel_pca.png\u0027)"},{"type":"code","language":"python","content":"import numpy as np\nimport matplotlib.pyplot as plt\nfrom sklearn.svm import SVC\nfrom sklearn.metrics import accuracy_score\n\n# XOR dataset: not linearly separable\nrng = np.random.RandomState(42)\nX_pos = np.vstack([rng.randn(50, 2) + [1, 1], rng.randn(50, 2) + [-1, -1]])\nX_neg = np.vstack([rng.randn(50, 2) + [1, -1], rng.randn(50, 2) + [-1,  1]])\nX = np.vstack([X_pos, X_neg])\ny = np.hstack([np.ones(100), -np.ones(100)])\n\nkernels = {\u0027linear\u0027: {}, \u0027poly\u0027: {\u0027degree\u0027: 3, \u0027coef0\u0027: 1}, \u0027rbf\u0027: {\u0027gamma\u0027: 0.5}}\nresults = {}\nfor name, kwargs in kernels.items():\n    clf = SVC(kernel=name, C=1.0, **kwargs)\n    clf.fit(X, y)\n    acc = accuracy_score(y, clf.predict(X))\n    results[name] = (clf, acc)\n    print(f\u0027kernel={name}: accuracy={acc:.3f}\u0027)\n\nfig, axes = plt.subplots(1, 3, figsize=(14, 4))\nxx, yy = np.meshgrid(np.linspace(-4, 4, 200), np.linspace(-4, 4, 200))\nfor ax, (name, (clf, acc)) in zip(axes, results.items()):\n    Z = clf.predict(np.c_[xx.ravel(), yy.ravel()]).reshape(xx.shape)\n    ax.contourf(xx, yy, Z, alpha=0.3)\n    ax.scatter(X[:, 0], X[:, 1], c=y, cmap=\u0027bwr\u0027, s=10)\n    ax.set_title(f\u0027{name} (acc={acc:.2f})\u0027)\nplt.tight_layout()\nplt.savefig(\u0027kernel_svm_xor.png\u0027, dpi=100)"},{"type":"code","language":"python","content":"import numpy as np\nfrom sklearn.kernel_approximation import Nystroem\nfrom sklearn.linear_model import Ridge\nfrom sklearn.pipeline import make_pipeline\nfrom sklearn.metrics import mean_squared_error\nfrom sklearn.datasets import make_regression\nfrom sklearn.preprocessing import StandardScaler\nimport time\n\nX, y = make_regression(n_samples=2000, n_features=20, noise=0.5, random_state=0)\nsc = StandardScaler()\nX = sc.fit_transform(X)\nX_tr, X_te = X[:1500], X[1500:]\ny_tr, y_te = y[:1500], y[1500:]\n\nprint(f\u0027{\"n_components\":\u003c14} {\"MSE\":\u003c10} {\"Time (s)\":\u003c10}\u0027)\nprint(\u0027-\u0027 * 36)\nfor n_comp in [50, 100, 200, 500]:\n    t0 = time.time()\n    pipe = make_pipeline(\n        Nystroem(kernel=\u0027rbf\u0027, gamma=0.5, n_components=n_comp, random_state=0),\n        Ridge(alpha=1.0)\n    )\n    pipe.fit(X_tr, y_tr)\n    mse = mean_squared_error(y_te, pipe.predict(X_te))\n    elapsed = time.time() - t0\n    print(f\u0027{n_comp:\u003c14} {mse:\u003c10.4f} {elapsed:\u003c10.3f}\u0027)\nprint(f\u0027Exact kernel matrix: {1500**2 * 8 / 1e6:.0f} MB vs Nystroem(m=200): {1500*200*8/1e6:.1f} MB\u0027)"},{"type":"heading","level":2,"content":"Method Comparison"},{"type":"table","headers":["Method","Dual Form","Training Cost","Prediction Cost","Best For"],"rows":[["Kernel Ridge Regression","α = (K+λI)⁻¹y","O(n³) matrix solve","O(n·d) kernel evals per point","Small-n smooth regression"],["Kernel PCA","Eigendecompose centered K","O(n³) eigendecomp","O(n·p) projections per point","Nonlinear dimensionality reduction"],["Kernel SVM","QP over α with box constraints","O(n²) to O(n³) QP","O(n_sv·d) kernel evals (sparse)","Classification with margin"],["Nyström Approx.","K ≈ K_{nm}K_{mm}⁻¹K_{mn}","O(nm²) with m≪n","O(m) feature vector, O(1) model","Large-scale kernel methods n\u003e10k"]]},{"type":"text","content":"All three methods share the same kernel matrix bottleneck. For n ≤ 5,000 use exact methods; for larger n use Nyström approximation or random Fourier features (Rahimi \u0026 Recht, 2007). The choice between KRR, kPCA, and kSVM depends on the task: regression, dimensionality reduction, or classification."}]"
---
# Kernel PCA, Kernel Ridge Regression, and Kernel SVM

The kernel trick enables any algorithm that can be written in terms of dot products to operate in an infinite-dimensional feature space at the cost of only n×n kernel matrix computations. This section covers three canonical kernelized algorithms — kernel ridge regression (KRR), kernel PCA, and kernel SVM — and explains the shared kernelization recipe that underlies all of them. The main practical bottleneck is the O(n²) memory for storing the kernel matrix, addressed by the Nyström approximation.

## The Kernelization Recipe

Every linear algorithm that operates on inner products can be kernelized in three steps: (1) derive the dual formulation in terms of ⟨xᵢ, xⱼ⟩; (2) replace every inner product ⟨xᵢ, xⱼ⟩ with k(xᵢ, xⱼ); (3) solve the dual problem in terms of the kernel matrix K. The resulting algorithm implicitly operates in the feature space defined by k — which can be infinite-dimensional — while the computation only requires evaluating n² kernel values. This is the kernel trick.

$$\langle \phi(x_i), \phi(x_j) \rangle_{H_k} = k(x_i, x_j) \quad \Rightarrow \quad \text{replace } x_i^\top x_j \mapsto k(x_i, x_j) \text{ in dual}$$

> **Why the Kernel Trick Is Powerful**: The RBF kernel corresponds to an infinite-dimensional feature map, yet computing k(x, z) = exp(−‖x−z‖²/2ℓ²) costs only O(d) operations (d = input dimension). Without the kernel trick, working with the infinite-dimensional feature map would be impossible. With it, you get the expressive power of an infinite feature space at O(d) cost per kernel evaluation.

## Kernel Ridge Regression

Ridge regression in primal form solves minw ‖Xw−y‖² + λ‖w‖². Using the representer theorem, the dual form is: find α such that f*(x) = Σᵢ αᵢ k(xᵢ, x). Substituting into the objective and differentiating gives α = (K+λI)⁻¹y. Prediction at new x* requires computing k(xᵢ, x*) for all training points: ŷ* = k*ᵀα where (k*)ᵢ = k(xᵢ, x*). Training cost is O(n³) for the matrix solve; prediction is O(n) kernel evaluations per test point.

$$\boldsymbol{\alpha} = (K + \lambda I)^{-1}\mathbf{y}, \qquad \hat{y}(x^*) = \mathbf{k}_*^\top \boldsymbol{\alpha}, \quad (\mathbf{k}_*)_i = k(x_i, x^*)$$

## Kernel PCA

Standard PCA finds a linear subspace of maximum variance. Kernel PCA applies PCA in the RKHS feature space φ(x), enabling nonlinear dimensionality reduction. The algorithm: (1) center the kernel matrix K̃ = K − 1ₙKᵀ − K1ₙ + 1ₙK1ₙᵀ; (2) eigendecompose K̃ = UΛUᵀ; (3) project new points using the eigenvectors. The resulting components capture nonlinear structure in the data — for example, kernel PCA with an RBF kernel can unfold a Swiss roll or separate concentric rings that linear PCA cannot.

## Kernel SVM

The SVM dual maximizes Σᵢ αᵢ − ½ Σᵢⱼ αᵢαⱼyᵢyⱼ k(xᵢ,xⱼ) subject to 0 ≤ αᵢ ≤ C and Σᵢ αᵢyᵢ = 0. Points with αᵢ > 0 are support vectors. The decision function f(x) = Σᵢ αᵢyᵢk(xᵢ,x) + b only involves the support vectors (often sparse). Kernel SVM requires solving an n×n QP but the sparsity of the solution means prediction uses far fewer than n kernel evaluations. The C parameter trades off margin width against training error.

$$f(x) = \sum_{i \in SV} \alpha_i y_i\, k(x_i, x) + b, \quad \alpha_i > 0 \text{ only for support vectors}$$

## Computational Bottlenecks

All exact kernel methods share the same O(n²) memory bottleneck: storing the full n×n kernel matrix. For n=10,000 points with float64, this is 800 MB; for n=100,000 it is 80 GB — infeasible on a single machine. Training costs range from O(n²·d) for kernel evaluation to O(n³) for matrix solves and eigendecompositions. These costs make exact kernel methods suitable for n up to ~20,000 points and motivate approximation methods for larger datasets.

## Nyström Approximation

The Nyström method approximates the full kernel matrix K ≈ K_{nm} K_{mm}⁻¹ K_{mn} using only m ≪ n landmark points. The landmarks are selected randomly or by greedy selection. This reduces memory from O(n²) to O(nm) and training cost from O(n³) to O(nm²). The approximated kernel features can then be fed to any linear model. Nyström provides a principled low-rank approximation with a convergence guarantee: ‖K − K̃‖ → 0 as m → n.

## Code Examples

```python
import numpy as np
from sklearn.kernel_ridge import KernelRidge
from sklearn.datasets import make_regression
from sklearn.preprocessing import StandardScaler
from sklearn.metrics import mean_squared_error

def rbf_gram(X1, X2, gamma=1.0):
    diff = X1[:, None, :] - X2[None, :, :]
    return np.exp(-gamma * np.sum(diff**2, axis=-1))

def krr_from_scratch(X_train, y_train, X_test, gamma=1.0, lam=0.1):
    K_train = rbf_gram(X_train, X_train, gamma)
    alpha = np.linalg.solve(K_train + lam * np.eye(len(y_train)), y_train)
    K_test = rbf_gram(X_test, X_train, gamma)
    return K_test @ alpha

X, y = make_regression(n_samples=200, n_features=10, noise=0.5, random_state=0)
sc = StandardScaler()
X = sc.fit_transform(X)
X_tr, X_te = X[:150], X[150:]
y_tr, y_te = y[:150], y[150:]

y_scratch = krr_from_scratch(X_tr, y_tr, X_te, gamma=0.5, lam=0.1)
krr = KernelRidge(kernel='rbf', alpha=0.1, gamma=0.5)
krr.fit(X_tr, y_tr)
y_sklearn = krr.predict(X_te)

print(f'From-scratch KRR MSE: {mean_squared_error(y_te, y_scratch):.4f}')
print(f'sklearn KRR      MSE: {mean_squared_error(y_te, y_sklearn):.4f}')
print(f'Max diff: {np.abs(y_scratch - y_sklearn).max():.2e}')
```

```python
import numpy as np
import matplotlib.pyplot as plt
from sklearn.datasets import make_swiss_roll
from sklearn.decomposition import KernelPCA, PCA

X, color = make_swiss_roll(n_samples=1000, noise=0.1, random_state=42)

pca = PCA(n_components=2)
X_pca = pca.fit_transform(X)

kpca = KernelPCA(n_components=2, kernel='rbf', gamma=0.04)
X_kpca = kpca.fit_transform(X)

fig, axes = plt.subplots(1, 3, figsize=(15, 4))
axes[0].scatter(X[:, 0], X[:, 2], c=color, cmap='rainbow', s=5)
axes[0].set_title('Original Swiss Roll (x-z view)')

axes[1].scatter(X_pca[:, 0], X_pca[:, 1], c=color, cmap='rainbow', s=5)
axes[1].set_title('Linear PCA (fails to unfold)')

axes[2].scatter(X_kpca[:, 0], X_kpca[:, 1], c=color, cmap='rainbow', s=5)
axes[2].set_title('Kernel PCA RBF (unfolds manifold)')

plt.tight_layout()
plt.savefig('kernel_pca.png', dpi=100)
print('Saved kernel_pca.png')
```

```python
import numpy as np
import matplotlib.pyplot as plt
from sklearn.svm import SVC
from sklearn.metrics import accuracy_score

# XOR dataset: not linearly separable
rng = np.random.RandomState(42)
X_pos = np.vstack([rng.randn(50, 2) + [1, 1], rng.randn(50, 2) + [-1, -1]])
X_neg = np.vstack([rng.randn(50, 2) + [1, -1], rng.randn(50, 2) + [-1,  1]])
X = np.vstack([X_pos, X_neg])
y = np.hstack([np.ones(100), -np.ones(100)])

kernels = {'linear': {}, 'poly': {'degree': 3, 'coef0': 1}, 'rbf': {'gamma': 0.5}}
results = {}
for name, kwargs in kernels.items():
    clf = SVC(kernel=name, C=1.0, **kwargs)
    clf.fit(X, y)
    acc = accuracy_score(y, clf.predict(X))
    results[name] = (clf, acc)
    print(f'kernel={name}: accuracy={acc:.3f}')

fig, axes = plt.subplots(1, 3, figsize=(14, 4))
xx, yy = np.meshgrid(np.linspace(-4, 4, 200), np.linspace(-4, 4, 200))
for ax, (name, (clf, acc)) in zip(axes, results.items()):
    Z = clf.predict(np.c_[xx.ravel(), yy.ravel()]).reshape(xx.shape)
    ax.contourf(xx, yy, Z, alpha=0.3)
    ax.scatter(X[:, 0], X[:, 1], c=y, cmap='bwr', s=10)
    ax.set_title(f'{name} (acc={acc:.2f})')
plt.tight_layout()
plt.savefig('kernel_svm_xor.png', dpi=100)
```

```python
import numpy as np
from sklearn.kernel_approximation import Nystroem
from sklearn.linear_model import Ridge
from sklearn.pipeline import make_pipeline
from sklearn.metrics import mean_squared_error
from sklearn.datasets import make_regression
from sklearn.preprocessing import StandardScaler
import time

X, y = make_regression(n_samples=2000, n_features=20, noise=0.5, random_state=0)
sc = StandardScaler()
X = sc.fit_transform(X)
X_tr, X_te = X[:1500], X[1500:]
y_tr, y_te = y[:1500], y[1500:]

print(f'{"n_components":<14} {"MSE":<10} {"Time (s)":<10}')
print('-' * 36)
for n_comp in [50, 100, 200, 500]:
    t0 = time.time()
    pipe = make_pipeline(
        Nystroem(kernel='rbf', gamma=0.5, n_components=n_comp, random_state=0),
        Ridge(alpha=1.0)
    )
    pipe.fit(X_tr, y_tr)
    mse = mean_squared_error(y_te, pipe.predict(X_te))
    elapsed = time.time() - t0
    print(f'{n_comp:<14} {mse:<10.4f} {elapsed:<10.3f}')
print(f'Exact kernel matrix: {1500**2 * 8 / 1e6:.0f} MB vs Nystroem(m=200): {1500*200*8/1e6:.1f} MB')
```

## Method Comparison

| Method | Dual Form | Training Cost | Prediction Cost | Best For |
| --- | --- | --- | --- | --- |
| Kernel Ridge Regression | α = (K+λI)⁻¹y | O(n³) matrix solve | O(n·d) kernel evals per point | Small-n smooth regression |
| Kernel PCA | Eigendecompose centered K | O(n³) eigendecomp | O(n·p) projections per point | Nonlinear dimensionality reduction |
| Kernel SVM | QP over α with box constraints | O(n²) to O(n³) QP | O(n_sv·d) kernel evals (sparse) | Classification with margin |
| Nyström Approx. | K ≈ K_{nm}K_{mm}⁻¹K_{mn} | O(nm²) with m≪n | O(m) feature vector, O(1) model | Large-scale kernel methods n>10k |

All three methods share the same kernel matrix bottleneck. For n ≤ 5,000 use exact methods; for larger n use Nyström approximation or random Fourier features (Rahimi & Recht, 2007). The choice between KRR, kPCA, and kSVM depends on the task: regression, dimensionality reduction, or classification.

