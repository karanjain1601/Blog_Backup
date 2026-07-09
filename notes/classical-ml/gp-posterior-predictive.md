---
title: "GP Posterior — Conditioning on Observations"
slug: "gp-posterior-predictive"
description: "Deriving the GP posterior by conditioning a joint Gaussian on noisy observations: closed-form mean and covariance, uncertainty calibration, and GPyTorch implementation."
tags: ["gaussian-processes", "kernel-methods", "classical-ml"]
topic: "classical-ml"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"heading","level":2,"content":"From Prior to Posterior"},{"type":"text","content":"Given training observations y = f(X) + ε where ε ~ N(0, σ²_n I), the GP posterior over function values at test points X* is again a GP. This is the key tractability property of GPs: Gaussian likelihoods combined with a GP prior yield a GP posterior. The posterior mean is the best point estimate; the posterior variance quantifies prediction uncertainty. Both are available in closed form, with no sampling required."},{"type":"list","ordered":false,"items":["Gaussian likelihood p(y|f) = N(y|f, σ²_nI) preserves GP conjugacy","Posterior is GP: f*|X,y,X* ~ GP(μ*, Σ*)","Posterior mean μ*: best linear unbiased predictor of f(X*)","Posterior covariance Σ*: quantifies remaining uncertainty after conditioning","Closed-form solution — no MCMC or variational approximation needed for Gaussian likelihood"]},{"type":"heading","level":2,"content":"Posterior Derivation via Joint Gaussian Conditioning"},{"type":"text","content":"The joint distribution of training outputs y and test function values f* is Gaussian: [y, f*]ᵀ ~ N(0, [[K + σ²_n I, K*ᵀ], [K*, K**]]). Applying the Gaussian conditioning formula gives: posterior mean μ* = K*ᵀ (K + σ²_n I)⁻¹ y and posterior covariance Σ* = K** − K*ᵀ (K + σ²_n I)⁻¹ K*. Here K = k(X,X) is the n×n training kernel matrix, K* = k(X,X*) is n×n* cross-covariance, and K** = k(X*,X*) is the n*×n* test kernel matrix."},{"type":"code","language":"python","content":"import numpy as np\nimport matplotlib.pyplot as plt\n\ndef rbf_kernel(X1, X2, ell=1.0, sf2=1.0):\n    X1 = np.atleast_2d(X1).reshape(-1,1)\n    X2 = np.atleast_2d(X2).reshape(-1,1)\n    return sf2 * np.exp(-0.5*(X1 - X2.T)**2 / ell**2)\n\ndef gp_posterior(X_train, y_train, X_test, ell=1.0, sf2=1.0, noise_var=0.1):\n    n = len(X_train)\n    K    = rbf_kernel(X_train, X_train, ell, sf2) + noise_var*np.eye(n)\n    K_s  = rbf_kernel(X_train, X_test,  ell, sf2)   # n x n*\n    K_ss = rbf_kernel(X_test,  X_test,  ell, sf2)   # n* x n*\n    L    = np.linalg.cholesky(K)\n    alpha = np.linalg.solve(L.T, np.linalg.solve(L, y_train))  # (K)^{-1} y\n    mu   = K_s.T @ alpha\n    v    = np.linalg.solve(L, K_s)\n    cov  = K_ss - v.T @ v\n    return mu, np.diag(cov)\n\nnp.random.seed(42)\nX_train = np.array([-4, -2, 0, 2, 4], dtype=float)\ny_train = np.sin(X_train) + 0.1*np.random.randn(len(X_train))\nX_test  = np.linspace(-6, 6, 200)\nmu, var = gp_posterior(X_train, y_train, X_test, ell=1.5, sf2=1.0, noise_var=0.05)\nstd = np.sqrt(var)\n\nplt.figure(figsize=(10,4))\nplt.fill_between(X_test, mu-2*std, mu+2*std, alpha=0.25, label=\u0027±2σ\u0027)\nplt.plot(X_test, mu, \u0027b-\u0027, lw=2, label=\u0027Posterior mean\u0027)\nplt.scatter(X_train, y_train, c=\u0027r\u0027, zorder=5, s=60, label=\u0027Observations\u0027)\nplt.legend(); plt.title(\u0027GP Posterior (RBF, ℓ=1.5)\u0027)\nplt.xlabel(\u0027x\u0027); plt.ylabel(\u0027f(x)\u0027); plt.tight_layout(); plt.show()"},{"type":"table","headers":["Matrix","Shape","Formula","Interpretation"],"rows":[["K","n × n","k(X,X) + σ²_n I","Noisy training covariance — inverted once at cost O(n³)"],["K*","n × n*","k(X,X*)","Cross-covariance: how training points inform test points"],["K**","n* × n*","k(X*,X*)","Prior test covariance before conditioning"],["Posterior mean","n* × 1","K*ᵀ (K+σ²_nI)⁻¹ y","Weighted combination of kernel evaluations (representer theorem)"],["Posterior cov","n* × n*","K** − K*ᵀ (K+σ²_nI)⁻¹ K*","Prior variance minus information gained from observations"]]},{"type":"heading","level":2,"content":"GPyTorch ExactGP with Confidence Bands"},{"type":"text","content":"GPyTorch implements GP inference using efficient linear algebra (Conjugate Gradients, low-rank approximations). ExactGP is the standard class for exact inference. After training (optimising hyperparameters via marginal likelihood), calling model(X_test) returns a MultivariateNormal whose mean and variance are the posterior predictive quantities."},{"type":"code","language":"python","content":"import torch\nimport gpytorch\nimport numpy as np\nimport matplotlib.pyplot as plt\n\nclass ExactGPModel(gpytorch.models.ExactGP):\n    def __init__(self, train_x, train_y, likelihood):\n        super().__init__(train_x, train_y, likelihood)\n        self.mean_module = gpytorch.means.ConstantMean()\n        self.covar_module = gpytorch.kernels.ScaleKernel(\n            gpytorch.kernels.RBFKernel())\n\n    def forward(self, x):\n        mean_x  = self.mean_module(x)\n        covar_x = self.covar_module(x)\n        return gpytorch.distributions.MultivariateNormal(mean_x, covar_x)\n\ntrain_x = torch.linspace(-4, 4, 20)\ntrain_y = torch.sin(train_x) + 0.1*torch.randn_like(train_x)\n\nlikelihood = gpytorch.likelihoods.GaussianLikelihood()\nmodel = ExactGPModel(train_x, train_y, likelihood)\n\nmodel.train(); likelihood.train()\noptimizer = torch.optim.Adam(model.parameters(), lr=0.1)\nmll = gpytorch.mlls.ExactMarginalLogLikelihood(likelihood, model)\nfor i in range(100):\n    optimizer.zero_grad()\n    output = model(train_x)\n    loss = -mll(output, train_y)\n    loss.backward(); optimizer.step()\n\nmodel.eval(); likelihood.eval()\ntest_x = torch.linspace(-6, 6, 200)\nwith torch.no_grad(), gpytorch.settings.fast_pred_var():\n    pred = likelihood(model(test_x))\n    lower, upper = pred.confidence_region()\n\nplt.figure(figsize=(10,4))\nplt.fill_between(test_x.numpy(), lower.numpy(), upper.numpy(), alpha=0.25)\nplt.plot(test_x.numpy(), pred.mean.numpy(), lw=2)\nplt.scatter(train_x.numpy(), train_y.numpy(), c=\u0027r\u0027, s=50, zorder=5)\nplt.title(\u0027GPyTorch ExactGP Posterior\u0027); plt.tight_layout(); plt.show()"},{"type":"heading","level":2,"content":"Posterior Variance: Near and Far from Data"},{"type":"text","content":"A key GP property is automatic uncertainty calibration. Posterior variance at a test point x* equals K(x*,x*) minus the amount of variance explained by the training observations. Near training points, the second term is large — posterior variance is small (high confidence). Far from all training points, the subtracted term approaches 0 and the posterior variance returns to the prior variance σ²_f. This behaviour requires no manual tuning."},{"type":"code","language":"python","content":"import numpy as np\nimport matplotlib.pyplot as plt\n\ndef rbf_kernel(X1, X2, ell=1.0, sf2=1.0):\n    X1 = np.atleast_2d(X1).reshape(-1,1)\n    X2 = np.atleast_2d(X2).reshape(-1,1)\n    return sf2 * np.exp(-0.5*(X1-X2.T)**2/ell**2)\n\ndef gp_posterior_var(X_train, X_test, ell, sf2, noise_var):\n    K    = rbf_kernel(X_train, X_train, ell, sf2) + noise_var*np.eye(len(X_train))\n    K_s  = rbf_kernel(X_train, X_test, ell, sf2)\n    K_ss = rbf_kernel(X_test,  X_test, ell, sf2)\n    L    = np.linalg.cholesky(K)\n    v    = np.linalg.solve(L, K_s)\n    return np.diag(K_ss - v.T@v)\n\nX_train = np.array([-3, -1, 1, 3], dtype=float)\nX_test  = np.linspace(-6, 6, 300)\nvar = gp_posterior_var(X_train, X_test, ell=1.0, sf2=1.0, noise_var=0.01)\n\nplt.figure(figsize=(10,3))\nplt.plot(X_test, var, lw=2, color=\u0027darkorange\u0027, label=\u0027Posterior variance\u0027)\nplt.axhline(1.0, ls=\u0027--\u0027, color=\u0027gray\u0027, label=\u0027Prior variance σ²_f=1\u0027)\nfor xp in X_train:\n    plt.axvline(xp, ls=\u0027:\u0027, color=\u0027steelblue\u0027, alpha=0.6)\nplt.fill_between(X_test, 0, var, alpha=0.2, color=\u0027darkorange\u0027)\nplt.xlabel(\u0027x\u0027); plt.ylabel(\u0027Posterior Var(f*)\u0027)\nplt.title(\u0027Posterior Variance: Shrinks Near Data, Returns to Prior Far Away\u0027)\nplt.legend(); plt.tight_layout(); plt.show()"},{"type":"heading","level":2,"content":"Noisy vs Noiseless Observations"},{"type":"text","content":"When noise variance σ²_n = 0, the GP interpolates exactly through all training points — the posterior mean passes through every observation and posterior variance is exactly 0 at training inputs. With σ²_n \u003e 0 (noisy observations), the posterior mean smooths through the data rather than interpolating, and the posterior variance at training inputs is σ²_n \u003e 0. Noiseless GPs are numerically unstable (K is only positive semi-definite) and should always include at least a small jitter term."},{"type":"code","language":"python","content":"import numpy as np\nimport matplotlib.pyplot as plt\n\ndef rbf_kernel(X1, X2, ell=1.0, sf2=1.0):\n    X1 = np.atleast_2d(X1).reshape(-1,1)\n    X2 = np.atleast_2d(X2).reshape(-1,1)\n    return sf2 * np.exp(-0.5*(X1-X2.T)**2/ell**2)\n\ndef gp_posterior(X_tr, y_tr, X_te, ell=1.0, sf2=1.0, noise_var=0.1):\n    K    = rbf_kernel(X_tr, X_tr, ell, sf2) + noise_var*np.eye(len(X_tr))\n    K_s  = rbf_kernel(X_tr, X_te, ell, sf2)\n    K_ss = rbf_kernel(X_te, X_te, ell, sf2)\n    L    = np.linalg.cholesky(K)\n    alpha = np.linalg.solve(L.T, np.linalg.solve(L, y_tr))\n    mu   = K_s.T @ alpha\n    v    = np.linalg.solve(L, K_s)\n    return mu, np.sqrt(np.maximum(np.diag(K_ss - v.T@v), 0))\n\nnp.random.seed(3)\nX_tr  = np.sort(np.random.uniform(-4, 4, 8))\ny_tr  = np.sin(X_tr) + 0.3*np.random.randn(8)\nX_te  = np.linspace(-5, 5, 300)\n\nfig, axes = plt.subplots(1, 2, figsize=(13,4), sharey=True)\nfor ax, noise, title in zip(axes,\n    [1e-6, 0.3], [\u0027Noiseless (σ²_n≈0) — interpolation\u0027, \u0027Noisy (σ²_n=0.3) — smoothing\u0027]):\n    mu, std = gp_posterior(X_tr, y_tr, X_te, ell=1.0, sf2=1.0, noise_var=noise)\n    ax.fill_between(X_te, mu-2*std, mu+2*std, alpha=0.25)\n    ax.plot(X_te, mu, lw=2)\n    ax.scatter(X_tr, y_tr, c=\u0027r\u0027, zorder=5, s=60)\n    ax.set_title(title); ax.set_xlabel(\u0027x\u0027)\naxes[0].set_ylabel(\u0027f(x)\u0027); plt.tight_layout(); plt.show()"},{"type":"callout","variant":"warning","title":"Always Include Jitter Even for Noiseless GPs","content":"Setting σ²_n = 0 exactly causes the kernel matrix K to be only positive semi-definite when training points repeat or are very close. Always add a small jitter (1e-6 to 1e-4) to the diagonal regardless of the assumed noise level. This tiny regularisation does not change predictions meaningfully but prevents Cholesky failures."},{"type":"callout","variant":"info","title":"O(n³) Bottleneck","content":"The Cholesky factorisation of the n×n matrix (K + σ²_n I) costs O(n³) time and O(n²) memory. For n \u003e 5,000 this becomes the dominant cost. Sparse GP approximations (inducing points, FITC, SVGP) reduce the cost to O(nm²) and O(m²) respectively, where m ≪ n is the number of inducing points."},{"type":"heading","level":2,"content":"Key Takeaways"},{"type":"text","content":"The GP posterior is analytically tractable when the likelihood is Gaussian: conditioning the joint Gaussian p(y, f*) on the observations y yields a closed-form Gaussian posterior over f*. Posterior mean μ* = K*ᵀ(K+σ²_nI)⁻¹y is a weighted sum of kernel evaluations. Posterior variance Σ* = K** − K*ᵀ(K+σ²_nI)⁻¹K* shrinks near observations and returns to prior variance far from data. The O(n³) cost of inverting K+σ²_nI is the main computational bottleneck of exact GP inference."},{"type":"list","ordered":false,"items":["Posterior mean: representer theorem — weighted kernel evaluations at training points","Posterior variance: prior variance minus information gained from data","Uncertainty is automatically calibrated: high near data, low far from data","O(n³) Cholesky limits exact GPs to n ≲ 5,000 — use sparse approximations beyond this","Noiseless GP (σ²_n=0): exact interpolation, numerically fragile","GPyTorch uses Conjugate Gradients to avoid full O(n³) Cholesky in many regimes"]},{"type":"divider"}]"
---
# GP Posterior — Conditioning on Observations

