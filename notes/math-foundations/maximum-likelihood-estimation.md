---
title: "Maximum Likelihood Estimation (MLE)"
slug: "maximum-likelihood-estimation"
description: "Likelihood and log-likelihood, MLE for Gaussian and Bernoulli, logistic regression via MLE, asymptotic properties (consistency, normality, efficiency), Fisher information, and the Cramér-Rao bound."
tags: ["probability", "statistics", "math", "foundations"]
topic: "math-foundations"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type": "text", "content": "Maximum likelihood estimation is the workhorse of statistical inference and the default framework for training ML models. Training a neural network with cross-entropy loss is exactly MLE for a categorical model. Fitting a Gaussian to data is MLE. Linear regression with MSE loss is MLE under a Gaussian noise model. Understanding MLE rigorously — the likelihood function, why we work in log-space, closed-form vs gradient-based solutions, and the asymptotic properties that justify why MLE works — gives a unified theoretical foundation for all these methods."}, {"type": "heading", "level": 2, "content": "Core Definition — Likelihood and Log-Likelihood"}, {"type": "text", "content": "Given a parametric model p(x|θ) and observed data x₁, …, xₙ (iid), the likelihood is:\n\nL(θ; x₁,…,xₙ) = Πᵢ p(xᵢ|θ)\n\nThe MLE is θ̂ = argmax_θ L(θ; x). Taking logs (monotone transformation, preserves argmax):\n\nℓ(θ) = log L(θ) = Σᵢ log p(xᵢ|θ)\n\nWorking with log-likelihood is preferred for two reasons:\n1. **Numerical stability**: products of many probabilities underflow to 0 for large n; sums of log-probabilities remain representable.\n2. **Decomposability**: the log-likelihood decomposes additively over data points, making optimisation, SGD, and mini-batching natural.\n\nFor regular models (smoothly parametrised, identifiable), the MLE is found by solving the score equations: ∇_θ ℓ(θ) = 0. Sometimes closed-form solutions exist (Gaussian, exponential family); more often we use gradient-based optimisation."}, {"type": "code", "language": "python", "content": "import numpy as np\nfrom scipy.optimize import minimize\nfrom scipy.stats import norm\n\nrng = np.random.default_rng(42)\n\n# MLE for Gaussian: closed-form vs gradient ascent\nn = 1000\nmu_true, sigma_true = 3.5, 1.2\nX = rng.normal(mu_true, sigma_true, n)\n\n# Closed-form MLE\nmu_hat     = np.mean(X)\nsigma_hat  = np.std(X, ddof=0)   # MLE uses n (biased)\nsigma_unb  = np.std(X, ddof=1)   # unbiased uses n-1\n\nprint(\"=== Gaussian MLE (n=1000) ===\")\nprint(f\"True:  mu={mu_true}, sigma={sigma_true}\")\nprint(f\"MLE:   mu={mu_hat:.4f}, sigma={sigma_hat:.4f}  (biased)\")\nprint(f\"Unbiased: sigma={sigma_unb:.4f}  (Bessel's correction)\")\n\n# Log-likelihood function\ndef neg_log_likelihood(params, X):\n    mu, log_sigma = params\n    sigma = np.exp(log_sigma)   # reparameterise to ensure sigma > 0\n    return -np.sum(norm.logpdf(X, mu, sigma))\n\n# Gradient-based MLE (should match closed-form)\nresult = minimize(neg_log_likelihood, x0=[0.0, 0.0], args=(X,), method='L-BFGS-B')\nmu_opt, sigma_opt = result.x[0], np.exp(result.x[1])\nprint(f\"Gradient ascent: mu={mu_opt:.4f}, sigma={sigma_opt:.4f}\")\n\n# Log-likelihood at MLE vs other values\nell_mle   = -neg_log_likelihood([mu_hat, np.log(sigma_hat)], X)\nell_wrong = -neg_log_likelihood([mu_hat + 0.5, np.log(sigma_hat)], X)\nprint(f\"\\nLog-likelihood at MLE:       {ell_mle:.2f}\")\nprint(f\"Log-likelihood at mu+0.5:    {ell_wrong:.2f}  (lower, as expected)\")\n\n# MLE for Bernoulli: p_hat = k/n (proportion of successes)\nk, n_bern = 37, 100\np_hat = k / n_bern\nprint(f\"\\n=== Bernoulli MLE ===\")\nprint(f\"Observed: {k}/{n_bern} successes => p_hat = {p_hat:.4f}\")\n# Log-likelihood: k*log(p) + (n-k)*log(1-p)\np_grid = np.linspace(0.01, 0.99, 1000)\nll = k * np.log(p_grid) + (n_bern - k) * np.log(1 - p_grid)\nprint(f\"Max LL at p={p_grid[np.argmax(ll)]:.4f}\")"}, {"type": "heading", "level": 2, "content": "MLE for Logistic Regression"}, {"type": "text", "content": "For binary classification with label y ∈ {0,1} and features x, logistic regression assumes:\n\np(y=1|x, w) = σ(wᵀx) = 1/(1 + exp(−wᵀx))\n\nThe log-likelihood for n iid observations is:\n\nℓ(w) = Σᵢ [yᵢ log σ(wᵀxᵢ) + (1−yᵢ) log(1−σ(wᵀxᵢ))]\n     = Σᵢ [yᵢ wᵀxᵢ − log(1 + exp(wᵀxᵢ))]\n\nThis is concave in w (the Hessian is −X^T D X where D is diagonal with positive entries), so gradient ascent or Newton-Raphson converges to the global maximum. The gradient is:\n\n∇_w ℓ(w) = Σᵢ (yᵢ − σ(wᵀxᵢ)) xᵢ = X^T (y − ŷ)\n\nNewton-Raphson update: w_{t+1} = w_t − H⁻¹ ∇ℓ where H = −X^T D X (IRLS: iteratively reweighted least squares)."}, {"type": "code", "language": "python", "content": "import numpy as np\nfrom scipy.special import expit  # numerically stable sigmoid\n\nrng = np.random.default_rng(42)\n\n# Generate binary classification data\nn, d = 500, 3\nX = rng.standard_normal((n, d))\nX = np.hstack([np.ones((n,1)), X])   # add intercept\nw_true = np.array([0.5, 1.2, -0.8, 0.3])\ny = (rng.uniform(size=n) < expit(X @ w_true)).astype(float)\n\ndef log_likelihood(w, X, y):\n    p = expit(X @ w)\n    return np.sum(y * np.log(p + 1e-15) + (1-y) * np.log(1-p + 1e-15))\n\ndef gradient(w, X, y):\n    return X.T @ (y - expit(X @ w))\n\ndef hessian(w, X):\n    p = expit(X @ w)\n    D = np.diag(p * (1 - p))   # weights\n    return -X.T @ D @ X\n\n# Newton-Raphson (IRLS)\nprint(\"=== Logistic Regression: Newton-Raphson ===\")\nw = np.zeros(d + 1)\nfor it in range(10):\n    g = gradient(w, X, y)\n    H = hessian(w, X)\n    w = w - np.linalg.solve(H, g)   # w = w - H^{-1} g\n    ll = log_likelihood(w, X, y)\n    grad_norm = np.linalg.norm(g)\n    print(f\"  iter {it+1:2d}: ll={ll:.4f}  ||grad||={grad_norm:.4e}\")\n\nprint(f\"\\nTrue w: {w_true}\")\nprint(f\"MLE  w: {np.round(w, 4)}\")\n\n# Gradient ascent comparison\nprint(\"\\n=== Gradient Ascent (lr=0.1) ===\")\nw_gd = np.zeros(d + 1)\nfor it in range(100):\n    w_gd += 0.1 * gradient(w_gd, X, y)\nprint(f\"GD w (100 steps): {np.round(w_gd, 4)}\")\nprint(f\"Newton converges in ~5 steps; GD needs many more.\")"}, {"type": "heading", "level": 2, "content": "Fisher Information and Cramér-Rao Bound"}, {"type": "text", "content": "The Fisher information matrix measures how much information the data carries about θ:\n\nI(θ) = E_θ[(∇_θ log p(X|θ))(∇_θ log p(X|θ))^T] = −E_θ[∇²_θ log p(X|θ)]\n\nFor n iid observations: Iₙ(θ) = n I₁(θ).\n\nThe Cramér-Rao lower bound (CRLB) states that for any unbiased estimator θ̂ of θ:\n\nVar(θ̂) ≥ I(θ)⁻¹\n\nThe MLE achieves this bound asymptotically (it is asymptotically efficient). Fisher information also determines the geometry used by natural gradient descent: the natural gradient ∇̃ℓ = I(θ)⁻¹ ∇ℓ follows the steepest ascent in the space of probability distributions (Fisher-Rao metric), not Euclidean parameter space."}, {"type": "heading", "level": 2, "content": "Asymptotic Properties of MLE"}, {"type": "text", "content": "Under regularity conditions, the MLE has three key asymptotic properties:\n\n1. **Consistency**: θ̂_n → θ* as n → ∞ (in probability). The MLE converges to the true parameter.\n\n2. **Asymptotic normality**: √n (θ̂_n − θ*) → N(0, I(θ*)⁻¹). The MLE is approximately Gaussian around the true parameter, with variance shrinking as 1/n.\n\n3. **Asymptotic efficiency**: the MLE achieves the Cramér-Rao lower bound — no other consistent estimator has smaller asymptotic variance.\n\n4. **Invariance**: if θ̂ is the MLE of θ, then g(θ̂) is the MLE of g(θ) for any function g. This means MLE of σ² is (σ̂)², and MLE of log σ is log σ̂.\n\nThese properties justify using MLE as the default estimator: it is consistent, as efficient as possible, and its uncertainty can be quantified via the Fisher information."}, {"type": "code", "language": "python", "content": "import numpy as np\nfrom scipy.stats import norm\n\nrng = np.random.default_rng(42)\n\n# Demonstrate consistency: MLE converges to true theta as n grows\nmu_true, sigma_true = 2.0, 1.5\nprint(\"=== MLE Consistency for Gaussian mu ===\")\nprint(f\"True mu = {mu_true}\")\nfor n in [10, 100, 1000, 10000, 100000]:\n    X = rng.normal(mu_true, sigma_true, n)\n    mu_hat = np.mean(X)\n    se = sigma_true / np.sqrt(n)\n    print(f\"  n={n:>7,}: mu_hat={mu_hat:.4f}  SE={se:.4f}  error={abs(mu_hat-mu_true):.4f}\")\n\n# Fisher information for Gaussian: I(mu) = 1/sigma^2\nI_mu = 1 / sigma_true**2\nprint(f\"\\nFisher information I(mu) = 1/sigma^2 = {I_mu:.4f}\")\nprint(f\"Cramer-Rao bound on Var(mu_hat): >= 1/(n*I) = sigma^2/n\")\nprint(f\"MLE achieves: Var(sample mean) = sigma^2/n = {sigma_true**2/1000:.6f} (n=1000)\")\n\n# Asymptotic normality: sqrt(n)(mu_hat - mu_true) -> N(0, 1/I)\nprint(\"\\n=== Asymptotic Normality Check (n=100, 5000 reps) ===\")\nn = 100; n_reps = 5000\nmu_hats = [np.mean(rng.normal(mu_true, sigma_true, n)) for _ in range(n_reps)]\nscaled = np.sqrt(n) * (np.array(mu_hats) - mu_true)   # should be ~ N(0, sigma^2)\nprint(f\"Empirical std of sqrt(n)*(mu_hat - mu): {np.std(scaled):.4f}\")\nprint(f\"Theoretical (sigma):                    {sigma_true:.4f}\")\n\n# MLE invariance: MLE of sigma^2 is (sigma_hat)^2\nX_sample = rng.normal(mu_true, sigma_true, 1000)\nsigma_hat = np.std(X_sample, ddof=0)\nprint(f\"\\nMLE invariance: MLE of sigma^2 = (sigma_hat)^2 = {sigma_hat**2:.4f}\")\nprint(f\"Direct MLE of sigma^2 = {np.var(X_sample, ddof=0):.4f}  (same)\")"}, {"type": "heading", "level": 2, "content": "ML and AI Connections"}, {"type": "text", "content": "MLE unifies the training objectives of nearly all discriminative models in ML:\n\n- **Cross-entropy loss** = negative log-likelihood of a categorical model: minimise −Σᵢ log p(yᵢ|xᵢ, θ)\n- **MSE loss** = negative log-likelihood under a Gaussian noise model: p(y|x,θ) = N(y; f(x,θ), σ²)\n- **Binary cross-entropy** = negative log-likelihood of a Bernoulli model: p(y|x,θ) = σ(f(x,θ))^y (1−σ(f(x,θ)))^{1-y}\n- **Contrastive loss / InfoNCE** = MLE for noise-contrastive estimation, learning representations by classifying real from noise samples\n\nFisher information also drives natural gradient methods (NGD, KFAC, Shampoo) which rescale gradients by the inverse Fisher matrix, taking steps that are equidistant in probability space rather than parameter space — potentially much faster convergence for ill-conditioned problems."}, {"type": "heading", "level": 2, "content": "Pitfalls"}, {"type": "text", "content": "Common MLE pitfalls:\n\n1. **Overfitting for small n**: MLE is asymptotically efficient but can severely overfit for small n. A Bernoulli model trained on 3 heads out of 3 flips gives p̂ = 1.0 — predicting heads with certainty. This is why MAP estimation (adding a prior) is preferred for small datasets.\n\n2. **Non-identifiability**: if multiple θ values give the same likelihood, the MLE is not unique. Example: mixture models with permutable component labels. Regularisation or constraints break the symmetry.\n\n3. **Numerical overflow in likelihood**: always work with log-likelihoods, never raw likelihoods. Πᵢ p(xᵢ|θ) underflows to 0 for n as small as 100 for typical ML models.\n\n4. **Confusing MLE with MMSE**: MLE maximises p(D|θ) not E[θ|D]. For asymmetric posteriors or small n, the MLE can be far from the posterior mean."}, {"type": "callout", "variant": "warning", "title": "MLE Requires i.i.d. Data", "content": "Standard MLE theory assumes data points are independent and identically distributed. In practice, data often violates this: time series have temporal correlation, hierarchical data has cluster structure, and fine-tuning data may have domain shift. Ignoring dependence gives asymptotically wrong standard errors and may bias the MLE itself. Use robust standard errors, mixed-effects models, or separate likelihoods for correlated data."}, {"type": "table", "headers": ["Model", "Loss Function", "MLE Interpretation"], "rows": [["Gaussian regression", "MSE = (y-ŷ)²", "MLE under p(y|x)=N(f(x,θ), σ²)"], ["Logistic regression", "Binary cross-entropy", "MLE under p(y|x)=Bernoulli(σ(wᵀx))"], ["Softmax classifier", "Cross-entropy", "MLE under p(y|x)=Categorical(softmax(Wx))"], ["Language model", "Cross-entropy per token", "MLE under p(xₜ|x_{<t})=Categorical"], ["VAE encoder", "ELBO", "Variational MLE for marginal log p(x)"], ["GAN discriminator", "Binary cross-entropy", "Noise-contrastive MLE"]]}, {"type": "divider"}, {"type": "heading", "level": 2, "content": "Key Takeaways"}, {"type": "list", "ordered": false, "items": ["MLE finds θ̂ = argmax_θ Σᵢ log p(xᵢ|θ) — always work with log-likelihood for numerical stability and additive decomposability.", "Closed-form MLE exists for Gaussian (sample mean and biased variance), Bernoulli (sample proportion), and exponential family distributions generally.", "Logistic regression MLE is concave (globally optimal), found efficiently via Newton-Raphson (5-10 iterations) or gradient ascent.", "Fisher information I(θ) = E[(∇ log p)²] measures data informativeness; the Cramér-Rao bound Var(θ̂) ≥ 1/I(θ) lower-bounds any unbiased estimator's variance.", "MLE is asymptotically consistent, normally distributed, and efficient — but can badly overfit for small n; use MAP estimation (regularisation) in that regime.", "Training with cross-entropy loss, MSE loss, or binary cross-entropy is exactly MLE under Categorical, Gaussian, and Bernoulli models respectively.", "Natural gradient descent uses the Fisher information matrix to rescale gradients, stepping in probability space rather than parameter space for faster convergence on ill-conditioned problems."]}]"
---
# Maximum Likelihood Estimation (MLE)

