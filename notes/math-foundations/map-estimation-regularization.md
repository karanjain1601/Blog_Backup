---
title: "MAP Estimation and Its Connection to Regularization"
slug: "map-estimation-regularization"
description: "MAP estimation as penalised MLE, Gaussian prior yields L2 regularisation, Laplace prior yields L1 (Lasso), empirical Bayes for hyperparameter selection, and when MAP differs from the posterior mean."
tags: ["probability", "statistics", "math", "foundations"]
topic: "math-foundations"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type": "text", "content": "Maximum a posteriori (MAP) estimation is the most common bridge between Bayesian statistics and practical ML. It adds a prior p(θ) to the MLE objective and maximises the unnormalised posterior p(D|θ) p(θ). The remarkable insight is that this is equivalent to regularised maximum likelihood: the Gaussian prior produces exactly L2 (ridge) regularisation, and the Laplace prior produces exactly L1 (Lasso) regularisation. Understanding MAP estimation shows that regularisation is not an ad hoc trick but a principled Bayesian choice of prior, and that the regularisation strength λ controls the prior scale."}, {"type": "heading", "level": 2, "content": "Core Definition"}, {"type": "text", "content": "MAP estimation finds the mode of the posterior distribution:\n\nθ̂_MAP = argmax_θ p(θ|D)\n       = argmax_θ [log p(D|θ) + log p(θ)]\n       = argmax_θ [ℓ(θ) + log p(θ)]\n\nBecause p(D) does not depend on θ, we maximise the unnormalised posterior. MAP equals MLE when the prior p(θ) is uniform (flat/uninformative) — uniform prior contributes a constant log prior and does not change the argmax.\n\nIn contrast to full Bayesian inference (which computes the entire posterior distribution p(θ|D)), MAP returns only a point estimate — the peak of the posterior. This makes MAP computationally tractable (optimisation rather than integration) but discards uncertainty information."}, {"type": "heading", "level": 2, "content": "Gaussian Prior = L2 Regularisation"}, {"type": "text", "content": "Suppose the prior on weights w is an isotropic Gaussian: p(w) = N(0, σ_p² I).\n\nlog p(w) = −‖w‖² / (2σ_p²) + const\n\nMAP objective:\nθ̂_MAP = argmax_w [ℓ(w) − ‖w‖² / (2σ_p²)]\n       = argmin_w [−ℓ(w) + λ‖w‖²]   where λ = 1/(2σ_p²)\n\nThis is exactly ridge regression (L2-regularised linear regression) or weight decay in neural networks. The regularisation strength λ is the inverse of twice the prior variance:\n- Large σ_p (diffuse prior) → small λ → weak regularisation → approaches MLE\n- Small σ_p (tight prior near 0) → large λ → strong regularisation → shrinks weights to 0\n\nThis reveals that weight decay in neural network training is equivalent to placing a Gaussian prior on the weights — a fundamental Bayesian justification for this universal heuristic."}, {"type": "code", "language": "python", "content": "import numpy as np\nfrom sklearn.linear_model import Ridge, Lasso, LinearRegression\n\nrng = np.random.default_rng(42)\n\n# Generate regression data\nn, d = 100, 20\nX = rng.standard_normal((n, d))\nw_true = rng.standard_normal(d) * 0.5\nw_true[10:] = 0.0   # last 10 coefficients are zero (sparse)\ny = X @ w_true + rng.normal(0, 0.5, n)\n\n# MLE = OLS (uniform prior)\nols = LinearRegression(fit_intercept=False).fit(X, y)\n\n# MAP with Gaussian prior (sigma_p = 1) => L2 reg with lambda = 1/(2*1^2) = 0.5\n# But sklearn Ridge uses alpha = lambda, so alpha = 0.5\nsigma_p = 1.0\nlam_ridge = 1 / (2 * sigma_p**2)\nridge = Ridge(alpha=lam_ridge, fit_intercept=False).fit(X, y)\n\n# MAP with Laplace prior (b=1) => L1 reg with lambda = 1/b = 1\nb_laplace = 1.0\nlam_lasso = 1 / b_laplace\nlasso = Lasso(alpha=lam_lasso / n, fit_intercept=False, max_iter=10000).fit(X, y)\n\nprint(\"=== MAP vs MLE: coefficient recovery ===\")\nprint(f\"True w (first 5):  {np.round(w_true[:5], 3)}\")\nprint(f\"OLS  w (first 5):  {np.round(ols.coef_[:5], 3)}\")\nprint(f\"Ridge w (first 5): {np.round(ridge.coef_[:5], 3)}\")\nprint(f\"Lasso w (first 5): {np.round(lasso.coef_[:5], 3)}\")\nprint()\nprint(f\"True w (last 5, should be 0): {np.round(w_true[15:], 3)}\")\nprint(f\"OLS  w (last 5):  {np.round(ols.coef_[15:], 3)}\")\nprint(f\"Ridge w (last 5): {np.round(ridge.coef_[15:], 3)}\")\nprint(f\"Lasso w (last 5): {np.round(lasso.coef_[15:], 3)}\")\n\nprint(\"\\n=== Number of zero coefficients (sparsity) ===\")\neps = 1e-4\nprint(f\"OLS   zeros: {np.sum(np.abs(ols.coef_)   < eps)}/20\")\nprint(f\"Ridge zeros: {np.sum(np.abs(ridge.coef_) < eps)}/20\")\nprint(f\"Lasso zeros: {np.sum(np.abs(lasso.coef_) < eps)}/20\")"}, {"type": "heading", "level": 2, "content": "Laplace Prior = L1 Regularisation"}, {"type": "text", "content": "The Laplace (double exponential) prior: p(w) ∝ exp(−λ|w|)\n\nlog p(w) = −λ‖w‖₁ + const\n\nMAP objective:\nθ̂_MAP = argmin_w [−ℓ(w) + λ‖w‖₁]\n\nThis is the Lasso (Least Absolute Shrinkage and Selection Operator) for linear regression. The Laplace prior has heavier tails than the Gaussian but a sharp peak at zero, which encourages exact sparsity: many weights are set to exactly 0. In contrast, the Gaussian prior shrinks weights toward zero but almost never sets them exactly to zero.\n\nIntuitively: at a weight w = ε near zero, the L2 penalty gradient is 2λε (small), not pushing strongly toward zero. The L1 penalty gradient is λ (constant), always pushing toward zero with the same force regardless of the weight magnitude. This constant push is what creates exact zeros through the subdifferential at w = 0."}, {"type": "heading", "level": 2, "content": "Empirical Bayes"}, {"type": "text", "content": "How do we choose the regularisation strength λ (equivalently, the prior hyperparameter σ_p)? Several approaches:\n\n1. **Cross-validation**: grid search over λ values, select by held-out loss. Practical and model-agnostic.\n\n2. **Empirical Bayes (Type-II MLE)**: maximise the marginal likelihood p(D|λ) = ∫ p(D|w, λ) p(w|λ) dw over λ. This marginalises out w, so λ is chosen by the data itself — 'letting the data choose the prior'.\n\n3. **Evidence maximisation**: for Gaussian linear models, the marginal likelihood has a closed form. For neural networks, it is approximated via Laplace approximation or ELBO methods.\n\nEmpirical Bayes can overfit (especially for small datasets) because we are choosing the prior based on the data — technically a frequentist method despite the Bayesian framing. Use cross-validation as a sanity check."}, {"type": "code", "language": "python", "content": "import numpy as np\nfrom scipy.optimize import minimize_scalar\nfrom scipy.linalg import solve\n\nrng = np.random.default_rng(42)\n\n# Empirical Bayes for Gaussian linear regression\n# Model: y = Xw + eps, w ~ N(0, alpha^{-1} I), eps ~ N(0, beta^{-1} I)\n# Marginal likelihood: p(y|X, alpha, beta) = N(y; 0, beta^{-1}I + alpha^{-1} XX^T)\n# Here we find alpha (prior precision) via marginal likelihood maximisation\n\nn, d = 50, 5\nX = rng.standard_normal((n, d))\nw_true = rng.standard_normal(d)\nbeta = 25.0  # noise precision (known for simplicity)\ny = X @ w_true + rng.normal(0, 1/np.sqrt(beta), n)\n\ndef log_marginal_likelihood(log_alpha):\n    alpha = np.exp(log_alpha)\n    # Covariance of y: C = (1/beta) I + (1/alpha) X X^T\n    C = (1/beta) * np.eye(n) + (1/alpha) * X @ X.T\n    sign, logdet = np.linalg.slogdet(C)\n    y_Cinv_y = y @ np.linalg.solve(C, y)\n    return -0.5 * (n * np.log(2*np.pi) + logdet + y_Cinv_y)\n\n# Search over alpha values\nalpha_grid = np.logspace(-3, 3, 100)\nlml_vals = [log_marginal_likelihood(np.log(a)) for a in alpha_grid]\nbest_alpha = alpha_grid[np.argmax(lml_vals)]\nprint(f\"Empirical Bayes best alpha (prior precision) = {best_alpha:.4f}\")\nprint(f\"Corresponding lambda = alpha/beta = {best_alpha/beta:.4f}\")\nprint(f\"Corresponding sigma_prior = 1/sqrt(alpha) = {1/np.sqrt(best_alpha):.4f}\")\n\n# MAP estimate with empirical Bayes prior\nA = beta * X.T @ X + best_alpha * np.eye(d)\nw_map = beta * solve(A, X.T @ y)\nw_mle = np.linalg.lstsq(X, y, rcond=None)[0]\nprint(f\"\\nTrue w:       {np.round(w_true, 3)}\")\nprint(f\"MLE w:        {np.round(w_mle, 3)}\")\nprint(f\"Emp. Bayes w: {np.round(w_map, 3)}\")\nprint(f\"\\nMSE(MLE):    {np.mean((w_mle - w_true)**2):.4f}\")\nprint(f\"MSE(EB-MAP): {np.mean((w_map - w_true)**2):.4f}\")"}, {"type": "heading", "level": 2, "content": "MAP vs MLE vs Posterior Mean"}, {"type": "text", "content": "For a Gaussian posterior (e.g., Bayesian linear regression with Gaussian prior and Gaussian likelihood), the MAP estimate equals the posterior mean. This is because a Gaussian is symmetric and unimodal, so its mode equals its mean.\n\nFor non-Gaussian posteriors (logistic regression, complex models), MAP differs from the posterior mean:\n- MAP is the mode: the single most probable parameter value\n- Posterior mean: the probability-weighted average over all parameter values\n- Posterior mean minimises expected squared loss, MAP minimises 0-1 loss (finds the most probable point)\n\nFor asymmetric or multimodal posteriors (common in deep learning), the MAP estimate may be a poor summary of the posterior. For example, if the posterior has two roughly equal modes, the MAP picks one and ignores the other — the posterior mean might fall between the modes in a low-probability region. In deep learning, many local minima are approximately equally good (flat loss landscape), and MAP just finds one of them."}, {"type": "code", "language": "python", "content": "import numpy as np\nfrom scipy import stats\n\nrng = np.random.default_rng(42)\n\n# Beta-Binomial: MAP vs posterior mean\n# Posterior: Beta(a + k, b + n - k) where prior is Beta(a, b)\n# MAP = (a + k - 1) / (a + b + n - 2)   (mode of Beta)\n# Mean = (a + k) / (a + b + n)\n\nn_flips, k_heads = 10, 3\na_prior, b_prior = 2.0, 2.0  # Beta(2,2) symmetric prior\n\na_post = a_prior + k_heads\nb_post = b_prior + (n_flips - k_heads)\n\nmap_est  = (a_post - 1) / (a_post + b_post - 2)\npost_mean = a_post / (a_post + b_post)\nmle_est  = k_heads / n_flips\n\nprint(\"=== Beta-Bernoulli: MAP vs MLE vs Posterior Mean ===\")\nprint(f\"Data: {k_heads}/{n_flips} heads, Prior: Beta({a_prior}, {b_prior})\")\nprint(f\"Posterior: Beta({a_post}, {b_post})\")\nprint(f\"MLE:            {mle_est:.4f}\")\nprint(f\"MAP:            {map_est:.4f}  (mode of Beta)\")\nprint(f\"Posterior mean: {post_mean:.4f}  (mean of Beta)\")\n\n# Effect of sample size on MAP vs posterior mean gap\nprint(\"\\n=== MAP vs Posterior Mean as n grows ===\")\nfor n in [5, 20, 100, 1000]:\n    k = round(0.3 * n)  # 30% heads\n    ap, bp = a_prior + k, b_prior + (n - k)\n    map_e  = (ap - 1) / (ap + bp - 2)\n    mean_e = ap / (ap + bp)\n    print(f\"  n={n:>5}: k={k:>3}  MAP={map_e:.4f}  E[theta|D]={mean_e:.4f}  diff={abs(map_e-mean_e):.4f}\")\nprint(\"  -> MAP and posterior mean converge as n -> inf\")\n\n# Visualise: MAP vs posterior mean for skewed posterior\nprint(\"\\n=== Skewed Gamma posterior ===\")\n# Posterior ~ Gamma(shape, rate) — asymmetric, MAP != mean\nshape, rate = 2.5, 3.0\nfrom scipy.stats import gamma\nmode_gamma = (shape - 1) / rate if shape >= 1 else 0.0\nmean_gamma = shape / rate\nprint(f\"Gamma({shape}, {rate}): mode(MAP)={mode_gamma:.4f}, mean={mean_gamma:.4f}, diff={abs(mean_gamma-mode_gamma):.4f}\")"}, {"type": "heading", "level": 2, "content": "Pitfalls"}, {"type": "text", "content": "Common MAP estimation pitfalls:\n\n1. **Confusing prior scale with regularisation strength**: λ = 1/(2σ_p²) for L2; doubling the prior variance halves λ. Always be clear which parameterisation you're using.\n\n2. **MAP ignores posterior uncertainty**: a single point estimate discards the shape, width, and multimodality of the posterior. For safety-critical applications, compute posterior credible intervals.\n\n3. **Mode vs mean mismatch**: for skewed posteriors (Gamma, Beta with low counts), the MAP (mode) can be far from the posterior mean. The MAP minimises 0-1 loss; the mean minimises squared loss.\n\n4. **Flat regions in deep learning**: neural networks often have large flat regions in loss landscape where many configurations are approximately equally good. 'MAP' in this context is just one of many equivalent solutions — the invariance of overparameterised models makes the prior choice particularly important for implicit regularisation."}, {"type": "callout", "variant": "tip", "title": "L2 Regularisation ≠ Weight Decay in Adaptive Methods", "content": "For SGD with momentum, L2 regularisation (adding λ‖w‖² to the loss) and weight decay (multiplying weights by (1−λ·lr) after each step) are equivalent. For Adam and other adaptive methods, they are NOT equivalent: L2 reg rescales the gradient, which is then divided by the adaptive step size, reducing the effective regularisation for parameters with large gradients. AdamW (decoupled weight decay) applies weight decay directly to the weights, not through the gradient, restoring the intended Bayesian prior interpretation."}, {"type": "table", "headers": ["Prior", "Regularisation", "Effect", "Typical λ"], "rows": [["Uniform (improper)", "None (MLE)", "No shrinkage", "—"], ["Gaussian N(0,σ²I)", "L2 / Ridge / weight decay", "Shrinks all weights toward 0", "0.01–0.1"], ["Laplace(0,b)", "L1 / Lasso", "Exact sparsity, feature selection", "0.001–0.1"], ["Student-t", "Robust (heavy tails)", "Allows occasional large weights", "Application-specific"], ["Spike-and-slab", "Hard sparsity", "Binary mask on each weight", "Variational or MCMC"]]}, {"type": "divider"}, {"type": "heading", "level": 2, "content": "Key Takeaways"}, {"type": "list", "ordered": false, "items": ["MAP = argmax_θ [log p(D|θ) + log p(θ)] — it is MLE plus a log-prior penalty; uniform prior recovers MLE.", "Gaussian prior N(0, σ_p²I) ↔ L2 regularisation λ‖w‖² with λ = 1/(2σ_p²); large prior variance = weak regularisation.", "Laplace prior exp(−λ|w|) ↔ L1 regularisation λ‖w‖₁; the sharp zero-peak creates exact sparsity unlike the Gaussian.", "Empirical Bayes selects the prior hyperparameter λ by maximising the marginal likelihood p(D|λ) — letting data choose the prior.", "MAP equals the posterior mean only for Gaussian posteriors (symmetric, unimodal); for asymmetric or multimodal posteriors they differ.", "AdamW implements decoupled weight decay — equivalent to a Gaussian prior under Adam — while L2 regularisation in Adam is not equivalent due to adaptive step rescaling.", "Regularisation in deep learning is implicit MAP: L2 weight decay encodes a Gaussian prior on all weights; dropout approximates a Bernoulli spike-and-slab prior."]}]"
---
# MAP Estimation and Its Connection to Regularization

