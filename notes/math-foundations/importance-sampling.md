---
title: "Importance Sampling"
slug: "importance-sampling"
description: "The importance sampling estimator, self-normalised IS, effective sample size, variance explosion with mismatched proposals, weight clipping, annealed IS, and applications in off-policy RL and RLHF."
tags: ["probability", "statistics", "math", "foundations"]
topic: "math-foundations"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type": "text", "content": "Importance sampling (IS) solves a fundamental problem: estimating expectations under a target distribution p when samples can only be drawn from a different proposal distribution q. This arises constantly in ML — computing expectations under a complex posterior when only a simple distribution is sampleable, correcting for distributional shift between training and deployment, evaluating policies trained on different data, and fine-tuning language models with RLHF where reference and fine-tuned distributions diverge. IS is also the foundation of Sequential Monte Carlo, annealed importance sampling for partition function estimation, and policy gradient variance reduction through baseline subtraction."}, {"type": "heading", "level": 2, "content": "Core Definition — The IS Estimator"}, {"type": "text", "content": "Goal: estimate E_p[f(X)] = ∫ f(x) p(x) dx but we can only sample from q(x).\n\nKey algebraic identity:\nE_p[f(X)] = ∫ f(x) p(x) dx = ∫ f(x) [p(x)/q(x)] q(x) dx = E_q[f(X) w(X)]\n\nwhere w(x) = p(x)/q(x) are the importance weights. Requirements: q must have support everywhere p is positive (q(x) > 0 whenever p(x) > 0).\n\nIS estimator (unnormalised):\nÊ_IS[f] = (1/N) Σᵢ f(xᵢ) w(xᵢ),  xᵢ ~ q\n\nSelf-normalised IS (SNIS) — does not require knowing the normalisation constant of p:\nÊ_SNIS[f] = Σᵢ f(xᵢ) w̃ᵢ  where w̃ᵢ = wᵢ / Σⱼ wⱼ\n\nSNIS is biased but consistent (bias O(1/N)). It is preferred when p is known only up to a normalising constant, which is the common case in Bayesian inference."}, {"type": "code", "language": "python", "content": "import numpy as np\nfrom scipy import stats\n\nrng = np.random.default_rng(42)\n\n# Target p: N(3, 0.5^2); Proposal q: N(0, 2^2)\n# Goal: E_p[X^2] = mu^2 + sigma^2 = 9.25\nmu_p, sigma_p = 3.0, 0.5\nmu_q, sigma_q = 0.0, 2.0\ntrue_val = mu_p**2 + sigma_p**2  # 9.25\n\nN = 5000\nx = rng.normal(mu_q, sigma_q, N)  # sample from q\n\n# Compute log importance weights (always work in log-space!)\nlog_w = stats.norm.logpdf(x, mu_p, sigma_p) - stats.norm.logpdf(x, mu_q, sigma_q)\nw = np.exp(log_w)\n\n# Unnormalised IS (requires p to be normalised)\nis_est   = np.mean(x**2 * w)\n\n# Self-normalised IS (works with unnormalised p)\nw_norm   = w / w.sum()\nsnis_est = np.sum(x**2 * w_norm)\n\n# Effective sample size: ESS = (sum w)^2 / sum(w^2)\ness = w.sum()**2 / np.sum(w**2)\n\nprint(f\"True E_p[X^2]:     {true_val:.4f}\")\nprint(f\"IS estimate:       {is_est:.4f}  (requires normalised p)\")\nprint(f\"SNIS estimate:     {snis_est:.4f}  (works with unnormalised p)\")\nprint(f\"ESS: {ess:.1f} / {N}  ({100*ess/N:.1f}%)\")\n\n# Weight diagnostics\nw_norm_sorted = np.sort(w_norm)[::-1]\ncumsum = np.cumsum(w_norm_sorted)\nn_50pct = np.searchsorted(cumsum, 0.5) + 1\nprint(f\"Top {n_50pct} samples carry 50% of total weight (out of {N})\")\nprint(f\"Max weight: {w_norm.max():.4e}, mean weight: {w_norm.mean():.4e}\")"}, {"type": "heading", "level": 2, "content": "Effective Sample Size and Variance"}, {"type": "text", "content": "The effective sample size (ESS) measures how many i.i.d. samples from p the IS estimate is equivalent to:\n\nESS = (Σᵢ wᵢ)² / Σᵢ wᵢ²\n\nFor normalised weights: ESS = 1 / Σᵢ w̃ᵢ² ∈ [1, N].\n\nProperties:\n- ESS = N when all weights are equal — this happens when q = p (perfect proposal)\n- ESS = 1 when one weight dominates all others — worst case, the estimate is based on a single sample\n- ESS/N measures the efficiency of IS: values above 0.5 indicate reasonable proposals; below 0.1 is problematic\n\nVariance of the IS estimator:\nVar_q[f(x) w(x)] = ∫ (f(x) w(x))² q(x) dx − (E_p[f(x)])²\n\nThis variance is finite if and only if E_q[(f(x) w(x))²] < ∞ — roughly requiring that p(x)/q(x) is bounded. If q has lighter tails than p anywhere, the ratio p/q can become unbounded and variance is infinite. The optimal IS proposal is q*(x) ∝ |f(x)| p(x), concentrating samples where the integrand is largest."}, {"type": "heading", "level": 2, "content": "Variance Explosion and Weight Clipping"}, {"type": "text", "content": "When q has lighter tails than p, the importance weights w(x) = p(x)/q(x) → ∞ for large |x|. This causes:\n\n1. A few samples with enormous weights dominate the estimate (ESS → 1)\n2. The IS estimator has infinite variance (despite being unbiased)\n3. In practice: highly variable estimates, numerical overflow in weights\n\nWeight clipping (truncation) caps weights at a maximum value c: w̃(x) = min(w(x), c). This introduces bias — it no longer correctly estimates E_p[f] — but reduces variance substantially. The bias is O(P(w(X) > c)) which is small when c is chosen appropriately.\n\nFor RLHF: the policy ratio π_θ(a|s)/π_ref(a|s) plays the role of an importance weight. PPO clips this ratio to [1−ε, 1+ε] for the same reason — preventing variance explosion when the policy drifts far from the reference, at the cost of introducing a small bias in the gradient estimate."}, {"type": "code", "language": "python", "content": "import numpy as np\nfrom scipy import stats\n\nrng = np.random.default_rng(42)\n\n# Variance explosion: proposal has lighter tails than target\n# Target p: t(3) (heavy tails), Proposal q: N(0,1) (light tails)\n# E_p[X^2] = df/(df-2) = 3.0 for t(3)\ntrue_val = 3.0\nN = 2000\n\nprint(\"=== Variance Explosion: q (Normal) lighter than p (t(3)) ===\")\nfor run in range(4):\n    x = rng.standard_normal(N)\n    log_w = stats.t.logpdf(x, df=3) - stats.norm.logpdf(x, 0, 1)\n    w = np.exp(log_w)\n    ess = w.sum()**2 / np.sum(w**2)\n    est = np.sum(x**2 * w / w.sum())\n    print(f\"  Run {run+1}: SNIS={est:7.2f}  ESS={ess:6.0f}  max_logw={np.log(w.max()):6.2f}\")\n\nprint(\"\\n=== Weight Clipping Bias-Variance Tradeoff ===\")\nx = rng.standard_normal(N)\nlog_w = stats.t.logpdf(x, df=3) - stats.norm.logpdf(x, 0, 1)\nw = np.exp(log_w)\nfor c in [np.inf, 50.0, 10.0, 5.0, 2.0]:\n    w_clipped = np.minimum(w, c)\n    w_norm    = w_clipped / w_clipped.sum()\n    est       = np.sum(x**2 * w_norm)\n    ess       = 1 / np.sum(w_norm**2)\n    c_str = f\"{c:.0f}\" if c != np.inf else \"none\"\n    print(f\"  clip={c_str:>5}: SNIS={est:.4f}  ESS={ess:.0f}  bias={abs(est-true_val):.4f}\")\n\nprint(\"\\n=== Correct: q = t(3) = target ===\")\nx_good = rng.standard_t(3, N)\nw_good = np.ones(N)   # all weights = 1\ness_good = N\nprint(f\"  SNIS={np.mean(x_good**2):.4f}  ESS={ess_good}  (all weights equal)\")"}, {"type": "heading", "level": 2, "content": "Off-Policy RL and RLHF Applications"}, {"type": "text", "content": "Importance sampling is central to off-policy reinforcement learning: we want to evaluate a target policy π_θ using trajectories collected by a behaviour policy π_b. The IS correction for a T-step trajectory τ = (s₀,a₀,…,sₜ) is:\n\nρ(τ) = Πₜ π_θ(aₜ|sₜ) / π_b(aₜ|sₜ)\n\nFor long trajectories, ρ(τ) is a product of T ratios — it can have exponentially growing variance. Per-decision IS uses partial products ρₜ = Π_{t'≤t} π_θ(aₜ'|sₜ') / π_b(aₜ'|sₜ') that reduce variance significantly.\n\nIn RLHF with PPO: the fine-tuned policy π_θ generates responses; the reward model scores them; the PPO loss clips the ratio r_t = π_θ(aₜ|sₜ)/π_old(aₜ|sₜ) to [1−ε, 1+ε] at each token. This is weight clipping applied per-token in the trajectory, preventing any single update from moving the policy too far from the reference."}, {"type": "code", "language": "python", "content": "import numpy as np\n\nrng = np.random.default_rng(42)\n\n# Off-policy IS: evaluate target policy using behaviour-policy trajectories\nn_states, n_actions = 5, 2\npi_target   = np.array([[0.7, 0.3]] * n_states)  # target: biased toward action 0\npi_behavior = np.array([[0.5, 0.5]] * n_states)  # behavior: uniform\n\ndef run_episode(pi, max_steps=8):\n    s = rng.integers(n_states)\n    traj, G = [], 0.0\n    for _ in range(max_steps):\n        a = rng.choice(n_actions, p=pi[s])\n        r = rng.standard_normal()\n        traj.append((s, a, r)); G += r\n        s = rng.integers(n_states)\n    return traj, G\n\nn_ep = 2000\nis_returns, direct_returns = [], []\nfor _ in range(n_ep):\n    traj, _ = run_episode(pi_behavior)\n    # Trajectory IS weight (product of per-step ratios)\n    log_rho = sum(np.log(pi_target[s,a]) - np.log(pi_behavior[s,a]) for s,a,r in traj)\n    rho = np.exp(np.clip(log_rho, -10, 10))   # clip for numerical safety\n    G = sum(r for _,_,r in traj)\n    is_returns.append(G * rho)\n    direct_returns.append(G)\n\ntrue_returns = [run_episode(pi_target)[1] for _ in range(n_ep)]\n\nprint(\"=== Off-Policy Value Estimation ===\")\nprint(f\"Naive (behavior policy):   {np.mean(direct_returns):.4f} SE={np.std(direct_returns)/np.sqrt(n_ep):.4f}\")\nprint(f\"IS-corrected:              {np.mean(is_returns):.4f} SE={np.std(is_returns)/np.sqrt(n_ep):.4f}\")\nprint(f\"True (target policy):      {np.mean(true_returns):.4f} SE={np.std(true_returns)/np.sqrt(n_ep):.4f}\")\n\n# PPO-style ratio clipping simulation\nprint(\"\\n=== PPO Ratio Clipping (eps=0.2) ===\")\nlog_ratios = [sum(np.log(pi_target[s,a])-np.log(pi_behavior[s,a]) for s,a,r in run_episode(pi_behavior)[0])\n              for _ in range(500)]\nratios = np.exp(np.array(log_ratios))\neps = 0.2\nclipped = np.clip(ratios, 1-eps, 1+eps)\npct_clipped = np.mean((ratios < 1-eps) | (ratios > 1+eps)) * 100\nprint(f\"Unclipped ratios: min={ratios.min():.3f} mean={ratios.mean():.3f} max={ratios.max():.3f}\")\nprint(f\"Clipped ratios:   min={clipped.min():.3f} mean={clipped.mean():.3f} max={clipped.max():.3f}\")\nprint(f\"{pct_clipped:.1f}% of trajectories had ratios outside [1-eps, 1+eps]\")"}, {"type": "heading", "level": 2, "content": "Annealed Importance Sampling"}, {"type": "text", "content": "Annealed importance sampling (AIS) estimates the ratio of partition functions Z₁/Z₀ — a quantity needed for Bayesian model comparison, normalising flow likelihood evaluation, and energy-based model training. It bridges between an easy proposal p₀ and a hard target p₁ through a sequence of intermediate distributions:\n\np_t(x) ∝ p₀(x)^{1-βₜ} p₁(x)^{βₜ},  β₀=0, β₁=1, β₀ < β₁ < … < βₙ = 1\n\nThe IS weight for a chain x₀ → x₁ → … → xₙ (where each xₜ is produced by a transition kernel targeting pₜ) is:\n\nw = Πₜ pₜ(xₜ₋₁) / p_{t-1}(xₜ₋₁)\n\nAIS with many intermediate steps (large T) gives small variance and reliable partition function estimates."}, {"type": "code", "language": "python", "content": "import numpy as np\nfrom scipy import stats\n\nrng = np.random.default_rng(42)\n\n# Annealed IS: estimate Z_1/Z_0 where p_0=N(0,1), p_1=N(3,0.5^2)\n# True ratio: Z_1/Z_0 = 1 (both are proper Gaussians)\n# But AIS estimates E_{p_1}[f] = integral f(x) p_1(x) dx / Z_1\n# More useful: AIS to estimate normalising constant of unnormalised target\n\nmu_target, sigma_target = 3.0, 0.5\n\ndef log_p0(x):  # proposal: N(0,1)\n    return stats.norm.logpdf(x, 0, 1)\n\ndef log_p1(x):  # target: N(3,0.5) (unnormalised in general case)\n    return stats.norm.logpdf(x, mu_target, sigma_target)\n\ndef log_pt(x, beta):  # intermediate: geometric average\n    return (1-beta)*log_p0(x) + beta*log_p1(x)\n\ndef ais_estimate(n_samples=500, n_steps=20):\n    \"\"\"Annealed IS with Gaussian MCMC transitions.\"\"\"\n    betas = np.linspace(0, 1, n_steps + 1)\n    log_weights = np.zeros(n_samples)\n\n    # Start from proposal\n    x = rng.standard_normal(n_samples)\n\n    for t in range(1, len(betas)):\n        beta_prev, beta_curr = betas[t-1], betas[t]\n        # AIS weight contribution: p_t(x) / p_{t-1}(x)\n        log_weights += log_pt(x, beta_curr) - log_pt(x, beta_prev)\n        # MCMC transition: Metropolis step targeting p_curr\n        x_prop = x + rng.normal(0, 0.5, n_samples)\n        log_alpha = log_pt(x_prop, beta_curr) - log_pt(x, beta_curr)\n        accept = np.log(rng.uniform(size=n_samples)) < log_alpha\n        x[accept] = x_prop[accept]\n\n    # AIS estimate: E_p1[X^2] = sum(X^2 * w) / sum(w)\n    log_w_normalised = log_weights - np.logaddexp.reduce(log_weights)\n    w_norm = np.exp(log_w_normalised)\n    E_x2   = np.sum(x**2 * w_norm)\n    ess    = np.exp(-np.logaddexp.reduce(2 * log_w_normalised))\n    return E_x2, ess\n\nprint(\"=== Annealed IS: Estimate E_p1[X^2] ===\")\nprint(f\"True value: {mu_target**2 + sigma_target**2:.4f}\")\nfor T in [5, 20, 100]:\n    estimates = [ais_estimate(n_samples=200, n_steps=T) for _ in range(5)]\n    ests = [e[0] for e in estimates]; esss = [e[1] for e in estimates]\n    print(f\"  T={T:>4} steps: mean={np.mean(ests):.4f} std={np.std(ests):.4f} avg_ESS={np.mean(esss):.0f}\")"}, {"type": "heading", "level": 2, "content": "Pitfalls"}, {"type": "text", "content": "Critical IS failure modes:\n\n1. **Tail mismatch causing infinite variance**: if q(x) = 0 anywhere p(x) > 0, the estimator is undefined. If q has lighter tails than p, variance is infinite — no amount of samples fixes this.\n\n2. **Long trajectory IS product collapse**: Πₜ p(aₜ)/q(aₜ) over T steps has variance that grows exponentially with T. Per-decision IS, V-trace, or clipping are essential for long-horizon problems.\n\n3. **Computing weights in linear space**: for even moderately different distributions, weights can be astronomical or zero. Always compute log_w = log p(x) − log q(x) and only exponentiate at the final step.\n\n4. **Ignoring ESS as a quality metric**: IS estimates can look numerically stable while having extremely high variance. Always compute ESS/N; below 0.1 is a red flag requiring a better proposal or fewer IS correction steps."}, {"type": "heading", "level": 2, "content": "Practical Guidance"}, {"type": "text", "content": "Guidelines for reliable IS in ML:\n\n- **Always work in log-space**: log_w = log p(x) − log q(x), then w = exp(log_w − log_w.max()) for stability.\n- **Monitor ESS/N**: flag estimates where ESS/N < 0.1 as unreliable.\n- **Weight clipping**: cap weights at a percentile (e.g., 95th percentile of weight distribution) or at a fixed constant. This is always a good default for production IS.\n- **For off-policy RL**: use V-trace (per-step ratio clipping) instead of full trajectory IS. V-trace clips each ratio to ρ̄ and c̄ separately for variance and bias control.\n- **For RLHF**: PPO's ratio clipping to [1−ε, 1+ε] is weight clipping applied per token. The KL penalty in DPO is an alternative that avoids explicit IS correction."}, {"type": "callout", "variant": "warning", "title": "ESS < 10% Indicates Severe IS Failure", "content": "When ESS/N < 0.1, fewer than 10% of samples effectively contribute to the estimate. The top few samples dominate, making the estimate unreliable and high-variance. Remedies: (1) use a heavier-tailed proposal; (2) reduce the IS correction distance (stay closer to on-policy); (3) use annealed IS to bridge gradually; (4) use normalising flows to learn a better proposal distribution."}, {"type": "callout", "variant": "tip", "title": "Optimal Proposal Minimises IS Variance", "content": "The variance-minimising IS proposal is q*(x) ∝ |f(x)| p(x) — it concentrates samples where the integrand is large. For f(x) ≥ 0 (e.g., positive reward functions), q*(x) ∝ f(x) p(x) is proportional to the unnormalised target multiplied by the function value. In RL, this is the motivation for experience replay prioritisation: sample transitions proportionally to |δ| (TD error), then correct with IS weights."}, {"type": "table", "headers": ["Method", "IS Correction", "Application", "Variance Control"], "rows": [["Vanilla IS", "Full ratio p/q", "Simple expectations", "Can be infinite"], ["SNIS", "Normalised weights", "Unknown normalising constants", "Biased, finite"], ["Per-decision IS", "Partial products", "Off-policy RL value estimation", "Lower than full IS"], ["V-trace", "Clipped per-step ratios", "Off-policy actor-critic (IMPALA)", "Controlled, bounded"], ["PPO", "Clipped policy ratio per token", "RLHF fine-tuning", "Low (near-on-policy)"], ["AIS", "Annealed sequence", "Partition function estimation", "Very low (many steps)"]]}, {"type": "divider"}, {"type": "heading", "level": 2, "content": "Key Takeaways"}, {"type": "list", "ordered": false, "items": ["IS estimator Ê_p[f] = (1/N) Σ f(xᵢ)w(xᵢ) with xᵢ~q and w=p/q corrects for sampling from the wrong distribution.", "SNIS normalises weights to sum to 1, enabling use with unnormalised p (standard in Bayesian inference) — biased but consistent.", "ESS = (Σwᵢ)²/Σwᵢ² measures efficiency; ESS/N < 0.1 indicates severe weight imbalance and unreliable estimates.", "IS has finite variance only if q has heavier tails than p everywhere; tail mismatch causes infinite variance that extra samples cannot fix.", "Weight clipping (truncation) at constant c trades bias for variance reduction — the principle behind PPO's ratio clipping in RLHF.", "Always compute importance weights in log-space (log p − log q) and only exponentiate at the final step to avoid numerical overflow.", "Annealed IS bridges between a simple proposal and a hard target through intermediate distributions, enabling reliable partition function estimation."]}]"
---
# Importance Sampling