Maximum likelihood estimation is the workhorse of statistical inference and the default framework for training ML models. Training a neural network with cross-entropy loss is exactly MLE for a categorical model. Fitting a Gaussian to data is MLE. Linear regression with MSE loss is MLE under a Gaussian noise model. Understanding MLE rigorously — the likelihood function, why we work in log-space, closed-form vs gradient-based solutions, and the asymptotic properties that justify why MLE works — gives a unified theoretical foundation for all these methods.

## Core Definition — Likelihood and Log-Likelihood

Given a parametric model p(x|θ) and observed data x₁, …, xₙ (iid), the likelihood is:

L(θ; x₁,…,xₙ) = Πᵢ p(xᵢ|θ)

The MLE is θ̂ = argmax_θ L(θ; x). Taking logs (monotone transformation, preserves argmax):

ℓ(θ) = log L(θ) = Σᵢ log p(xᵢ|θ)

Working with log-likelihood is preferred for two reasons:
1. **Numerical stability**: products of many probabilities underflow to 0 for large n; sums of log-probabilities remain representable.
2. **Decomposability**: the log-likelihood decomposes additively over data points, making optimisation, SGD, and mini-batching natural.

For regular models (smoothly parametrised, identifiable), the MLE is found by solving the score equations: ∇_θ ℓ(θ) = 0. Sometimes closed-form solutions exist (Gaussian, exponential family); more often we use gradient-based optimisation.

