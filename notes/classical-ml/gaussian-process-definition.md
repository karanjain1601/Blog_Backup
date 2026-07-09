---
title: "Gaussian Process Definition — Mean and Covariance Functions"
slug: "gaussian-process-definition"
description: "A rigorous introduction to Gaussian processes as distributions over functions. Covers the mean function, covariance function, GP priors, marginalization consistency, connection to RKHS, and the Bayesian model structure of GPs."
tags: ["kernel-methods", "gaussian-processes", "classical-ml"]
topic: "classical-ml"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"A Gaussian Process (GP) is a probability distribution over functions. Rather than parameterizing a function by a finite number of weights (as in neural networks), a GP defines a consistent distribution over all possible function values simultaneously. Any finite collection of function evaluations follows a multivariate Gaussian distribution. GPs are the canonical nonparametric Bayesian model for regression: they express prior beliefs through a mean function and covariance function, update those beliefs with data via Bayes\u0027 rule, and produce calibrated uncertainty estimates."},{"type":"heading","level":2,"content":"Formal Definition of a GP"},{"type":"text","content":"A Gaussian Process f ~ GP(m, k) is a collection of random variables {f(x) : x ∈ X} such that any finite marginal {f(x₁), …, f(xₙ)} is jointly Gaussian with mean vector μᵢ = m(xᵢ) and covariance matrix Kᵢⱼ = k(xᵢ, xⱼ). The entire distribution is specified by just two functions: the mean function m : X → ℝ and the covariance function (kernel) k : X × X → ℝ. This infinite-dimensional consistency is guaranteed by the Kolmogorov extension theorem, which requires only that all finite marginals are consistent."},{"type":"math","display":true,"content":"f \\sim \\mathcal{GP}(m, k) \\iff \\begin{pmatrix} f(x_1) \\\\ \\vdots \\\\ f(x_n) \\end{pmatrix} \\sim \\mathcal{N}\\!\\left(\\begin{pmatrix} m(x_1) \\\\ \\vdots \\\\ m(x_n) \\end{pmatrix}, \\begin{pmatrix} k(x_1,x_1) \u0026 \\cdots \u0026 k(x_1,x_n) \\\\ \\vdots \u0026 \\ddots \u0026 \\vdots \\\\ k(x_n,x_1) \u0026 \\cdots \u0026 k(x_n,x_n) \\end{pmatrix}\\right)"},{"type":"heading","level":2,"content":"Mean Function"},{"type":"text","content":"The mean function m(x) = E[f(x)] specifies the expected function value at each input x. The most common choice is zero mean m(x) = 0, which is appropriate when the data is centered and no strong prior about the function\u0027s baseline is available. Linear mean functions m(x) = aᵀx + b are useful when the function is expected to trend linearly outside the training domain. Polynomial or neural-network-based mean functions are used for complex trends. The choice matters most for extrapolation; within the training data, the posterior adapts regardless of the prior mean."},{"type":"heading","level":2,"content":"Covariance Function"},{"type":"text","content":"The covariance function (kernel) k(x, x\u0027) = Cov[f(x), f(x\u0027)] = E[(f(x)−m(x))(f(x\u0027)−m(x\u0027))] completely determines the correlation structure of the prior. High k(x, x\u0027) means f(x) and f(x\u0027) tend to be close; low k(x, x\u0027) means they can vary independently. The kernel encodes smoothness (how quickly correlations decay with distance), periodicity, stationarity, and other structural assumptions. The kernel must be a Mercer kernel (PSD) so that the covariance matrix is always valid."},{"type":"math","display":true,"content":"k(x, x\u0027) = \\text{Cov}[f(x), f(x\u0027)] = \\mathbb{E}\\big[(f(x) - m(x))(f(x\u0027) - m(x\u0027))\\big]"},{"type":"callout","variant":"info","title":"GP = Nonparametric Bayesian Model","content":"Traditional parametric models have a fixed number of parameters (e.g., weights in linear regression). GPs are nonparametric: the effective complexity grows with the data. Adding more observations can always increase model expressiveness. This makes GPs a Bayesian model over function spaces rather than parameter spaces — the prior is a distribution over functions, and the posterior is updated consistently via Bayes\u0027 rule as data arrives."},{"type":"heading","level":2,"content":"GP as a Distribution Over Functions"},{"type":"text","content":"A GP prior f ~ GP(0, k) defines a probability measure over the space of functions C(X) (continuous functions on X). Drawing a sample from the prior means drawing a whole function f : X → ℝ, not just a finite-dimensional vector. The sample functions are continuous if the kernel is continuous, and their smoothness is determined by the kernel: RBF kernels produce C∞ samples; Matérn-ν kernels produce samples with ⌊ν⌋ continuous derivatives. This is the sense in which GPs are infinite-dimensional priors — they assign probability to entire functions."},{"type":"heading","level":2,"content":"Connection to RKHS"},{"type":"text","content":"A subtle but important fact: GP sample paths are almost surely NOT in the RKHS H_k. The RKHS norm ‖f‖_k of a typical GP sample is infinite. However, the posterior mean function (after conditioning on data) IS in H_k and equals the kernel ridge regression solution. This apparent paradox is resolved by noting that H_k contains the \u0027smooth\u0027 functions, while GP samples include rougher paths with probability 1. The RKHS and GP prior are complementary: the RKHS is where the posterior mean lives, and the GP prior generates the full distribution including uncertainty."},{"type":"heading","level":2,"content":"GP as a Bayesian Model"},{"type":"text","content":"The Bayesian structure of a GP is explicit: the prior f ~ GP(m, k) assigns probability to every function; the likelihood p(y | f, X) = N(y; f(X), σ²_n I) models noisy observations; the posterior p(f | X, y) ∝ p(y | f, X) p(f) is again a GP (due to Gaussian conjugacy). This posterior is computed analytically — no MCMC or variational inference needed. The marginal likelihood p(y | X) = ∫ p(y|f,X) p(f) df is also Gaussian and used to optimize kernel hyperparameters."},{"type":"list","ordered":false,"items":["Prior: f ~ GP(m, k) — distribution over functions encoding smoothness assumptions.","Likelihood: y | f ~ N(f(X), σ²_n I) — Gaussian observation noise model.","Posterior: f | X, y ~ GP(m_post, k_post) — updated distribution over functions given data.","Marginal likelihood: p(y | X, θ) — used to optimize hyperparameters θ = {ℓ, σ², σ²_n} by MLE.","Prediction: p(f* | x*, X, y) = N(μ*, σ²*) — Gaussian predictive distribution at new x*."]},{"type":"heading","level":2,"content":"Code Examples"},{"type":"code","language":"python","content":"import numpy as np\nimport matplotlib.pyplot as plt\n\ndef rbf_kernel(X1, X2, ell=1.0, sigma2=1.0):\n    diff = X1[:, None, :] - X2[None, :, :]\n    return sigma2 * np.exp(-np.sum(diff**2, axis=-1) / (2 * ell**2))\n\ndef matern52_kernel(X1, X2, ell=1.0, sigma2=1.0):\n    diff = X1[:, None, :] - X2[None, :, :]\n    r = np.sqrt(np.sum(diff**2, axis=-1)) / ell\n    return sigma2 * (1 + np.sqrt(5)*r + 5*r**2/3) * np.exp(-np.sqrt(5)*r)\n\ndef sample_gp_prior(x, kernel_fn, n_samples=5, seed=0):\n    X = x[:, None]\n    K = kernel_fn(X, X) + 1e-8 * np.eye(len(x))\n    L = np.linalg.cholesky(K)\n    rng = np.random.RandomState(seed)\n    return (L @ rng.randn(len(x), n_samples)).T\n\nx = np.linspace(-5, 5, 300)\nfig, axes = plt.subplots(1, 2, figsize=(12, 4))\nfor ax, (name, kfn) in zip(axes, [\n    (\u0027GP prior: RBF ell=1\u0027, lambda X1, X2: rbf_kernel(X1, X2, ell=1.0)),\n    (\u0027GP prior: Matern-5/2 ell=1\u0027, lambda X1, X2: matern52_kernel(X1, X2, ell=1.0)),\n]):\n    for s in sample_gp_prior(x, kfn):\n        ax.plot(x, s, alpha=0.8)\n    ax.set_title(name)\n    ax.set_xlabel(\u0027x\u0027)\n    ax.set_ylabel(\u0027f(x)\u0027)\nplt.tight_layout()\nplt.savefig(\u0027gp_prior_samples.png\u0027, dpi=100)\nprint(\u0027Saved gp_prior_samples.png -- each curve is one function drawn from GP prior\u0027)"},{"type":"code","language":"python","content":"import numpy as np\nimport matplotlib.pyplot as plt\n\ndef rbf_kernel_matrix(X1, X2, ell=1.0, sigma2=1.0):\n    diff = X1[:, None, :] - X2[None, :, :]\n    return sigma2 * np.exp(-np.sum(diff**2, axis=-1) / (2 * ell**2))\n\nx = np.linspace(-5, 5, 300)[:, None]\nconfigs = [\n    (0.5, 1.0, \u0027ell=0.5, sigma2=1 (short range)\u0027),\n    (2.0, 1.0, \u0027ell=2.0, sigma2=1 (long range)\u0027),\n    (1.0, 0.5, \u0027ell=1.0, sigma2=0.5 (low amplitude)\u0027),\n]\nfig, axes = plt.subplots(1, 3, figsize=(14, 4))\nfor ax, (ell, sigma2, title) in zip(axes, configs):\n    K = rbf_kernel_matrix(x, x, ell=ell, sigma2=sigma2)\n    K += 1e-8 * np.eye(len(x))\n    mean = np.zeros(len(x))\n    std = np.sqrt(np.diag(K))\n    ax.fill_between(x.ravel(), mean - 2*std, mean + 2*std, alpha=0.2, label=\u0027+/-2sigma\u0027)\n    ax.fill_between(x.ravel(), mean - std,   mean + std,   alpha=0.3, label=\u0027+/-1sigma\u0027)\n    ax.plot(x, mean, \u0027k--\u0027, label=\u0027mean\u0027)\n    L = np.linalg.cholesky(K)\n    rng = np.random.RandomState(0)\n    for _ in range(3):\n        ax.plot(x, L @ rng.randn(len(x)), alpha=0.7)\n    ax.set_title(title)\n    ax.legend(fontsize=7)\nplt.tight_layout()\nplt.savefig(\u0027gp_prior_bands.png\u0027, dpi=100)\nprint(\u0027Saved gp_prior_bands.png\u0027)"},{"type":"code","language":"python","content":"import numpy as np\nfrom scipy import stats\n\ndef rbf_kernel_matrix(X1, X2, ell=1.0):\n    diff = X1[:, None, :] - X2[None, :, :]\n    return np.exp(-np.sum(diff**2, axis=-1) / (2 * ell**2))\n\nrng = np.random.RandomState(42)\nx_full = np.linspace(-3, 3, 50)[:, None]\nK_full = rbf_kernel_matrix(x_full, x_full) + 1e-8 * np.eye(50)\nL = np.linalg.cholesky(K_full)\n\n# Draw many samples from the full GP\nn_samples = 5000\nsamples = (L @ rng.randn(50, n_samples)).T  # shape (n_samples, 50)\n\nprint(\u0027Verifying GP marginalization consistency:\u0027)\nprint(f\u0027{\"Index\":\u003c8} {\"Empirical var\":\u003c16} {\"Expected var\":\u003c16} {\"KS p-value\"}\u0027)\nfor idx in [10, 25, 40]:\n    marginal_samples = samples[:, idx]\n    k_ii = K_full[idx, idx]\n    ks_stat, p_value = stats.kstest(marginal_samples, \u0027norm\u0027, args=(0, np.sqrt(k_ii)))\n    print(f\u0027{idx:\u003c8} {np.var(marginal_samples):\u003c16.4f} {k_ii:\u003c16.4f} {p_value:.3f}\u0027)\n\nprint(\u0027All p-values \u003e 0.05: marginals are consistent Gaussians as expected.\u0027)"},{"type":"code","language":"python","content":"import numpy as np\nimport matplotlib.pyplot as plt\n\ndef rbf_kernel_matrix(X1, X2, ell=1.0, sigma2=1.0):\n    diff = X1[:, None, :] - X2[None, :, :]\n    return sigma2 * np.exp(-np.sum(diff**2, axis=-1) / (2 * ell**2))\n\ndef polynomial_mean(X, coeffs):\n    # Polynomial mean: m(x) = sum_i c_i * x^i\n    return sum(c * X.ravel()**i for i, c in enumerate(coeffs))\n\nx_train = np.linspace(-3, 3, 20)[:, None]\nrng = np.random.RandomState(5)\ntrue_mean = 0.5 * x_train.ravel()**2 - 1.0\ny_train = true_mean + 0.3 * rng.randn(20)\n\n# Subtract quadratic mean, fit GP residual\nmean_train = polynomial_mean(x_train, [0, 0, 0.5])\ny_centered = y_train - mean_train\n\nlam = 0.05\nK = rbf_kernel_matrix(x_train, x_train, ell=0.8) + lam * np.eye(20)\nalpha = np.linalg.solve(K, y_centered)\n\nx_test = np.linspace(-4, 4, 200)[:, None]\nK_star = rbf_kernel_matrix(x_test, x_train, ell=0.8)\nmean_test = polynomial_mean(x_test, [0, 0, 0.5])\ny_pred = mean_test + K_star @ alpha\n\nplt.figure(figsize=(10, 4))\nplt.scatter(x_train, y_train, label=\u0027Training data\u0027, zorder=5, s=40)\nplt.plot(x_test, y_pred, label=\u0027GP prediction (quadratic mean)\u0027, color=\u0027red\u0027)\nplt.plot(x_test, mean_test, \u0027--\u0027, label=\u0027Mean function only\u0027, color=\u0027orange\u0027, alpha=0.7)\nplt.legend()\nplt.title(\u0027GP with Non-Zero Polynomial Mean Function\u0027)\nplt.savefig(\u0027gp_nonzero_mean.png\u0027, dpi=100)\nprint(\u0027Saved gp_nonzero_mean.png\u0027)"},{"type":"heading","level":2,"content":"Design Choices Reference"},{"type":"table","headers":["Design Choice","Options","Effect on Prior","Recommendation"],"rows":[["Mean function m(x)","Zero, linear, polynomial, neural net","Centers the prior; affects extrapolation","Use zero mean within training range; linear/polynomial for extrapolation"],["Covariance function k(x,x\u0027)","RBF, Matérn, polynomial, periodic, composite","Controls smoothness and correlation range","Matérn-5/2 as default; RBF for very smooth functions"],["Length-scale ℓ","Fixed, tuned by marginal MLE, cross-validated","Controls correlation decay rate","Learn via marginal likelihood maximization (type-II MLE)"],["Signal variance σ²","Fixed, learned from data","Overall function amplitude","Learn from data; initialize to var(y)"],["Noise variance σ²_n","Fixed, learned, heteroscedastic","Separates signal from observation noise","Learn from data; use heteroscedastic model for varying noise"]]},{"type":"text","content":"A GP is fully specified by m and k. The zero-mean RBF GP is a reasonable starting point for most regression tasks. For problems with known structure — trends, periodicity, additive decompositions — encode that structure in the mean and covariance functions rather than relying on the data alone. Hyperparameters are learned by maximizing the log marginal likelihood log p(y | X, θ), which automatically balances data fit and prior complexity."}]"
---
# Gaussian Process Definition — Mean and Covariance Functions

