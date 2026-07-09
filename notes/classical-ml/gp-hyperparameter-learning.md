---
title: "GP Hyperparameter Learning — Type-II MLE and Marginal Likelihood"
slug: "gp-hyperparameter-learning"
description: "Optimising GP kernel hyperparameters by maximising the log marginal likelihood: derivation, gradient computation via Cholesky, Bayesian Occam's razor, and ARD for feature selection."
tags: ["gaussian-processes", "kernel-methods", "classical-ml"]
topic: "classical-ml"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"heading","level":2,"content":"What Are GP Hyperparameters?"},{"type":"text","content":"Every GP kernel has hyperparameters θ that must be set before inference. For the RBF kernel: length-scale ℓ controls correlation range, signal variance σ²_f controls function amplitude, and noise variance σ²_n separates observation noise from signal. Setting these by hand (cross-validation grid search) is expensive and ignores the principled Bayesian alternative: maximising the log marginal likelihood, also called Type-II Maximum Likelihood (Type-II MLE) or evidence maximisation."},{"type":"list","ordered":false,"items":["Length-scale ℓ: the single most important hyperparameter — controls function smoothness","Signal variance σ²_f: scales K, controlling function amplitude","Noise variance σ²_n: added to diagonal of K, separates signal from noise","Mean function params: constant, linear, or polynomial terms for global trend","ARD length-scales: one ℓ_d per input dimension for automatic feature relevance","Type-II MLE (evidence maximisation): optimise all θ jointly via marginal likelihood"]},{"type":"heading","level":2,"content":"Log Marginal Likelihood Derivation"},{"type":"text","content":"Integrating out the latent function f gives the marginal likelihood p(y|X,θ) = ∫p(y|f)p(f|X,θ)df = N(y | m(X), K_θ + σ²_n I). The log marginal likelihood decomposes into three interpretable terms: log p(y|X,θ) = −½ yᵀ(K+σ²_nI)⁻¹y − ½ log|K+σ²_nI| − n/2 log(2π). The first term is a data-fit term (large when the model explains y well). The second is a complexity penalty (large when K is large/complex). The third is a constant. Jointly they implement Bayesian Occam\u0027s razor: simpler models that still explain the data are preferred."},{"type":"code","language":"python","content":"import numpy as np\nfrom scipy.optimize import minimize\n\ndef rbf_kernel(X1, X2, ell, sf2):\n    X1 = np.atleast_2d(X1).reshape(-1,1)\n    X2 = np.atleast_2d(X2).reshape(-1,1)\n    return sf2 * np.exp(-0.5*(X1-X2.T)**2/ell**2)\n\ndef log_marginal_likelihood(params, X, y):\n    log_ell, log_sf2, log_sn2 = params\n    ell = np.exp(log_ell); sf2 = np.exp(log_sf2); sn2 = np.exp(log_sn2)\n    n = len(y)\n    K = rbf_kernel(X, X, ell, sf2) + sn2*np.eye(n)\n    try:\n        L = np.linalg.cholesky(K)\n    except np.linalg.LinAlgError:\n        return 1e10\n    alpha = np.linalg.solve(L.T, np.linalg.solve(L, y))\n    log_det = 2*np.sum(np.log(np.diag(L)))\n    lml = -0.5*(y @ alpha) - 0.5*log_det - 0.5*n*np.log(2*np.pi)\n    return -lml   # return negative for minimisation\n\nnp.random.seed(42)\nX = np.linspace(-5, 5, 40)\ny = np.sin(X) + 0.2*np.random.randn(40)\n\n# Optimise hyperparameters from multiple restarts\nbest_val, best_params = np.inf, None\nfor _ in range(5):\n    x0 = np.log(np.random.uniform([0.1, 0.1, 0.01], [5.0, 5.0, 1.0]))\n    res = minimize(log_marginal_likelihood, x0, args=(X, y), method=\u0027L-BFGS-B\u0027)\n    if res.fun \u003c best_val:\n        best_val, best_params = res.fun, res.x\n\nell_opt, sf2_opt, sn2_opt = np.exp(best_params)\nprint(f\u0027Optimised: ℓ={ell_opt:.3f}, σ²_f={sf2_opt:.3f}, σ²_n={sn2_opt:.4f}\u0027)"},{"type":"table","headers":["Hyperparameter","Role","Diagnosis When Wrong","Typical Range"],"rows":[["Length-scale ℓ","Controls correlation range","Too small → wiggly, overfit; too large → underfit","0.1 × data_range – 2 × data_range"],["Signal variance σ²_f","Function amplitude","Too small → mean near zero; too large → wild extrapolation","Matched to output std: 0.1–10"],["Noise variance σ²_n","Observation noise","Too small → interpolation; too large → smooth but misfit","0.001–1.0 (as fraction of output variance)"],["Mean params (if linear/const mean)","Capture global trend","Ignored baseline → biased extrapolation","Fit from data; often zero works"]]},{"type":"heading","level":2,"content":"GPyTorch Marginal Likelihood Optimisation"},{"type":"text","content":"GPyTorch computes the exact marginal log likelihood (ExactMarginalLogLikelihood) and its gradient through automatic differentiation. A standard training loop uses Adam or L-BFGS with 100–200 iterations. Log-parameterising hyperparameters (working in log space) ensures positivity and better-conditioned gradients. GPyTorch\u0027s ParameterConstraint system handles this automatically."},{"type":"code","language":"python","content":"import torch\nimport gpytorch\nimport numpy as np\nimport matplotlib.pyplot as plt\n\nclass GPModel(gpytorch.models.ExactGP):\n    def __init__(self, train_x, train_y, likelihood):\n        super().__init__(train_x, train_y, likelihood)\n        self.mean_module  = gpytorch.means.ZeroMean()\n        self.covar_module = gpytorch.kernels.ScaleKernel(gpytorch.kernels.RBFKernel())\n    def forward(self, x):\n        return gpytorch.distributions.MultivariateNormal(\n            self.mean_module(x), self.covar_module(x))\n\nnp.random.seed(0)\nX_np = np.linspace(-5, 5, 50)\ny_np = np.sin(X_np) + 0.2*np.random.randn(50)\ntrain_x = torch.tensor(X_np, dtype=torch.float32)\ntrain_y = torch.tensor(y_np, dtype=torch.float32)\n\nlikelihood = gpytorch.likelihoods.GaussianLikelihood()\nmodel = GPModel(train_x, train_y, likelihood)\nmodel.train(); likelihood.train()\nmll = gpytorch.mlls.ExactMarginalLogLikelihood(likelihood, model)\noptimizer = torch.optim.Adam(model.parameters(), lr=0.1)\nfor i in range(150):\n    optimizer.zero_grad()\n    loss = -mll(model(train_x), train_y)\n    loss.backward(); optimizer.step()\n\nell = model.covar_module.base_kernel.lengthscale.item()\nsf2 = model.covar_module.outputscale.item()\nsn2 = likelihood.noise.item()\nprint(f\u0027Learned: ℓ={ell:.3f}, σ²_f={sf2:.3f}, σ²_n={sn2:.4f}\u0027)"},{"type":"heading","level":2,"content":"Marginal Likelihood Landscape and Bayesian Occam\u0027s Razor"},{"type":"text","content":"The marginal likelihood surface over (ℓ, σ²_f) is typically unimodal for simple datasets but can have multiple local optima for complex or noisy data. The data-fit term favours complex models (many parameters, small ℓ); the complexity penalty log|K+σ²_nI| penalises them. Their sum — the marginal likelihood — peaks at the simplest model that still explains the data. This automatic complexity control is the Bayesian Occam\u0027s razor."},{"type":"code","language":"python","content":"import numpy as np\nimport matplotlib.pyplot as plt\nfrom scipy.optimize import minimize\n\ndef rbf_kernel(X1, X2, ell, sf2):\n    X1 = np.atleast_2d(X1).reshape(-1,1)\n    X2 = np.atleast_2d(X2).reshape(-1,1)\n    return sf2 * np.exp(-0.5*(X1-X2.T)**2/ell**2)\n\ndef lml_grid(X, y, ell, sf2, sn2=0.05):\n    n = len(y)\n    K = rbf_kernel(X, X, ell, sf2) + sn2*np.eye(n)\n    try:\n        L = np.linalg.cholesky(K)\n        alpha = np.linalg.solve(L.T, np.linalg.solve(L, y))\n        log_det = 2*np.sum(np.log(np.diag(L)))\n        return -0.5*(y@alpha) - 0.5*log_det - 0.5*n*np.log(2*np.pi)\n    except Exception:\n        return np.nan\n\nnp.random.seed(5)\nX = np.linspace(-5, 5, 30)\ny = np.sin(X) + 0.15*np.random.randn(30)\n\nells  = np.logspace(-1, 1, 40)\nsf2s  = np.logspace(-1, 1, 40)\nZ = np.array([[lml_grid(X, y, e, s) for e in ells] for s in sf2s])\n\nplt.figure(figsize=(8,6))\nplt.contourf(np.log10(ells), np.log10(sf2s), Z, levels=30, cmap=\u0027viridis\u0027)\nplt.colorbar(label=\u0027Log Marginal Likelihood\u0027)\nplt.xlabel(\u0027log₁₀(ℓ)\u0027); plt.ylabel(\u0027log₁₀(σ²_f)\u0027)\nplt.title(\u0027Marginal Likelihood Landscape\u0027)\nplt.tight_layout(); plt.show()"},{"type":"callout","variant":"info","title":"Multiple Restarts Avoid Local Optima","content":"The marginal likelihood objective is non-convex. Run L-BFGS-B from 5–20 random initialisations in log-parameter space and take the optimum with the highest log marginal likelihood. This is especially important for high-dimensional or compositional kernels with many hyperparameters."},{"type":"heading","level":2,"content":"ARD — Automatic Relevance Determination"},{"type":"text","content":"Automatic Relevance Determination (ARD) extends the scalar length-scale ℓ to a separate ℓ_d per input dimension d. The ARD kernel is k(x,x\u0027) = σ²_f exp(−Σ_d (xd−x\u0027d)²/(2ℓ_d²)). After marginal likelihood optimisation, small ℓ_d → dimension d is relevant (function varies sharply with it); large ℓ_d → dimension d is irrelevant (function is flat). ARD provides automatic, continuous feature selection embedded in the GP."},{"type":"code","language":"python","content":"import torch\nimport gpytorch\nimport numpy as np\n\nnp.random.seed(42)\nn, d = 100, 6\nX_np = np.random.randn(n, d)\n# Only first 2 features matter\ny_np = np.sin(X_np[:,0]) + 0.5*X_np[:,1] + 0.1*np.random.randn(n)\n\ntrain_x = torch.tensor(X_np, dtype=torch.float32)\ntrain_y = torch.tensor(y_np, dtype=torch.float32)\n\nlikelihood = gpytorch.likelihoods.GaussianLikelihood()\nmodel_ard = gpytorch.models.ExactGP(train_x, train_y, likelihood)\nmodel_ard.mean_module  = gpytorch.means.ZeroMean()\nmodel_ard.covar_module = gpytorch.kernels.ScaleKernel(\n    gpytorch.kernels.RBFKernel(ard_num_dims=d))\nmodel_ard.forward = lambda x: gpytorch.distributions.MultivariateNormal(\n    model_ard.mean_module(x), model_ard.covar_module(x))\n\nmodel_ard.train(); likelihood.train()\nmll = gpytorch.mlls.ExactMarginalLogLikelihood(likelihood, model_ard)\nopt = torch.optim.Adam(model_ard.parameters(), lr=0.1)\nfor _ in range(200):\n    opt.zero_grad(); (-mll(model_ard(train_x), train_y)).backward(); opt.step()\n\nells = model_ard.covar_module.base_kernel.lengthscale.detach().numpy()[0]\nfor i, l in enumerate(ells):\n    print(f\u0027Feature {i}: ℓ = {l:.3f}  {\"\u003c-- relevant\" if l \u003c 1.0 else \"irrelevant\"}\u0027)"},{"type":"heading","level":2,"content":"Key Takeaways"},{"type":"text","content":"Type-II MLE optimises GP hyperparameters by maximising the log marginal likelihood log p(y|X,θ). The objective balances data-fit against model complexity (Bayesian Occam\u0027s razor) without a held-out validation set. Optimisation uses gradient-based methods (L-BFGS-B or Adam) in log-parameter space with multiple restarts. ARD extends scalar length-scales to per-dimension values, providing automatic feature selection. For large n, gradient computation through Cholesky remains the standard approach."},{"type":"callout","variant":"warning","title":"Marginal Likelihood ≠ Predictive Accuracy","content":"Maximising the marginal likelihood is not the same as minimising prediction error. The complexity penalty can cause the optimiser to choose a simpler model than what gives best test RMSE, especially for small datasets. When pure predictive accuracy matters, compare with cross-validated hyperparameter selection."},{"type":"list","ordered":false,"items":["Log marginal likelihood = data fit − complexity penalty − constant","Three terms: −½yᵀ(K+σ²I)⁻¹y, −½log|K+σ²I|, −n/2 log(2π)","Gradient through Cholesky: ∂LML/∂θ via matrix derivatives — automatic in GPyTorch","L-BFGS-B with 5–20 random restarts avoids local optima","ARD: separate ℓ_d per dimension gives automatic relevance determination","Bayesian Occam\u0027s razor: marginal likelihood prefers simpler models that fit the data"]},{"type":"divider"}]"
---
# GP Hyperparameter Learning — Type-II MLE and Marginal Likelihood