## From Prior to Posterior

Given training observations y = f(X) + ε where ε ~ N(0, σ²_n I), the GP posterior over function values at test points X* is again a GP. This is the key tractability property of GPs: Gaussian likelihoods combined with a GP prior yield a GP posterior. The posterior mean is the best point estimate; the posterior variance quantifies prediction uncertainty. Both are available in closed form, with no sampling required.

- Gaussian likelihood p(y|f) = N(y|f, σ²_nI) preserves GP conjugacy
- Posterior is GP: f*|X,y,X* ~ GP(μ*, Σ*)
- Posterior mean μ*: best linear unbiased predictor of f(X*)
- Posterior covariance Σ*: quantifies remaining uncertainty after conditioning
- Closed-form solution — no MCMC or variational approximation needed for Gaussian likelihood

## Posterior Derivation via Joint Gaussian Conditioning

The joint distribution of training outputs y and test function values f* is Gaussian: [y, f*]ᵀ ~ N(0, [[K + σ²_n I, K*ᵀ], [K*, K**]]). Applying the Gaussian conditioning formula gives: posterior mean μ* = K*ᵀ (K + σ²_n I)⁻¹ y and posterior covariance Σ* = K** − K*ᵀ (K + σ²_n I)⁻¹ K*. Here K = k(X,X) is the n×n training kernel matrix, K* = k(X,X*) is n×n* cross-covariance, and K** = k(X*,X*) is the n*×n* test kernel matrix.