A Gaussian Process (GP) is a probability distribution over functions. Rather than parameterizing a function by a finite number of weights (as in neural networks), a GP defines a consistent distribution over all possible function values simultaneously. Any finite collection of function evaluations follows a multivariate Gaussian distribution. GPs are the canonical nonparametric Bayesian model for regression: they express prior beliefs through a mean function and covariance function, update those beliefs with data via Bayes' rule, and produce calibrated uncertainty estimates.

## Formal Definition of a GP

A Gaussian Process f ~ GP(m, k) is a collection of random variables {f(x) : x ∈ X} such that any finite marginal {f(x₁), …, f(xₙ)} is jointly Gaussian with mean vector μᵢ = m(xᵢ) and covariance matrix Kᵢⱼ = k(xᵢ, xⱼ). The entire distribution is specified by just two functions: the mean function m : X → ℝ and the covariance function (kernel) k : X × X → ℝ. This infinite-dimensional consistency is guaranteed by the Kolmogorov extension theorem, which requires only that all finite marginals are consistent.

$$f \sim \mathcal{GP}(m, k) \iff \begin{pmatrix} f(x_1) \\ \vdots \\ f(x_n) \end{pmatrix} \sim \mathcal{N}\!\left(\begin{pmatrix} m(x_1) \\ \vdots \\ m(x_n) \end{pmatrix}, \begin{pmatrix} k(x_1,x_1) & \cdots & k(x_1,x_n) \\ \vdots & \ddots & \vdots \\ k(x_n,x_1) & \cdots & k(x_n,x_n) \end{pmatrix}\right)$$