Importance sampling (IS) solves a fundamental problem: estimating expectations under a target distribution p when samples can only be drawn from a different proposal distribution q. This arises constantly in ML — computing expectations under a complex posterior when only a simple distribution is sampleable, correcting for distributional shift between training and deployment, evaluating policies trained on different data, and fine-tuning language models with RLHF where reference and fine-tuned distributions diverge. IS is also the foundation of Sequential Monte Carlo, annealed importance sampling for partition function estimation, and policy gradient variance reduction through baseline subtraction.

## Core Definition — The IS Estimator

Goal: estimate E_p[f(X)] = ∫ f(x) p(x) dx but we can only sample from q(x).

Key algebraic identity:
E_p[f(X)] = ∫ f(x) p(x) dx = ∫ f(x) [p(x)/q(x)] q(x) dx = E_q[f(X) w(X)]

where w(x) = p(x)/q(x) are the importance weights. Requirements: q must have support everywhere p is positive (q(x) > 0 whenever p(x) > 0).

IS estimator (unnormalised):
Ê_IS[f] = (1/N) Σᵢ f(xᵢ) w(xᵢ),  xᵢ ~ q

Self-normalised IS (SNIS) — does not require knowing the normalisation constant of p:
Ê_SNIS[f] = Σᵢ f(xᵢ) w̃ᵢ  where w̃ᵢ = wᵢ / Σⱼ wⱼ