```python
import numpy as np
from scipy.optimize import minimize
from scipy.stats import norm

rng = np.random.default_rng(42)

# MLE for Gaussian: closed-form vs gradient ascent
n = 1000
mu_true, sigma_true = 3.5, 1.2
X = rng.normal(mu_true, sigma_true, n)

# Closed-form MLE
mu_hat     = np.mean(X)
sigma_hat  = np.std(X, ddof=0)   # MLE uses n (biased)
sigma_unb  = np.std(X, ddof=1)   # unbiased uses n-1

print("=== Gaussian MLE (n=1000) ===")
print(f"True:  mu={mu_true}, sigma={sigma_true}")
print(f"MLE:   mu={mu_hat:.4f}, sigma={sigma_hat:.4f}  (biased)")
print(f"Unbiased: sigma={sigma_unb:.4f}  (Bessel's correction)")

# Log-likelihood function
def neg_log_likelihood(params, X):
    mu, log_sigma = params
    sigma = np.exp(log_sigma)   # reparameterise to ensure sigma > 0
    return -np.sum(norm.logpdf(X, mu, sigma))

# Gradient-based MLE (should match closed-form)
result = minimize(neg_log_likelihood, x0=[0.0, 0.0], args=(X,), method='L-BFGS-B')
mu_opt, sigma_opt = result.x[0], np.exp(result.x[1])
print(f"Gradient ascent: mu={mu_opt:.4f}, sigma={sigma_opt:.4f}")

# Log-likelihood at MLE vs other values
ell_mle   = -neg_log_likelihood([mu_hat, np.log(sigma_hat)], X)
ell_wrong = -neg_log_likelihood([mu_hat + 0.5, np.log(sigma_hat)], X)
print(f"\nLog-likelihood at MLE:       {ell_mle:.2f}")
print(f"Log-likelihood at mu+0.5:    {ell_wrong:.2f}  (lower, as expected)")

# MLE for Bernoulli: p_hat = k/n (proportion of successes)
k, n_bern = 37, 100
p_hat = k / n_bern
print(f"\n=== Bernoulli MLE ===")
print(f"Observed: {k}/{n_bern} successes => p_hat = {p_hat:.4f}")
# Log-likelihood: k*log(p) + (n-k)*log(1-p)
p_grid = np.linspace(0.01, 0.99, 1000)
ll = k * np.log(p_grid) + (n_bern - k) * np.log(1 - p_grid)
print(f"Max LL at p={p_grid[np.argmax(ll)]:.4f}")
```