## Mean Function

The mean function m(x) = E[f(x)] specifies the expected function value at each input x. The most common choice is zero mean m(x) = 0, which is appropriate when the data is centered and no strong prior about the function's baseline is available. Linear mean functions m(x) = aᵀx + b are useful when the function is expected to trend linearly outside the training domain. Polynomial or neural-network-based mean functions are used for complex trends. The choice matters most for extrapolation; within the training data, the posterior adapts regardless of the prior mean.

## Covariance Function

The covariance function (kernel) k(x, x') = Cov[f(x), f(x')] = E[(f(x)−m(x))(f(x')−m(x'))] completely determines the correlation structure of the prior. High k(x, x') means f(x) and f(x') tend to be close; low k(x, x') means they can vary independently. The kernel encodes smoothness (how quickly correlations decay with distance), periodicity, stationarity, and other structural assumptions. The kernel must be a Mercer kernel (PSD) so that the covariance matrix is always valid.

$$k(x, x') = \text{Cov}[f(x), f(x')] = \mathbb{E}\big[(f(x) - m(x))(f(x') - m(x'))\big]$$

> **GP = Nonparametric Bayesian Model**: Traditional parametric models have a fixed number of parameters (e.g., weights in linear regression). GPs are nonparametric: the effective complexity grows with the data. Adding more observations can always increase model expressiveness. This makes GPs a Bayesian model over function spaces rather than parameter spaces — the prior is a distribution over functions, and the posterior is updated consistently via Bayes' rule as data arrives.