## What Are GP Hyperparameters?

Every GP kernel has hyperparameters θ that must be set before inference. For the RBF kernel: length-scale ℓ controls correlation range, signal variance σ²_f controls function amplitude, and noise variance σ²_n separates observation noise from signal. Setting these by hand (cross-validation grid search) is expensive and ignores the principled Bayesian alternative: maximising the log marginal likelihood, also called Type-II Maximum Likelihood (Type-II MLE) or evidence maximisation.

- Length-scale ℓ: the single most important hyperparameter — controls function smoothness
- Signal variance σ²_f: scales K, controlling function amplitude
- Noise variance σ²_n: added to diagonal of K, separates signal from noise
- Mean function params: constant, linear, or polynomial terms for global trend
- ARD length-scales: one ℓ_d per input dimension for automatic feature relevance
- Type-II MLE (evidence maximisation): optimise all θ jointly via marginal likelihood

## Log Marginal Likelihood Derivation

Integrating out the latent function f gives the marginal likelihood p(y|X,θ) = ∫p(y|f)p(f|X,θ)df = N(y | m(X), K_θ + σ²_n I). The log marginal likelihood decomposes into three interpretable terms: log p(y|X,θ) = −½ yᵀ(K+σ²_nI)⁻¹y − ½ log|K+σ²_nI| − n/2 log(2π). The first term is a data-fit term (large when the model explains y well). The second is a complexity penalty (large when K is large/complex). The third is a constant. Jointly they implement Bayesian Occam's razor: simpler models that still explain the data are preferred.