## MLE for Logistic Regression

For binary classification with label y ∈ {0,1} and features x, logistic regression assumes:

p(y=1|x, w) = σ(wᵀx) = 1/(1 + exp(−wᵀx))

The log-likelihood for n iid observations is:

ℓ(w) = Σᵢ [yᵢ log σ(wᵀxᵢ) + (1−yᵢ) log(1−σ(wᵀxᵢ))]
     = Σᵢ [yᵢ wᵀxᵢ − log(1 + exp(wᵀxᵢ))]

This is concave in w (the Hessian is −X^T D X where D is diagonal with positive entries), so gradient ascent or Newton-Raphson converges to the global maximum. The gradient is:

∇_w ℓ(w) = Σᵢ (yᵢ − σ(wᵀxᵢ)) xᵢ = X^T (y − ŷ)

Newton-Raphson update: w_{t+1} = w_t − H⁻¹ ∇ℓ where H = −X^T D X (IRLS: iteratively reweighted least squares).

```python
import numpy as np
from scipy.special import expit  # numerically stable sigmoid

rng = np.random.default_rng(42)

# Generate binary classification data
n, d = 500, 3
X = rng.standard_normal((n, d))
X = np.hstack([np.ones((n,1)), X])   # add intercept
w_true = np.array([0.5, 1.2, -0.8, 0.3])
y = (rng.uniform(size=n) < expit(X @ w_true)).astype(float)

def log_likelihood(w, X, y):
    p = expit(X @ w)
    return np.sum(y * np.log(p + 1e-15) + (1-y) * np.log(1-p + 1e-15))

def gradient(w, X, y):
    return X.T @ (y - expit(X @ w))

def hessian(w, X):
    p = expit(X @ w)
    D = np.diag(p * (1 - p))   # weights
    return -X.T @ D @ X

# Newton-Raphson (IRLS)
print("=== Logistic Regression: Newton-Raphson ===")
w = np.zeros(d + 1)
for it in range(10):
    g = gradient(w, X, y)
    H = hessian(w, X)
    w = w - np.linalg.solve(H, g)   # w = w - H^{-1} g
    ll = log_likelihood(w, X, y)
    grad_norm = np.linalg.norm(g)
    print(f"  iter {it+1:2d}: ll={ll:.4f}  ||grad||={grad_norm:.4e}")

print(f"\nTrue w: {w_true}")
print(f"MLE  w: {np.round(w, 4)}")

# Gradient ascent comparison
print("\n=== Gradient Ascent (lr=0.1) ===")
w_gd = np.zeros(d + 1)
for it in range(100):
    w_gd += 0.1 * gradient(w_gd, X, y)
print(f"GD w (100 steps): {np.round(w_gd, 4)}")
print(f"Newton converges in ~5 steps; GD needs many more.")
```