## GP as a Distribution Over Functions

A GP prior f ~ GP(0, k) defines a probability measure over the space of functions C(X) (continuous functions on X). Drawing a sample from the prior means drawing a whole function f : X → ℝ, not just a finite-dimensional vector. The sample functions are continuous if the kernel is continuous, and their smoothness is determined by the kernel: RBF kernels produce C∞ samples; Matérn-ν kernels produce samples with ⌊ν⌋ continuous derivatives. This is the sense in which GPs are infinite-dimensional priors — they assign probability to entire functions.

## Connection to RKHS

A subtle but important fact: GP sample paths are almost surely NOT in the RKHS H_k. The RKHS norm ‖f‖_k of a typical GP sample is infinite. However, the posterior mean function (after conditioning on data) IS in H_k and equals the kernel ridge regression solution. This apparent paradox is resolved by noting that H_k contains the 'smooth' functions, while GP samples include rougher paths with probability 1. The RKHS and GP prior are complementary: the RKHS is where the posterior mean lives, and the GP prior generates the full distribution including uncertainty.

## GP as a Bayesian Model

The Bayesian structure of a GP is explicit: the prior f ~ GP(m, k) assigns probability to every function; the likelihood p(y | f, X) = N(y; f(X), σ²_n I) models noisy observations; the posterior p(f | X, y) ∝ p(y | f, X) p(f) is again a GP (due to Gaussian conjugacy). This posterior is computed analytically — no MCMC or variational inference needed. The marginal likelihood p(y | X) = ∫ p(y|f,X) p(f) df is also Gaussian and used to optimize kernel hyperparameters.