```python
import numpy as np
from scipy.optimize import minimize

def rbf_kernel(X1, X2, ell, sf2):
    X1 = np.atleast_2d(X1).reshape(-1,1)
    X2 = np.atleast_2d(X2).reshape(-1,1)
    return sf2 * np.exp(-0.5*(X1-X2.T)**2/ell**2)

def log_marginal_likelihood(params, X, y):
    log_ell, log_sf2, log_sn2 = params
    ell = np.exp(log_ell); sf2 = np.exp(log_sf2); sn2 = np.exp(log_sn2)
    n = len(y)
    K = rbf_kernel(X, X, ell, sf2) + sn2*np.eye(n)
    try:
        L = np.linalg.cholesky(K)
    except np.linalg.LinAlgError:
        return 1e10
    alpha = np.linalg.solve(L.T, np.linalg.solve(L, y))
    log_det = 2*np.sum(np.log(np.diag(L)))
    lml = -0.5*(y @ alpha) - 0.5*log_det - 0.5*n*np.log(2*np.pi)
    return -lml   # return negative for minimisation

np.random.seed(42)
X = np.linspace(-5, 5, 40)
y = np.sin(X) + 0.2*np.random.randn(40)

# Optimise hyperparameters from multiple restarts
best_val, best_params = np.inf, None
for _ in range(5):
    x0 = np.log(np.random.uniform([0.1, 0.1, 0.01], [5.0, 5.0, 1.0]))
    res = minimize(log_marginal_likelihood, x0, args=(X, y), method='L-BFGS-B')
    if res.fun < best_val:
        best_val, best_params = res.fun, res.x

ell_opt, sf2_opt, sn2_opt = np.exp(best_params)
print(f'Optimised: ℓ={ell_opt:.3f}, σ²_f={sf2_opt:.3f}, σ²_n={sn2_opt:.4f}')
```