Maximum a posteriori (MAP) estimation is the most common bridge between Bayesian statistics and practical ML. It adds a prior p(θ) to the MLE objective and maximises the unnormalised posterior p(D|θ) p(θ). The remarkable insight is that this is equivalent to regularised maximum likelihood: the Gaussian prior produces exactly L2 (ridge) regularisation, and the Laplace prior produces exactly L1 (Lasso) regularisation. Understanding MAP estimation shows that regularisation is not an ad hoc trick but a principled Bayesian choice of prior, and that the regularisation strength λ controls the prior scale.

## Core Definition

MAP estimation finds the mode of the posterior distribution:

θ̂_MAP = argmax_θ p(θ|D)
       = argmax_θ [log p(D|θ) + log p(θ)]
       = argmax_θ [ℓ(θ) + log p(θ)]

Because p(D) does not depend on θ, we maximise the unnormalised posterior. MAP equals MLE when the prior p(θ) is uniform (flat/uninformative) — uniform prior contributes a constant log prior and does not change the argmax.

In contrast to full Bayesian inference (which computes the entire posterior distribution p(θ|D)), MAP returns only a point estimate — the peak of the posterior. This makes MAP computationally tractable (optimisation rather than integration) but discards uncertainty information.

## Gaussian Prior = L2 Regularisation