```python
import numpy as np
import matplotlib.pyplot as plt

def rbf_kernel(X1, X2, ell=1.0, sf2=1.0):
    X1 = np.atleast_2d(X1).reshape(-1,1)
    X2 = np.atleast_2d(X2).reshape(-1,1)
    return sf2 * np.exp(-0.5*(X1 - X2.T)**2 / ell**2)

def gp_posterior(X_train, y_train, X_test, ell=1.0, sf2=1.0, noise_var=0.1):
    n = len(X_train)
    K    = rbf_kernel(X_train, X_train, ell, sf2) + noise_var*np.eye(n)
    K_s  = rbf_kernel(X_train, X_test,  ell, sf2)   # n x n*
    K_ss = rbf_kernel(X_test,  X_test,  ell, sf2)   # n* x n*
    L    = np.linalg.cholesky(K)
    alpha = np.linalg.solve(L.T, np.linalg.solve(L, y_train))  # (K)^{-1} y
    mu   = K_s.T @ alpha
    v    = np.linalg.solve(L, K_s)
    cov  = K_ss - v.T @ v
    return mu, np.diag(cov)

np.random.seed(42)
X_train = np.array([-4, -2, 0, 2, 4], dtype=float)
y_train = np.sin(X_train) + 0.1*np.random.randn(len(X_train))
X_test  = np.linspace(-6, 6, 200)
mu, var = gp_posterior(X_train, y_train, X_test, ell=1.5, sf2=1.0, noise_var=0.05)
std = np.sqrt(var)

plt.figure(figsize=(10,4))
plt.fill_between(X_test, mu-2*std, mu+2*std, alpha=0.25, label='±2σ')
plt.plot(X_test, mu, 'b-', lw=2, label='Posterior mean')
plt.scatter(X_train, y_train, c='r', zorder=5, s=60, label='Observations')
plt.legend(); plt.title('GP Posterior (RBF, ℓ=1.5)')
plt.xlabel('x'); plt.ylabel('f(x)'); plt.tight_layout(); plt.show()
```