- Prior: f ~ GP(m, k) — distribution over functions encoding smoothness assumptions.
- Likelihood: y | f ~ N(f(X), σ²_n I) — Gaussian observation noise model.
- Posterior: f | X, y ~ GP(m_post, k_post) — updated distribution over functions given data.
- Marginal likelihood: p(y | X, θ) — used to optimize hyperparameters θ = {ℓ, σ², σ²_n} by MLE.
- Prediction: p(f* | x*, X, y) = N(μ*, σ²*) — Gaussian predictive distribution at new x*.

## Code Examples

```python
import numpy as np
import matplotlib.pyplot as plt

def rbf_kernel(X1, X2, ell=1.0, sigma2=1.0):
    diff = X1[:, None, :] - X2[None, :, :]
    return sigma2 * np.exp(-np.sum(diff**2, axis=-1) / (2 * ell**2))

def matern52_kernel(X1, X2, ell=1.0, sigma2=1.0):
    diff = X1[:, None, :] - X2[None, :, :]
    r = np.sqrt(np.sum(diff**2, axis=-1)) / ell
    return sigma2 * (1 + np.sqrt(5)*r + 5*r**2/3) * np.exp(-np.sqrt(5)*r)

def sample_gp_prior(x, kernel_fn, n_samples=5, seed=0):
    X = x[:, None]
    K = kernel_fn(X, X) + 1e-8 * np.eye(len(x))
    L = np.linalg.cholesky(K)
    rng = np.random.RandomState(seed)
    return (L @ rng.randn(len(x), n_samples)).T

x = np.linspace(-5, 5, 300)
fig, axes = plt.subplots(1, 2, figsize=(12, 4))
for ax, (name, kfn) in zip(axes, [
    ('GP prior: RBF ell=1', lambda X1, X2: rbf_kernel(X1, X2, ell=1.0)),
    ('GP prior: Matern-5/2 ell=1', lambda X1, X2: matern52_kernel(X1, X2, ell=1.0)),
]):
    for s in sample_gp_prior(x, kfn):
        ax.plot(x, s, alpha=0.8)
    ax.set_title(name)
    ax.set_xlabel('x')
    ax.set_ylabel('f(x)')
plt.tight_layout()
plt.savefig('gp_prior_samples.png', dpi=100)
print('Saved gp_prior_samples.png -- each curve is one function drawn from GP prior')
```