Suppose the prior on weights w is an isotropic Gaussian: p(w) = N(0, σ_p² I).

log p(w) = −‖w‖² / (2σ_p²) + const

MAP objective:
θ̂_MAP = argmax_w [ℓ(w) − ‖w‖² / (2σ_p²)]
       = argmin_w [−ℓ(w) + λ‖w‖²]   where λ = 1/(2σ_p²)

This is exactly ridge regression (L2-regularised linear regression) or weight decay in neural networks. The regularisation strength λ is the inverse of twice the prior variance:
- Large σ_p (diffuse prior) → small λ → weak regularisation → approaches MLE
- Small σ_p (tight prior near 0) → large λ → strong regularisation → shrinks weights to 0

This reveals that weight decay in neural network training is equivalent to placing a Gaussian prior on the weights — a fundamental Bayesian justification for this universal heuristic.

```python
import numpy as np
from sklearn.linear_model import Ridge, Lasso, LinearRegression

rng = np.random.default_rng(42)

# Generate regression data
n, d = 100, 20
X = rng.standard_normal((n, d))
w_true = rng.standard_normal(d) * 0.5
w_true[10:] = 0.0   # last 10 coefficients are zero (sparse)
y = X @ w_true + rng.normal(0, 0.5, n)

# MLE = OLS (uniform prior)
ols = LinearRegression(fit_intercept=False).fit(X, y)

# MAP with Gaussian prior (sigma_p = 1) => L2 reg with lambda = 1/(2*1^2) = 0.5
# But sklearn Ridge uses alpha = lambda, so alpha = 0.5
sigma_p = 1.0
lam_ridge = 1 / (2 * sigma_p**2)
ridge = Ridge(alpha=lam_ridge, fit_intercept=False).fit(X, y)

# MAP with Laplace prior (b=1) => L1 reg with lambda = 1/b = 1
b_laplace = 1.0
lam_lasso = 1 / b_laplace
lasso = Lasso(alpha=lam_lasso / n, fit_intercept=False, max_iter=10000).fit(X, y)

print("=== MAP vs MLE: coefficient recovery ===")
print(f"True w (first 5):  {np.round(w_true[:5], 3)}")
print(f"OLS  w (first 5):  {np.round(ols.coef_[:5], 3)}")
print(f"Ridge w (first 5): {np.round(ridge.coef_[:5], 3)}")
print(f"Lasso w (first 5): {np.round(lasso.coef_[:5], 3)}")
print()
print(f"True w (last 5, should be 0): {np.round(w_true[15:], 3)}")
print(f"OLS  w (last 5):  {np.round(ols.coef_[15:], 3)}")
print(f"Ridge w (last 5): {np.round(ridge.coef_[15:], 3)}")
print(f"Lasso w (last 5): {np.round(lasso.coef_[15:], 3)}")

print("\n=== Number of zero coefficients (sparsity) ===")
eps = 1e-4
print(f"OLS   zeros: {np.sum(np.abs(ols.coef_)   < eps)}/20")
print(f"Ridge zeros: {np.sum(np.abs(ridge.coef_) < eps)}/20")
print(f"Lasso zeros: {np.sum(np.abs(lasso.coef_) < eps)}/20")
```