SNIS is biased but consistent (bias O(1/N)). It is preferred when p is known only up to a normalising constant, which is the common case in Bayesian inference.

```python
import numpy as np
from scipy import stats

rng = np.random.default_rng(42)

# Target p: N(3, 0.5^2); Proposal q: N(0, 2^2)
# Goal: E_p[X^2] = mu^2 + sigma^2 = 9.25
mu_p, sigma_p = 3.0, 0.5
mu_q, sigma_q = 0.0, 2.0
true_val = mu_p**2 + sigma_p**2  # 9.25

N = 5000
x = rng.normal(mu_q, sigma_q, N)  # sample from q

# Compute log importance weights (always work in log-space!)
log_w = stats.norm.logpdf(x, mu_p, sigma_p) - stats.norm.logpdf(x, mu_q, sigma_q)
w = np.exp(log_w)

# Unnormalised IS (requires p to be normalised)
is_est   = np.mean(x**2 * w)

# Self-normalised IS (works with unnormalised p)
w_norm   = w / w.sum()
snis_est = np.sum(x**2 * w_norm)

# Effective sample size: ESS = (sum w)^2 / sum(w^2)
ess = w.sum()**2 / np.sum(w**2)

print(f"True E_p[X^2]:     {true_val:.4f}")
print(f"IS estimate:       {is_est:.4f}  (requires normalised p)")
print(f"SNIS estimate:     {snis_est:.4f}  (works with unnormalised p)")
print(f"ESS: {ess:.1f} / {N}  ({100*ess/N:.1f}%)")

# Weight diagnostics
w_norm_sorted = np.sort(w_norm)[::-1]
cumsum = np.cumsum(w_norm_sorted)
n_50pct = np.searchsorted(cumsum, 0.5) + 1
print(f"Top {n_50pct} samples carry 50% of total weight (out of {N})")
print(f"Max weight: {w_norm.max():.4e}, mean weight: {w_norm.mean():.4e}")
```