| Matrix | Shape | Formula | Interpretation |
| --- | --- | --- | --- |
| K | n × n | k(X,X) + σ²_n I | Noisy training covariance — inverted once at cost O(n³) |
| K* | n × n* | k(X,X*) | Cross-covariance: how training points inform test points |
| K** | n* × n* | k(X*,X*) | Prior test covariance before conditioning |
| Posterior mean | n* × 1 | K*ᵀ (K+σ²_nI)⁻¹ y | Weighted combination of kernel evaluations (representer theorem) |
| Posterior cov | n* × n* | K** − K*ᵀ (K+σ²_nI)⁻¹ K* | Prior variance minus information gained from observations |

## GPyTorch ExactGP with Confidence Bands

GPyTorch implements GP inference using efficient linear algebra (Conjugate Gradients, low-rank approximations). ExactGP is the standard class for exact inference. After training (optimising hyperparameters via marginal likelihood), calling model(X_test) returns a MultivariateNormal whose mean and variance are the posterior predictive quantities.

```python
import torch
import gpytorch
import numpy as np
import matplotlib.pyplot as plt

class ExactGPModel(gpytorch.models.ExactGP):
    def __init__(self, train_x, train_y, likelihood):
        super().__init__(train_x, train_y, likelihood)
        self.mean_module = gpytorch.means.ConstantMean()
        self.covar_module = gpytorch.kernels.ScaleKernel(
            gpytorch.kernels.RBFKernel())

    def forward(self, x):
        mean_x  = self.mean_module(x)
        covar_x = self.covar_module(x)
        return gpytorch.distributions.MultivariateNormal(mean_x, covar_x)

train_x = torch.linspace(-4, 4, 20)
train_y = torch.sin(train_x) + 0.1*torch.randn_like(train_x)

likelihood = gpytorch.likelihoods.GaussianLikelihood()
model = ExactGPModel(train_x, train_y, likelihood)

model.train(); likelihood.train()
optimizer = torch.optim.Adam(model.parameters(), lr=0.1)
mll = gpytorch.mlls.ExactMarginalLogLikelihood(likelihood, model)
for i in range(100):
    optimizer.zero_grad()
    output = model(train_x)
    loss = -mll(output, train_y)
    loss.backward(); optimizer.step()

model.eval(); likelihood.eval()
test_x = torch.linspace(-6, 6, 200)
with torch.no_grad(), gpytorch.settings.fast_pred_var():
    pred = likelihood(model(test_x))
    lower, upper = pred.confidence_region()

plt.figure(figsize=(10,4))
plt.fill_between(test_x.numpy(), lower.numpy(), upper.numpy(), alpha=0.25)
plt.plot(test_x.numpy(), pred.mean.numpy(), lw=2)
plt.scatter(train_x.numpy(), train_y.numpy(), c='r', s=50, zorder=5)
plt.title('GPyTorch ExactGP Posterior'); plt.tight_layout(); plt.show()
```