## Laplace Prior = L1 Regularisation

The Laplace (double exponential) prior: p(w) ∝ exp(−λ|w|)

log p(w) = −λ‖w‖₁ + const

MAP objective:
θ̂_MAP = argmin_w [−ℓ(w) + λ‖w‖₁]

This is the Lasso (Least Absolute Shrinkage and Selection Operator) for linear regression. The Laplace prior has heavier tails than the Gaussian but a sharp peak at zero, which encourages exact sparsity: many weights are set to exactly 0. In contrast, the Gaussian prior shrinks weights toward zero but almost never sets them exactly to zero.

Intuitively: at a weight w = ε near zero, the L2 penalty gradient is 2λε (small), not pushing strongly toward zero. The L1 penalty gradient is λ (constant), always pushing toward zero with the same force regardless of the weight magnitude. This constant push is what creates exact zeros through the subdifferential at w = 0.

## Empirical Bayes

How do we choose the regularisation strength λ (equivalently, the prior hyperparameter σ_p)? Several approaches:

1. **Cross-validation**: grid search over λ values, select by held-out loss. Practical and model-agnostic.

2. **Empirical Bayes (Type-II MLE)**: maximise the marginal likelihood p(D|λ) = ∫ p(D|w, λ) p(w|λ) dw over λ. This marginalises out w, so λ is chosen by the data itself — 'letting the data choose the prior'.