## Effective Sample Size and Variance

The effective sample size (ESS) measures how many i.i.d. samples from p the IS estimate is equivalent to:

ESS = (Σᵢ wᵢ)² / Σᵢ wᵢ²

For normalised weights: ESS = 1 / Σᵢ w̃ᵢ² ∈ [1, N].

Properties:
- ESS = N when all weights are equal — this happens when q = p (perfect proposal)
- ESS = 1 when one weight dominates all others — worst case, the estimate is based on a single sample
- ESS/N measures the efficiency of IS: values above 0.5 indicate reasonable proposals; below 0.1 is problematic

Variance of the IS estimator:
Var_q[f(x) w(x)] = ∫ (f(x) w(x))² q(x) dx − (E_p[f(x)])²

This variance is finite if and only if E_q[(f(x) w(x))²] < ∞ — roughly requiring that p(x)/q(x) is bounded. If q has lighter tails than p anywhere, the ratio p/q can become unbounded and variance is infinite. The optimal IS proposal is q*(x) ∝ |f(x)| p(x), concentrating samples where the integrand is largest.

## Variance Explosion and Weight Clipping

When q has lighter tails than p, the importance weights w(x) = p(x)/q(x) → ∞ for large |x|. This causes:

1. A few samples with enormous weights dominate the estimate (ESS → 1)
2. The IS estimator has infinite variance (despite being unbiased)
3. In practice: highly variable estimates, numerical overflow in weights