## Posterior Variance: Near and Far from Data

A key GP property is automatic uncertainty calibration. Posterior variance at a test point x* equals K(x*,x*) minus the amount of variance explained by the training observations. Near training points, the second term is large — posterior variance is small (high confidence). Far from all training points, the subtracted term approaches 0 and the posterior variance returns to the prior variance σ²_f. This behaviour requires no manual tuning.

```python
import numpy as np
import matplotlib.pyplot as plt

def rbf_kernel(X1, X2, ell=1.0, sf2=1.0):
    X1 = np.atleast_2d(X1).reshape(-1,1)
    X2 = np.atleast_2d(X2).reshape(-1,1)
    return sf2 * np.exp(-0.5*(X1-X2.T)**2/ell**2)

def gp_posterior_var(X_train, X_test, ell, sf2, noise_var):
    K    = rbf_kernel(X_train, X_train, ell, sf2) + noise_var*np.eye(len(X_train))
    K_s  = rbf_kernel(X_train, X_test, ell, sf2)
    K_ss = rbf_kernel(X_test,  X_test, ell, sf2)
    L    = np.linalg.cholesky(K)
    v    = np.linalg.solve(L, K_s)
    return np.diag(K_ss - v.T@v)

X_train = np.array([-3, -1, 1, 3], dtype=float)
X_test  = np.linspace(-6, 6, 300)
var = gp_posterior_var(X_train, X_test, ell=1.0, sf2=1.0, noise_var=0.01)

plt.figure(figsize=(10,3))
plt.plot(X_test, var, lw=2, color='darkorange', label='Posterior variance')
plt.axhline(1.0, ls='--', color='gray', label='Prior variance σ²_f=1')
for xp in X_train:
    plt.axvline(xp, ls=':', color='steelblue', alpha=0.6)
plt.fill_between(X_test, 0, var, alpha=0.2, color='darkorange')
plt.xlabel('x'); plt.ylabel('Posterior Var(f*)')
plt.title('Posterior Variance: Shrinks Near Data, Returns to Prior Far Away')
plt.legend(); plt.tight_layout(); plt.show()
```