3. **Evidence maximisation**: for Gaussian linear models, the marginal likelihood has a closed form. For neural networks, it is approximated via Laplace approximation or ELBO methods.

Empirical Bayes can overfit (especially for small datasets) because we are choosing the prior based on the data — technically a frequentist method despite the Bayesian framing. Use cross-validation as a sanity check.

```python
import numpy as np
from scipy.optimize import minimize_scalar
from scipy.linalg import solve

rng = np.random.default_rng(42)

# Empirical Bayes for Gaussian linear regression
# Model: y = Xw + eps, w ~ N(0, alpha^{-1} I), eps ~ N(0, beta^{-1} I)
# Marginal likelihood: p(y|X, alpha, beta) = N(y; 0, beta^{-1}I + alpha^{-1} XX^T)
# Here we find alpha (prior precision) via marginal likelihood maximisation

n, d = 50, 5
X = rng.standard_normal((n, d))
w_true = rng.standard_normal(d)
beta = 25.0  # noise precision (known for simplicity)
y = X @ w_true + rng.normal(0, 1/np.sqrt(beta), n)

def log_marginal_likelihood(log_alpha):
    alpha = np.exp(log_alpha)
    # Covariance of y: C = (1/beta) I + (1/alpha) X X^T
    C = (1/beta) * np.eye(n) + (1/alpha) * X @ X.T
    sign, logdet = np.linalg.slogdet(C)
    y_Cinv_y = y @ np.linalg.solve(C, y)
    return -0.5 * (n * np.log(2*np.pi) + logdet + y_Cinv_y)

# Search over alpha values
alpha_grid = np.logspace(-3, 3, 100)
lml_vals = [log_marginal_likelihood(np.log(a)) for a in alpha_grid]
best_alpha = alpha_grid[np.argmax(lml_vals)]
print(f"Empirical Bayes best alpha (prior precision) = {best_alpha:.4f}")
print(f"Corresponding lambda = alpha/beta = {best_alpha/beta:.4f}")
print(f"Corresponding sigma_prior = 1/sqrt(alpha) = {1/np.sqrt(best_alpha):.4f}")

# MAP estimate with empirical Bayes prior
A = beta * X.T @ X + best_alpha * np.eye(d)
w_map = beta * solve(A, X.T @ y)
w_mle = np.linalg.lstsq(X, y, rcond=None)[0]
print(f"\nTrue w:       {np.round(w_true, 3)}")
print(f"MLE w:        {np.round(w_mle, 3)}")
print(f"Emp. Bayes w: {np.round(w_map, 3)}")
print(f"\nMSE(MLE):    {np.mean((w_mle - w_true)**2):.4f}")
print(f"MSE(EB-MAP): {np.mean((w_map - w_true)**2):.4f}")
```