## Fisher Information and Cramér-Rao Bound

The Fisher information matrix measures how much information the data carries about θ:

I(θ) = E_θ[(∇_θ log p(X|θ))(∇_θ log p(X|θ))^T] = −E_θ[∇²_θ log p(X|θ)]

For n iid observations: Iₙ(θ) = n I₁(θ).

The Cramér-Rao lower bound (CRLB) states that for any unbiased estimator θ̂ of θ:

Var(θ̂) ≥ I(θ)⁻¹

The MLE achieves this bound asymptotically (it is asymptotically efficient). Fisher information also determines the geometry used by natural gradient descent: the natural gradient ∇̃ℓ = I(θ)⁻¹ ∇ℓ follows the steepest ascent in the space of probability distributions (Fisher-Rao metric), not Euclidean parameter space.

## Asymptotic Properties of MLE

Under regularity conditions, the MLE has three key asymptotic properties:

1. **Consistency**: θ̂_n → θ* as n → ∞ (in probability). The MLE converges to the true parameter.

2. **Asymptotic normality**: √n (θ̂_n − θ*) → N(0, I(θ*)⁻¹). The MLE is approximately Gaussian around the true parameter, with variance shrinking as 1/n.

3. **Asymptotic efficiency**: the MLE achieves the Cramér-Rao lower bound — no other consistent estimator has smaller asymptotic variance.