## Noisy vs Noiseless Observations

When noise variance σ²_n = 0, the GP interpolates exactly through all training points — the posterior mean passes through every observation and posterior variance is exactly 0 at training inputs. With σ²_n > 0 (noisy observations), the posterior mean smooths through the data rather than interpolating, and the posterior variance at training inputs is σ²_n > 0. Noiseless GPs are numerically unstable (K is only positive semi-definite) and should always include at least a small jitter term.

```python
import numpy as np
import matplotlib.pyplot as plt

def rbf_kernel(X1, X2, ell=1.0, sf2=1.0):
    X1 = np.atleast_2d(X1).reshape(-1,1)
    X2 = np.atleast_2d(X2).reshape(-1,1)
    return sf2 * np.exp(-0.5*(X1-X2.T)**2/ell**2)

def gp_posterior(X_tr, y_tr, X_te, ell=1.0, sf2=1.0, noise_var=0.1):
    K    = rbf_kernel(X_tr, X_tr, ell, sf2) + noise_var*np.eye(len(X_tr))
    K_s  = rbf_kernel(X_tr, X_te, ell, sf2)
    K_ss = rbf_kernel(X_te, X_te, ell, sf2)
    L    = np.linalg.cholesky(K)
    alpha = np.linalg.solve(L.T, np.linalg.solve(L, y_tr))
    mu   = K_s.T @ alpha
    v    = np.linalg.solve(L, K_s)
    return mu, np.sqrt(np.maximum(np.diag(K_ss - v.T@v), 0))

np.random.seed(3)
X_tr  = np.sort(np.random.uniform(-4, 4, 8))
y_tr  = np.sin(X_tr) + 0.3*np.random.randn(8)
X_te  = np.linspace(-5, 5, 300)

fig, axes = plt.subplots(1, 2, figsize=(13,4), sharey=True)
for ax, noise, title in zip(axes,
    [1e-6, 0.3], ['Noiseless (σ²_n≈0) — interpolation', 'Noisy (σ²_n=0.3) — smoothing']):
    mu, std = gp_posterior(X_tr, y_tr, X_te, ell=1.0, sf2=1.0, noise_var=noise)
    ax.fill_between(X_te, mu-2*std, mu+2*std, alpha=0.25)
    ax.plot(X_te, mu, lw=2)
    ax.scatter(X_tr, y_tr, c='r', zorder=5, s=60)
    ax.set_title(title); ax.set_xlabel('x')
axes[0].set_ylabel('f(x)'); plt.tight_layout(); plt.show()
```