## MAP vs MLE vs Posterior Mean

For a Gaussian posterior (e.g., Bayesian linear regression with Gaussian prior and Gaussian likelihood), the MAP estimate equals the posterior mean. This is because a Gaussian is symmetric and unimodal, so its mode equals its mean.

For non-Gaussian posteriors (logistic regression, complex models), MAP differs from the posterior mean:
- MAP is the mode: the single most probable parameter value
- Posterior mean: the probability-weighted average over all parameter values
- Posterior mean minimises expected squared loss, MAP minimises 0-1 loss (finds the most probable point)

For asymmetric or multimodal posteriors (common in deep learning), the MAP estimate may be a poor summary of the posterior. For example, if the posterior has two roughly equal modes, the MAP picks one and ignores the other — the posterior mean might fall between the modes in a low-probability region. In deep learning, many local minima are approximately equally good (flat loss landscape), and MAP just finds one of them.

```python
import numpy as np
from scipy import stats

rng = np.random.default_rng(42)

# Beta-Binomial: MAP vs posterior mean
# Posterior: Beta(a + k, b + n - k) where prior is Beta(a, b)
# MAP = (a + k - 1) / (a + b + n - 2)   (mode of Beta)
# Mean = (a + k) / (a + b + n)

n_flips, k_heads = 10, 3
a_prior, b_prior = 2.0, 2.0  # Beta(2,2) symmetric prior

a_post = a_prior + k_heads
b_post = b_prior + (n_flips - k_heads)

map_est  = (a_post - 1) / (a_post + b_post - 2)
post_mean = a_post / (a_post + b_post)
mle_est  = k_heads / n_flips

print("=== Beta-Bernoulli: MAP vs MLE vs Posterior Mean ===")
print(f"Data: {k_heads}/{n_flips} heads, Prior: Beta({a_prior}, {b_prior})")
print(f"Posterior: Beta({a_post}, {b_post})")
print(f"MLE:            {mle_est:.4f}")
print(f"MAP:            {map_est:.4f}  (mode of Beta)")
print(f"Posterior mean: {post_mean:.4f}  (mean of Beta)")

# Effect of sample size on MAP vs posterior mean gap
print("\n=== MAP vs Posterior Mean as n grows ===")
for n in [5, 20, 100, 1000]:
    k = round(0.3 * n)  # 30% heads
    ap, bp = a_prior + k, b_prior + (n - k)
    map_e  = (ap - 1) / (ap + bp - 2)
    mean_e = ap / (ap + bp)
    print(f"  n={n:>5}: k={k:>3}  MAP={map_e:.4f}  E[theta|D]={mean_e:.4f}  diff={abs(map_e-mean_e):.4f}")
print("  -> MAP and posterior mean converge as n -> inf")

# Visualise: MAP vs posterior mean for skewed posterior
print("\n=== Skewed Gamma posterior ===")
# Posterior ~ Gamma(shape, rate) — asymmetric, MAP != mean
shape, rate = 2.5, 3.0
from scipy.stats import gamma
mode_gamma = (shape - 1) / rate if shape >= 1 else 0.0
mean_gamma = shape / rate
print(f"Gamma({shape}, {rate}): mode(MAP)={mode_gamma:.4f}, mean={mean_gamma:.4f}, diff={abs(mean_gamma-mode_gamma):.4f}")
```