| Hyperparameter | Role | Diagnosis When Wrong | Typical Range |
| --- | --- | --- | --- |
| Length-scale ℓ | Controls correlation range | Too small → wiggly, overfit; too large → underfit | 0.1 × data_range – 2 × data_range |
| Signal variance σ²_f | Function amplitude | Too small → mean near zero; too large → wild extrapolation | Matched to output std: 0.1–10 |
| Noise variance σ²_n | Observation noise | Too small → interpolation; too large → smooth but misfit | 0.001–1.0 (as fraction of output variance) |
| Mean params (if linear/const mean) | Capture global trend | Ignored baseline → biased extrapolation | Fit from data; often zero works |

## GPyTorch Marginal Likelihood Optimisation

GPyTorch computes the exact marginal log likelihood (ExactMarginalLogLikelihood) and its gradient through automatic differentiation. A standard training loop uses Adam or L-BFGS with 100–200 iterations. Log-parameterising hyperparameters (working in log space) ensures positivity and better-conditioned gradients. GPyTorch's ParameterConstraint system handles this automatically.

```python
import torch
import gpytorch
import numpy as np
import matplotlib.pyplot as plt

class GPModel(gpytorch.models.ExactGP):
    def __init__(self, train_x, train_y, likelihood):
        super().__init__(train_x, train_y, likelihood)
        self.mean_module  = gpytorch.means.ZeroMean()
        self.covar_module = gpytorch.kernels.ScaleKernel(gpytorch.kernels.RBFKernel())
    def forward(self, x):
        return gpytorch.distributions.MultivariateNormal(
            self.mean_module(x), self.covar_module(x))

np.random.seed(0)
X_np = np.linspace(-5, 5, 50)
y_np = np.sin(X_np) + 0.2*np.random.randn(50)
train_x = torch.tensor(X_np, dtype=torch.float32)
train_y = torch.tensor(y_np, dtype=torch.float32)

likelihood = gpytorch.likelihoods.GaussianLikelihood()
model = GPModel(train_x, train_y, likelihood)
model.train(); likelihood.train()
mll = gpytorch.mlls.ExactMarginalLogLikelihood(likelihood, model)
optimizer = torch.optim.Adam(model.parameters(), lr=0.1)
for i in range(150):
    optimizer.zero_grad()
    loss = -mll(model(train_x), train_y)
    loss.backward(); optimizer.step()

ell = model.covar_module.base_kernel.lengthscale.item()
sf2 = model.covar_module.outputscale.item()
sn2 = likelihood.noise.item()
print(f'Learned: ℓ={ell:.3f}, σ²_f={sf2:.3f}, σ²_n={sn2:.4f}')
```