```python
import numpy as np
import matplotlib.pyplot as plt

def rbf_kernel_matrix(X1, X2, ell=1.0, sigma2=1.0):
    diff = X1[:, None, :] - X2[None, :, :]
    return sigma2 * np.exp(-np.sum(diff**2, axis=-1) / (2 * ell**2))

x = np.linspace(-5, 5, 300)[:, None]
configs = [
    (0.5, 1.0, 'ell=0.5, sigma2=1 (short range)'),
    (2.0, 1.0, 'ell=2.0, sigma2=1 (long range)'),
    (1.0, 0.5, 'ell=1.0, sigma2=0.5 (low amplitude)'),
]
fig, axes = plt.subplots(1, 3, figsize=(14, 4))
for ax, (ell, sigma2, title) in zip(axes, configs):
    K = rbf_kernel_matrix(x, x, ell=ell, sigma2=sigma2)
    K += 1e-8 * np.eye(len(x))
    mean = np.zeros(len(x))
    std = np.sqrt(np.diag(K))
    ax.fill_between(x.ravel(), mean - 2*std, mean + 2*std, alpha=0.2, label='+/-2sigma')
    ax.fill_between(x.ravel(), mean - std,   mean + std,   alpha=0.3, label='+/-1sigma')
    ax.plot(x, mean, 'k--', label='mean')
    L = np.linalg.cholesky(K)
    rng = np.random.RandomState(0)
    for _ in range(3):
        ax.plot(x, L @ rng.randn(len(x)), alpha=0.7)
    ax.set_title(title)
    ax.legend(fontsize=7)
plt.tight_layout()
plt.savefig('gp_prior_bands.png', dpi=100)
print('Saved gp_prior_bands.png')
```