## Pitfalls

Common MAP estimation pitfalls:

1. **Confusing prior scale with regularisation strength**: λ = 1/(2σ_p²) for L2; doubling the prior variance halves λ. Always be clear which parameterisation you're using.

2. **MAP ignores posterior uncertainty**: a single point estimate discards the shape, width, and multimodality of the posterior. For safety-critical applications, compute posterior credible intervals.

3. **Mode vs mean mismatch**: for skewed posteriors (Gamma, Beta with low counts), the MAP (mode) can be far from the posterior mean. The MAP minimises 0-1 loss; the mean minimises squared loss.

4. **Flat regions in deep learning**: neural networks often have large flat regions in loss landscape where many configurations are approximately equally good. 'MAP' in this context is just one of many equivalent solutions — the invariance of overparameterised models makes the prior choice particularly important for implicit regularisation.

> **TIP: L2 Regularisation ≠ Weight Decay in Adaptive Methods**
>
> For SGD with momentum, L2 regularisation (adding λ‖w‖² to the loss) and weight decay (multiplying weights by (1−λ·lr) after each step) are equivalent. For Adam and other adaptive methods, they are NOT equivalent: L2 reg rescales the gradient, which is then divided by the adaptive step size, reducing the effective regularisation for parameters with large gradients. AdamW (decoupled weight decay) applies weight decay directly to the weights, not through the gradient, restoring the intended Bayesian prior interpretation.