## Marginal Likelihood Landscape and Bayesian Occam's Razor

The marginal likelihood surface over (ℓ, σ²_f) is typically unimodal for simple datasets but can have multiple local optima for complex or noisy data. The data-fit term favours complex models (many parameters, small ℓ); the complexity penalty log|K+σ²_nI| penalises them. Their sum — the marginal likelihood — peaks at the simplest model that still explains the data. This automatic complexity control is the Bayesian Occam's razor.

```python
import numpy as np
import matplotlib.pyplot as plt
from scipy.optimize import minimize

def rbf_kernel(X1, X2, ell, sf2):
    X1 = np.atleast_2d(X1).reshape(-1,1)
    X2 = np.atleast_2d(X2).reshape(-1,1)
    return sf2 * np.exp(-0.5*(X1-X2.T)**2/ell**2)

def lml_grid(X, y, ell, sf2, sn2=0.05):
    n = len(y)
    K = rbf_kernel(X, X, ell, sf2) + sn2*np.eye(n)
    try:
        L = np.linalg.cholesky(K)
        alpha = np.linalg.solve(L.T, np.linalg.solve(L, y))
        log_det = 2*np.sum(np.log(np.diag(L)))
        return -0.5*(y@alpha) - 0.5*log_det - 0.5*n*np.log(2*np.pi)
    except Exception:
        return np.nan

np.random.seed(5)
X = np.linspace(-5, 5, 30)
y = np.sin(X) + 0.15*np.random.randn(30)

ells  = np.logspace(-1, 1, 40)
sf2s  = np.logspace(-1, 1, 40)
Z = np.array([[lml_grid(X, y, e, s) for e in ells] for s in sf2s])

plt.figure(figsize=(8,6))
plt.contourf(np.log10(ells), np.log10(sf2s), Z, levels=30, cmap='viridis')
plt.colorbar(label='Log Marginal Likelihood')
plt.xlabel('log₁₀(ℓ)'); plt.ylabel('log₁₀(σ²_f)')
plt.title('Marginal Likelihood Landscape')
plt.tight_layout(); plt.show()
```