4. **Invariance**: if θ̂ is the MLE of θ, then g(θ̂) is the MLE of g(θ) for any function g. This means MLE of σ² is (σ̂)², and MLE of log σ is log σ̂.

These properties justify using MLE as the default estimator: it is consistent, as efficient as possible, and its uncertainty can be quantified via the Fisher information.

```python
import numpy as np
from scipy.stats import norm

rng = np.random.default_rng(42)

# Demonstrate consistency: MLE converges to true theta as n grows
mu_true, sigma_true = 2.0, 1.5
print("=== MLE Consistency for Gaussian mu ===")
print(f"True mu = {mu_true}")
for n in [10, 100, 1000, 10000, 100000]:
    X = rng.normal(mu_true, sigma_true, n)
    mu_hat = np.mean(X)
    se = sigma_true / np.sqrt(n)
    print(f"  n={n:>7,}: mu_hat={mu_hat:.4f}  SE={se:.4f}  error={abs(mu_hat-mu_true):.4f}")

# Fisher information for Gaussian: I(mu) = 1/sigma^2
I_mu = 1 / sigma_true**2
print(f"\nFisher information I(mu) = 1/sigma^2 = {I_mu:.4f}")
print(f"Cramer-Rao bound on Var(mu_hat): >= 1/(n*I) = sigma^2/n")
print(f"MLE achieves: Var(sample mean) = sigma^2/n = {sigma_true**2/1000:.6f} (n=1000)")

# Asymptotic normality: sqrt(n)(mu_hat - mu_true) -> N(0, 1/I)
print("\n=== Asymptotic Normality Check (n=100, 5000 reps) ===")
n = 100; n_reps = 5000
mu_hats = [np.mean(rng.normal(mu_true, sigma_true, n)) for _ in range(n_reps)]
scaled = np.sqrt(n) * (np.array(mu_hats) - mu_true)   # should be ~ N(0, sigma^2)
print(f"Empirical std of sqrt(n)*(mu_hat - mu): {np.std(scaled):.4f}")
print(f"Theoretical (sigma):                    {sigma_true:.4f}")

# MLE invariance: MLE of sigma^2 is (sigma_hat)^2
X_sample = rng.normal(mu_true, sigma_true, 1000)
sigma_hat = np.std(X_sample, ddof=0)
print(f"\nMLE invariance: MLE of sigma^2 = (sigma_hat)^2 = {sigma_hat**2:.4f}")
print(f"Direct MLE of sigma^2 = {np.var(X_sample, ddof=0):.4f}  (same)")
```