```python
import numpy as np
from scipy import stats

def rbf_kernel_matrix(X1, X2, ell=1.0):
    diff = X1[:, None, :] - X2[None, :, :]
    return np.exp(-np.sum(diff**2, axis=-1) / (2 * ell**2))

rng = np.random.RandomState(42)
x_full = np.linspace(-3, 3, 50)[:, None]
K_full = rbf_kernel_matrix(x_full, x_full) + 1e-8 * np.eye(50)
L = np.linalg.cholesky(K_full)

# Draw many samples from the full GP
n_samples = 5000
samples = (L @ rng.randn(50, n_samples)).T  # shape (n_samples, 50)

print('Verifying GP marginalization consistency:')
print(f'{"Index":<8} {"Empirical var":<16} {"Expected var":<16} {"KS p-value"}')
for idx in [10, 25, 40]:
    marginal_samples = samples[:, idx]
    k_ii = K_full[idx, idx]
    ks_stat, p_value = stats.kstest(marginal_samples, 'norm', args=(0, np.sqrt(k_ii)))
    print(f'{idx:<8} {np.var(marginal_samples):<16.4f} {k_ii:<16.4f} {p_value:.3f}')

print('All p-values > 0.05: marginals are consistent Gaussians as expected.')
```

```python
import numpy as np
import matplotlib.pyplot as plt

def rbf_kernel_matrix(X1, X2, ell=1.0, sigma2=1.0):
    diff = X1[:, None, :] - X2[None, :, :]
    return sigma2 * np.exp(-np.sum(diff**2, axis=-1) / (2 * ell**2))

def polynomial_mean(X, coeffs):
    # Polynomial mean: m(x) = sum_i c_i * x^i
    return sum(c * X.ravel()**i for i, c in enumerate(coeffs))

x_train = np.linspace(-3, 3, 20)[:, None]
rng = np.random.RandomState(5)
true_mean = 0.5 * x_train.ravel()**2 - 1.0
y_train = true_mean + 0.3 * rng.randn(20)

# Subtract quadratic mean, fit GP residual
mean_train = polynomial_mean(x_train, [0, 0, 0.5])
y_centered = y_train - mean_train

lam = 0.05
K = rbf_kernel_matrix(x_train, x_train, ell=0.8) + lam * np.eye(20)
alpha = np.linalg.solve(K, y_centered)

x_test = np.linspace(-4, 4, 200)[:, None]
K_star = rbf_kernel_matrix(x_test, x_train, ell=0.8)
mean_test = polynomial_mean(x_test, [0, 0, 0.5])
y_pred = mean_test + K_star @ alpha

plt.figure(figsize=(10, 4))
plt.scatter(x_train, y_train, label='Training data', zorder=5, s=40)
plt.plot(x_test, y_pred, label='GP prediction (quadratic mean)', color='red')
plt.plot(x_test, mean_test, '--', label='Mean function only', color='orange', alpha=0.7)
plt.legend()
plt.title('GP with Non-Zero Polynomial Mean Function')
plt.savefig('gp_nonzero_mean.png', dpi=100)
print('Saved gp_nonzero_mean.png')
```

## Design Choices Reference

| Design Choice | Options | Effect on Prior | Recommendation |
| --- | --- | --- | --- |
| Mean function m(x) | Zero, linear, polynomial, neural net | Centers the prior; affects extrapolation | Use zero mean within training range; linear/polynomial for extrapolation |
| Covariance function k(x,x') | RBF, Matérn, polynomial, periodic, composite | Controls smoothness and correlation range | Matérn-5/2 as default; RBF for very smooth functions |
| Length-scale ℓ | Fixed, tuned by marginal MLE, cross-validated | Controls correlation decay rate | Learn via marginal likelihood maximization (type-II MLE) |
| Signal variance σ² | Fixed, learned from data | Overall function amplitude | Learn from data; initialize to var(y) |
| Noise variance σ²_n | Fixed, learned, heteroscedastic | Separates signal from observation noise | Learn from data; use heteroscedastic model for varying noise |

A GP is fully specified by m and k. The zero-mean RBF GP is a reasonable starting point for most regression tasks. For problems with known structure — trends, periodicity, additive decompositions — encode that structure in the mean and covariance functions rather than relying on the data alone. Hyperparameters are learned by maximizing the log marginal likelihood log p(y | X, θ), which automatically balances data fit and prior complexity.