Weight clipping (truncation) caps weights at a maximum value c: w̃(x) = min(w(x), c). This introduces bias — it no longer correctly estimates E_p[f] — but reduces variance substantially. The bias is O(P(w(X) > c)) which is small when c is chosen appropriately.

For RLHF: the policy ratio π_θ(a|s)/π_ref(a|s) plays the role of an importance weight. PPO clips this ratio to [1−ε, 1+ε] for the same reason — preventing variance explosion when the policy drifts far from the reference, at the cost of introducing a small bias in the gradient estimate.

```python
import numpy as np
from scipy import stats

rng = np.random.default_rng(42)

# Variance explosion: proposal has lighter tails than target
# Target p: t(3) (heavy tails), Proposal q: N(0,1) (light tails)
# E_p[X^2] = df/(df-2) = 3.0 for t(3)
true_val = 3.0
N = 2000

print("=== Variance Explosion: q (Normal) lighter than p (t(3)) ===")
for run in range(4):
    x = rng.standard_normal(N)
    log_w = stats.t.logpdf(x, df=3) - stats.norm.logpdf(x, 0, 1)
    w = np.exp(log_w)
    ess = w.sum()**2 / np.sum(w**2)
    est = np.sum(x**2 * w / w.sum())
    print(f"  Run {run+1}: SNIS={est:7.2f}  ESS={ess:6.0f}  max_logw={np.log(w.max()):6.2f}")

print("\n=== Weight Clipping Bias-Variance Tradeoff ===")
x = rng.standard_normal(N)
log_w = stats.t.logpdf(x, df=3) - stats.norm.logpdf(x, 0, 1)
w = np.exp(log_w)
for c in [np.inf, 50.0, 10.0, 5.0, 2.0]:
    w_clipped = np.minimum(w, c)
    w_norm    = w_clipped / w_clipped.sum()
    est       = np.sum(x**2 * w_norm)
    ess       = 1 / np.sum(w_norm**2)
    c_str = f"{c:.0f}" if c != np.inf else "none"
    print(f"  clip={c_str:>5}: SNIS={est:.4f}  ESS={ess:.0f}  bias={abs(est-true_val):.4f}")

print("\n=== Correct: q = t(3) = target ===")
x_good = rng.standard_t(3, N)
w_good = np.ones(N)   # all weights = 1
ess_good = N
print(f"  SNIS={np.mean(x_good**2):.4f}  ESS={ess_good}  (all weights equal)")
```