## ML and AI Connections

MLE unifies the training objectives of nearly all discriminative models in ML:

- **Cross-entropy loss** = negative log-likelihood of a categorical model: minimise −Σᵢ log p(yᵢ|xᵢ, θ)
- **MSE loss** = negative log-likelihood under a Gaussian noise model: p(y|x,θ) = N(y; f(x,θ), σ²)
- **Binary cross-entropy** = negative log-likelihood of a Bernoulli model: p(y|x,θ) = σ(f(x,θ))^y (1−σ(f(x,θ)))^{1-y}
- **Contrastive loss / InfoNCE** = MLE for noise-contrastive estimation, learning representations by classifying real from noise samples

Fisher information also drives natural gradient methods (NGD, KFAC, Shampoo) which rescale gradients by the inverse Fisher matrix, taking steps that are equidistant in probability space rather than parameter space — potentially much faster convergence for ill-conditioned problems.

## Pitfalls

Common MLE pitfalls:

1. **Overfitting for small n**: MLE is asymptotically efficient but can severely overfit for small n. A Bernoulli model trained on 3 heads out of 3 flips gives p̂ = 1.0 — predicting heads with certainty. This is why MAP estimation (adding a prior) is preferred for small datasets.

2. **Non-identifiability**: if multiple θ values give the same likelihood, the MLE is not unique. Example: mixture models with permutable component labels. Regularisation or constraints break the symmetry.