> **Multiple Restarts Avoid Local Optima**: The marginal likelihood objective is non-convex. Run L-BFGS-B from 5–20 random initialisations in log-parameter space and take the optimum with the highest log marginal likelihood. This is especially important for high-dimensional or compositional kernels with many hyperparameters.

## ARD — Automatic Relevance Determination

Automatic Relevance Determination (ARD) extends the scalar length-scale ℓ to a separate ℓ_d per input dimension d. The ARD kernel is k(x,x') = σ²_f exp(−Σ_d (xd−x'd)²/(2ℓ_d²)). After marginal likelihood optimisation, small ℓ_d → dimension d is relevant (function varies sharply with it); large ℓ_d → dimension d is irrelevant (function is flat). ARD provides automatic, continuous feature selection embedded in the GP.

```python
import torch
import gpytorch
import numpy as np

np.random.seed(42)
n, d = 100, 6
X_np = np.random.randn(n, d)
# Only first 2 features matter
y_np = np.sin(X_np[:,0]) + 0.5*X_np[:,1] + 0.1*np.random.randn(n)

train_x = torch.tensor(X_np, dtype=torch.float32)
train_y = torch.tensor(y_np, dtype=torch.float32)

likelihood = gpytorch.likelihoods.GaussianLikelihood()
model_ard = gpytorch.models.ExactGP(train_x, train_y, likelihood)
model_ard.mean_module  = gpytorch.means.ZeroMean()
model_ard.covar_module = gpytorch.kernels.ScaleKernel(
    gpytorch.kernels.RBFKernel(ard_num_dims=d))
model_ard.forward = lambda x: gpytorch.distributions.MultivariateNormal(
    model_ard.mean_module(x), model_ard.covar_module(x))

model_ard.train(); likelihood.train()
mll = gpytorch.mlls.ExactMarginalLogLikelihood(likelihood, model_ard)
opt = torch.optim.Adam(model_ard.parameters(), lr=0.1)
for _ in range(200):
    opt.zero_grad(); (-mll(model_ard(train_x), train_y)).backward(); opt.step()

ells = model_ard.covar_module.base_kernel.lengthscale.detach().numpy()[0]
for i, l in enumerate(ells):
    print(f'Feature {i}: ℓ = {l:.3f}  {"<-- relevant" if l < 1.0 else "irrelevant"}')
```

## Key Takeaways

Type-II MLE optimises GP hyperparameters by maximising the log marginal likelihood log p(y|X,θ). The objective balances data-fit against model complexity (Bayesian Occam's razor) without a held-out validation set. Optimisation uses gradient-based methods (L-BFGS-B or Adam) in log-parameter space with multiple restarts. ARD extends scalar length-scales to per-dimension values, providing automatic feature selection. For large n, gradient computation through Cholesky remains the standard approach.

> **Marginal Likelihood ≠ Predictive Accuracy**: Maximising the marginal likelihood is not the same as minimising prediction error. The complexity penalty can cause the optimiser to choose a simpler model than what gives best test RMSE, especially for small datasets. When pure predictive accuracy matters, compare with cross-validated hyperparameter selection.

- Log marginal likelihood = data fit − complexity penalty − constant
- Three terms: −½yᵀ(K+σ²I)⁻¹y, −½log|K+σ²I|, −n/2 log(2π)
- Gradient through Cholesky: ∂LML/∂θ via matrix derivatives — automatic in GPyTorch
- L-BFGS-B with 5–20 random restarts avoids local optima
- ARD: separate ℓ_d per dimension gives automatic relevance determination
- Bayesian Occam's razor: marginal likelihood prefers simpler models that fit the data

---