## Off-Policy RL and RLHF Applications

Importance sampling is central to off-policy reinforcement learning: we want to evaluate a target policy π_θ using trajectories collected by a behaviour policy π_b. The IS correction for a T-step trajectory τ = (s₀,a₀,…,sₜ) is:

ρ(τ) = Πₜ π_θ(aₜ|sₜ) / π_b(aₜ|sₜ)

For long trajectories, ρ(τ) is a product of T ratios — it can have exponentially growing variance. Per-decision IS uses partial products ρₜ = Π_{t'≤t} π_θ(aₜ'|sₜ') / π_b(aₜ'|sₜ') that reduce variance significantly.

In RLHF with PPO: the fine-tuned policy π_θ generates responses; the reward model scores them; the PPO loss clips the ratio r_t = π_θ(aₜ|sₜ)/π_old(aₜ|sₜ) to [1−ε, 1+ε] at each token. This is weight clipping applied per-token in the trajectory, preventing any single update from moving the policy too far from the reference.

```python
import numpy as np

rng = np.random.default_rng(42)

# Off-policy IS: evaluate target policy using behaviour-policy trajectories
n_states, n_actions = 5, 2
pi_target   = np.array([[0.7, 0.3]] * n_states)  # target: biased toward action 0
pi_behavior = np.array([[0.5, 0.5]] * n_states)  # behavior: uniform

def run_episode(pi, max_steps=8):
    s = rng.integers(n_states)
    traj, G = [], 0.0
    for _ in range(max_steps):
        a = rng.choice(n_actions, p=pi[s])
        r = rng.standard_normal()
        traj.append((s, a, r)); G += r
        s = rng.integers(n_states)
    return traj, G

n_ep = 2000
is_returns, direct_returns = [], []
for _ in range(n_ep):
    traj, _ = run_episode(pi_behavior)
    # Trajectory IS weight (product of per-step ratios)
    log_rho = sum(np.log(pi_target[s,a]) - np.log(pi_behavior[s,a]) for s,a,r in traj)
    rho = np.exp(np.clip(log_rho, -10, 10))   # clip for numerical safety
    G = sum(r for _,_,r in traj)
    is_returns.append(G * rho)
    direct_returns.append(G)

true_returns = [run_episode(pi_target)[1] for _ in range(n_ep)]

print("=== Off-Policy Value Estimation ===")
print(f"Naive (behavior policy):   {np.mean(direct_returns):.4f} SE={np.std(direct_returns)/np.sqrt(n_ep):.4f}")
print(f"IS-corrected:              {np.mean(is_returns):.4f} SE={np.std(is_returns)/np.sqrt(n_ep):.4f}")
print(f"True (target policy):      {np.mean(true_returns):.4f} SE={np.std(true_returns)/np.sqrt(n_ep):.4f}")

# PPO-style ratio clipping simulation
print("\n=== PPO Ratio Clipping (eps=0.2) ===")
log_ratios = [sum(np.log(pi_target[s,a])-np.log(pi_behavior[s,a]) for s,a,r in run_episode(pi_behavior)[0])
              for _ in range(500)]
ratios = np.exp(np.array(log_ratios))
eps = 0.2
clipped = np.clip(ratios, 1-eps, 1+eps)
pct_clipped = np.mean((ratios < 1-eps) | (ratios > 1+eps)) * 100
print(f"Unclipped ratios: min={ratios.min():.3f} mean={ratios.mean():.3f} max={ratios.max():.3f}")
print(f"Clipped ratios:   min={clipped.min():.3f} mean={clipped.mean():.3f} max={clipped.max():.3f}")
print(f"{pct_clipped:.1f}% of trajectories had ratios outside [1-eps, 1+eps]")
```

## Annealed Importance Sampling

Annealed importance sampling (AIS) estimates the ratio of partition functions Z₁/Z₀ — a quantity needed for Bayesian model comparison, normalising flow likelihood evaluation, and energy-based model training. It bridges between an easy proposal p₀ and a hard target p₁ through a sequence of intermediate distributions:

p_t(x) ∝ p₀(x)^{1-βₜ} p₁(x)^{βₜ},  β₀=0, β₁=1, β₀ < β₁ < … < βₙ = 1

The IS weight for a chain x₀ → x₁ → … → xₙ (where each xₜ is produced by a transition kernel targeting pₜ) is:

w = Πₜ pₜ(xₜ₋₁) / p_{t-1}(xₜ₋₁)

AIS with many intermediate steps (large T) gives small variance and reliable partition function estimates.

```python
import numpy as np
from scipy import stats

rng = np.random.default_rng(42)

# Annealed IS: estimate Z_1/Z_0 where p_0=N(0,1), p_1=N(3,0.5^2)
# True ratio: Z_1/Z_0 = 1 (both are proper Gaussians)
# But AIS estimates E_{p_1}[f] = integral f(x) p_1(x) dx / Z_1
# More useful: AIS to estimate normalising constant of unnormalised target

mu_target, sigma_target = 3.0, 0.5

def log_p0(x):  # proposal: N(0,1)
    return stats.norm.logpdf(x, 0, 1)

def log_p1(x):  # target: N(3,0.5) (unnormalised in general case)
    return stats.norm.logpdf(x, mu_target, sigma_target)

def log_pt(x, beta):  # intermediate: geometric average
    return (1-beta)*log_p0(x) + beta*log_p1(x)

def ais_estimate(n_samples=500, n_steps=20):
    """Annealed IS with Gaussian MCMC transitions."""
    betas = np.linspace(0, 1, n_steps + 1)
    log_weights = np.zeros(n_samples)

    # Start from proposal
    x = rng.standard_normal(n_samples)

    for t in range(1, len(betas)):
        beta_prev, beta_curr = betas[t-1], betas[t]
        # AIS weight contribution: p_t(x) / p_{t-1}(x)
        log_weights += log_pt(x, beta_curr) - log_pt(x, beta_prev)
        # MCMC transition: Metropolis step targeting p_curr
        x_prop = x + rng.normal(0, 0.5, n_samples)
        log_alpha = log_pt(x_prop, beta_curr) - log_pt(x, beta_curr)
        accept = np.log(rng.uniform(size=n_samples)) < log_alpha
        x[accept] = x_prop[accept]

    # AIS estimate: E_p1[X^2] = sum(X^2 * w) / sum(w)
    log_w_normalised = log_weights - np.logaddexp.reduce(log_weights)
    w_norm = np.exp(log_w_normalised)
    E_x2   = np.sum(x**2 * w_norm)
    ess    = np.exp(-np.logaddexp.reduce(2 * log_w_normalised))
    return E_x2, ess

print("=== Annealed IS: Estimate E_p1[X^2] ===")
print(f"True value: {mu_target**2 + sigma_target**2:.4f}")
for T in [5, 20, 100]:
    estimates = [ais_estimate(n_samples=200, n_steps=T) for _ in range(5)]
    ests = [e[0] for e in estimates]; esss = [e[1] for e in estimates]
    print(f"  T={T:>4} steps: mean={np.mean(ests):.4f} std={np.std(ests):.4f} avg_ESS={np.mean(esss):.0f}")
```

## Pitfalls

Critical IS failure modes:

1. **Tail mismatch causing infinite variance**: if q(x) = 0 anywhere p(x) > 0, the estimator is undefined. If q has lighter tails than p, variance is infinite — no amount of samples fixes this.

2. **Long trajectory IS product collapse**: Πₜ p(aₜ)/q(aₜ) over T steps has variance that grows exponentially with T. Per-decision IS, V-trace, or clipping are essential for long-horizon problems.

3. **Computing weights in linear space**: for even moderately different distributions, weights can be astronomical or zero. Always compute log_w = log p(x) − log q(x) and only exponentiate at the final step.

4. **Ignoring ESS as a quality metric**: IS estimates can look numerically stable while having extremely high variance. Always compute ESS/N; below 0.1 is a red flag requiring a better proposal or fewer IS correction steps.

## Practical Guidance

Guidelines for reliable IS in ML:

- **Always work in log-space**: log_w = log p(x) − log q(x), then w = exp(log_w − log_w.max()) for stability.
- **Monitor ESS/N**: flag estimates where ESS/N < 0.1 as unreliable.
- **Weight clipping**: cap weights at a percentile (e.g., 95th percentile of weight distribution) or at a fixed constant. This is always a good default for production IS.
- **For off-policy RL**: use V-trace (per-step ratio clipping) instead of full trajectory IS. V-trace clips each ratio to ρ̄ and c̄ separately for variance and bias control.
- **For RLHF**: PPO's ratio clipping to [1−ε, 1+ε] is weight clipping applied per token. The KL penalty in DPO is an alternative that avoids explicit IS correction.

> **WARNING: ESS < 10% Indicates Severe IS Failure**
>
> When ESS/N < 0.1, fewer than 10% of samples effectively contribute to the estimate. The top few samples dominate, making the estimate unreliable and high-variance. Remedies: (1) use a heavier-tailed proposal; (2) reduce the IS correction distance (stay closer to on-policy); (3) use annealed IS to bridge gradually; (4) use normalising flows to learn a better proposal distribution.

> **TIP: Optimal Proposal Minimises IS Variance**
>
> The variance-minimising IS proposal is q*(x) ∝ |f(x)| p(x) — it concentrates samples where the integrand is large. For f(x) ≥ 0 (e.g., positive reward functions), q*(x) ∝ f(x) p(x) is proportional to the unnormalised target multiplied by the function value. In RL, this is the motivation for experience replay prioritisation: sample transitions proportionally to |δ| (TD error), then correct with IS weights.

| Method | IS Correction | Application | Variance Control |
| --- | --- | --- | --- |
| Vanilla IS | Full ratio p/q | Simple expectations | Can be infinite |
| SNIS | Normalised weights | Unknown normalising constants | Biased, finite |
| Per-decision IS | Partial products | Off-policy RL value estimation | Lower than full IS |
| V-trace | Clipped per-step ratios | Off-policy actor-critic (IMPALA) | Controlled, bounded |
| PPO | Clipped policy ratio per token | RLHF fine-tuning | Low (near-on-policy) |
| AIS | Annealed sequence | Partition function estimation | Very low (many steps) |

---

## Key Takeaways

- IS estimator Ê_p[f] = (1/N) Σ f(xᵢ)w(xᵢ) with xᵢ~q and w=p/q corrects for sampling from the wrong distribution.
- SNIS normalises weights to sum to 1, enabling use with unnormalised p (standard in Bayesian inference) — biased but consistent.
- ESS = (Σwᵢ)²/Σwᵢ² measures efficiency; ESS/N < 0.1 indicates severe weight imbalance and unreliable estimates.
- IS has finite variance only if q has heavier tails than p everywhere; tail mismatch causes infinite variance that extra samples cannot fix.
- Weight clipping (truncation) at constant c trades bias for variance reduction — the principle behind PPO's ratio clipping in RLHF.
- Always compute importance weights in log-space (log p − log q) and only exponentiate at the final step to avoid numerical overflow.
- Annealed IS bridges between a simple proposal and a hard target through intermediate distributions, enabling reliable partition function estimation.