3. **Numerical overflow in likelihood**: always work with log-likelihoods, never raw likelihoods. Πᵢ p(xᵢ|θ) underflows to 0 for n as small as 100 for typical ML models.

4. **Confusing MLE with MMSE**: MLE maximises p(D|θ) not E[θ|D]. For asymmetric posteriors or small n, the MLE can be far from the posterior mean.

> **WARNING: MLE Requires i.i.d. Data**
>
> Standard MLE theory assumes data points are independent and identically distributed. In practice, data often violates this: time series have temporal correlation, hierarchical data has cluster structure, and fine-tuning data may have domain shift. Ignoring dependence gives asymptotically wrong standard errors and may bias the MLE itself. Use robust standard errors, mixed-effects models, or separate likelihoods for correlated data.

| Model | Loss Function | MLE Interpretation |
| --- | --- | --- |
| Gaussian regression | MSE = (y-ŷ)² | MLE under p(y|x)=N(f(x,θ), σ²) |
| Logistic regression | Binary cross-entropy | MLE under p(y|x)=Bernoulli(σ(wᵀx)) |
| Softmax classifier | Cross-entropy | MLE under p(y|x)=Categorical(softmax(Wx)) |
| Language model | Cross-entropy per token | MLE under p(xₜ|x_{<t})=Categorical |
| VAE encoder | ELBO | Variational MLE for marginal log p(x) |
| GAN discriminator | Binary cross-entropy | Noise-contrastive MLE |

---

## Key Takeaways

- MLE finds θ̂ = argmax_θ Σᵢ log p(xᵢ|θ) — always work with log-likelihood for numerical stability and additive decomposability.
- Closed-form MLE exists for Gaussian (sample mean and biased variance), Bernoulli (sample proportion), and exponential family distributions generally.
- Logistic regression MLE is concave (globally optimal), found efficiently via Newton-Raphson (5-10 iterations) or gradient ascent.
- Fisher information I(θ) = E[(∇ log p)²] measures data informativeness; the Cramér-Rao bound Var(θ̂) ≥ 1/I(θ) lower-bounds any unbiased estimator's variance.
- MLE is asymptotically consistent, normally distributed, and efficient — but can badly overfit for small n; use MAP estimation (regularisation) in that regime.
- Training with cross-entropy loss, MSE loss, or binary cross-entropy is exactly MLE under Categorical, Gaussian, and Bernoulli models respectively.
- Natural gradient descent uses the Fisher information matrix to rescale gradients, stepping in probability space rather than parameter space for faster convergence on ill-conditioned problems.