> **Always Include Jitter Even for Noiseless GPs**: Setting σ²_n = 0 exactly causes the kernel matrix K to be only positive semi-definite when training points repeat or are very close. Always add a small jitter (1e-6 to 1e-4) to the diagonal regardless of the assumed noise level. This tiny regularisation does not change predictions meaningfully but prevents Cholesky failures.

> **O(n³) Bottleneck**: The Cholesky factorisation of the n×n matrix (K + σ²_n I) costs O(n³) time and O(n²) memory. For n > 5,000 this becomes the dominant cost. Sparse GP approximations (inducing points, FITC, SVGP) reduce the cost to O(nm²) and O(m²) respectively, where m ≪ n is the number of inducing points.

## Key Takeaways

The GP posterior is analytically tractable when the likelihood is Gaussian: conditioning the joint Gaussian p(y, f*) on the observations y yields a closed-form Gaussian posterior over f*. Posterior mean μ* = K*ᵀ(K+σ²_nI)⁻¹y is a weighted sum of kernel evaluations. Posterior variance Σ* = K** − K*ᵀ(K+σ²_nI)⁻¹K* shrinks near observations and returns to prior variance far from data. The O(n³) cost of inverting K+σ²_nI is the main computational bottleneck of exact GP inference.

- Posterior mean: representer theorem — weighted kernel evaluations at training points
- Posterior variance: prior variance minus information gained from data
- Uncertainty is automatically calibrated: high near data, low far from data
- O(n³) Cholesky limits exact GPs to n ≲ 5,000 — use sparse approximations beyond this
- Noiseless GP (σ²_n=0): exact interpolation, numerically fragile
- GPyTorch uses Conjugate Gradients to avoid full O(n³) Cholesky in many regimes

---