| Prior | Regularisation | Effect | Typical λ |
| --- | --- | --- | --- |
| Uniform (improper) | None (MLE) | No shrinkage | — |
| Gaussian N(0,σ²I) | L2 / Ridge / weight decay | Shrinks all weights toward 0 | 0.01–0.1 |
| Laplace(0,b) | L1 / Lasso | Exact sparsity, feature selection | 0.001–0.1 |
| Student-t | Robust (heavy tails) | Allows occasional large weights | Application-specific |
| Spike-and-slab | Hard sparsity | Binary mask on each weight | Variational or MCMC |

---

## Key Takeaways

- MAP = argmax_θ [log p(D|θ) + log p(θ)] — it is MLE plus a log-prior penalty; uniform prior recovers MLE.
- Gaussian prior N(0, σ_p²I) ↔ L2 regularisation λ‖w‖² with λ = 1/(2σ_p²); large prior variance = weak regularisation.
- Laplace prior exp(−λ|w|) ↔ L1 regularisation λ‖w‖₁; the sharp zero-peak creates exact sparsity unlike the Gaussian.
- Empirical Bayes selects the prior hyperparameter λ by maximising the marginal likelihood p(D|λ) — letting data choose the prior.
- MAP equals the posterior mean only for Gaussian posteriors (symmetric, unimodal); for asymmetric or multimodal posteriors they differ.
- AdamW implements decoupled weight decay — equivalent to a Gaussian prior under Adam — while L2 regularisation in Adam is not equivalent due to adaptive step rescaling.
- Regularisation in deep learning is implicit MAP: L2 weight decay encodes a Gaussian prior on all weights; dropout approximates a Bernoulli spike-and-slab prior.
