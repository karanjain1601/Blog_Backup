---
title: "Monte Carlo Methods"
slug: "monte-carlo-methods"
description: "Monte Carlo integration, the O(1/sqrt(N)) convergence rate, variance reduction techniques (control variates, antithetic sampling, stratified sampling), quasi-Monte Carlo with Sobol sequences, and Monte Carlo policy evaluation for RL."
tags: ["probability", "statistics", "math", "foundations"]
topic: "math-foundations"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type": "text", "content": "Monte Carlo methods use random sampling to solve deterministic and stochastic problems that are analytically intractable. Their killer feature is dimension-independence: classical quadrature (trapezoidal rule, Gaussian quadrature) achieves O(N^{-k/d}) convergence where k is the order of the method and d is the dimension — this becomes catastrophically slow in high dimensions. Monte Carlo achieves O(1/√N) convergence independent of dimension, making it the only practical integration method for the high-dimensional integrals that appear throughout probabilistic ML, Bayesian inference, and reinforcement learning."}, {"type": "heading", "level": 2, "content": "Core Definition — Monte Carlo Integration"}, {"type": "text", "content": "To estimate E_p[f(X)] = ∫ f(x) p(x) dx, draw N independent samples x₁, …, xₙ ~ p(X) and compute:\n\nÊ[f] = (1/N) Σᵢ f(xᵢ)\n\nBy the Law of Large Numbers, Ê[f] → E[f] as N → ∞. By the Central Limit Theorem:\n\n√N (Ê[f] − E[f]) → N(0, Var_p[f(X)])\n\nSo the standard error of the Monte Carlo estimate is:\n\nSE = √(Var_p[f(X)] / N) = σ_f / √N\n\nThis O(1/√N) convergence rate is slow — to halve the error you need 4× as many samples — but crucially, it is independent of dimension d. For d = 100 features, classical numerical integration with 10 grid points per dimension requires 10^100 function evaluations; Monte Carlo needs the same N regardless of d."}, {"type": "code", "language": "python", "content": "import numpy as np\nimport matplotlib\nmatplotlib.use('Agg')\n\nrng = np.random.default_rng(42)\n\n# Monte Carlo integration: E[X^2] where X ~ Uniform(0,1)\n# True value: integral_0^1 x^2 dx = 1/3\ntrue_val = 1.0 / 3.0\nprint(\"=== MC Integration: E[X^2], X~Uniform(0,1) ===\")\nprint(f\"True value: {true_val:.8f}\")\n\nfor N in [100, 1_000, 10_000, 100_000, 1_000_000]:\n    samples = rng.uniform(0, 1, N)\n    estimate = np.mean(samples**2)\n    se = np.std(samples**2, ddof=1) / np.sqrt(N)\n    error = abs(estimate - true_val)\n    print(f\"  N={N:>9,}: estimate={estimate:.6f}  SE={se:.2e}  error={error:.2e}\")\n\n# Convergence rate: error ~ 1/sqrt(N)\nprint(\"\\n=== Convergence Rate Verification ===\")\nN_vals = [100, 1000, 10000, 100000]\nerrors = []\nfor N in N_vals:\n    n_reps = 200\n    ests = [np.mean(rng.uniform(0,1,N)**2) for _ in range(n_reps)]\n    errors.append(np.std(ests))\n\nfor N, err in zip(N_vals, errors):\n    print(f\"  N={N:>7,}: empirical SE={err:.4e}  theory={1/(3*np.sqrt(N)):.4e}\")\n\n# MC estimate of pi: fraction of points inside unit circle\nprint(\"\\n=== Monte Carlo for pi ===\")\nN = 1_000_000\nx, y = rng.uniform(-1, 1, N), rng.uniform(-1, 1, N)\npi_est = 4 * np.mean(x**2 + y**2 <= 1)\nprint(f\"pi estimate (N={N:,}): {pi_est:.6f}  (true: {np.pi:.6f})\")"}, {"type": "heading", "level": 2, "content": "Variance Reduction Techniques"}, {"type": "text", "content": "The Monte Carlo SE = σ_f / √N can be reduced by decreasing σ_f rather than increasing N. Several techniques achieve this:\n\n**Control variates**: if we know E[g(X)] analytically and g is correlated with f, use the estimator:\nÊ_CV[f] = (1/N) Σ [f(xᵢ) − c(g(xᵢ) − E[g(X)])]\nThe optimal constant c* = Cov(f, g) / Var(g) achieves variance reduction of factor 1 − ρ²(f,g).\n\n**Antithetic variates**: use pairs (xᵢ, x̃ᵢ) where x̃ᵢ is the 'reflection' of xᵢ (e.g., for uniform samples, x̃ᵢ = 1 − xᵢ). If f(x) and f(x̃) are negatively correlated, Var(f(x) + f(x̃))/2 < Var(f(x)).\n\n**Stratified sampling**: divide the domain into K strata and draw N/K samples from each. Variance of the estimator is reduced by eliminating between-stratum variability.\n\n**Rao-Blackwellization**: condition on a sufficient statistic to reduce variance without introducing bias: E[f(X,Y)|Y] uses the conditional expectation, which always has variance ≤ Var(f(X,Y))."}, {"type": "code", "language": "python", "content": "import numpy as np\n\nrng = np.random.default_rng(42)\n\n# Target: E[exp(X)] where X~Uniform(0,1)\n# True value: integral_0^1 exp(x) dx = e - 1 ≈ 1.71828\ntrue_val = np.e - 1.0\nf = np.exp\n\nprint(\"=== Variance Reduction for E[exp(X)], X~U(0,1) ===\")\nprint(f\"True value: {true_val:.8f}\")\n\nN = 10_000\n\n# 1. Standard MC\nx_mc = rng.uniform(0, 1, N)\nmc_est = np.mean(f(x_mc))\nmc_se  = np.std(f(x_mc)) / np.sqrt(N)\nprint(f\"\\nStandard MC:      est={mc_est:.6f}  SE={mc_se:.4e}\")\n\n# 2. Antithetic variates: pair x with (1-x)\nx_anti = rng.uniform(0, 1, N // 2)\ny_anti = 1 - x_anti\nanti_vals = (f(x_anti) + f(y_anti)) / 2\nanti_est  = np.mean(anti_vals)\nanti_se   = np.std(anti_vals) / np.sqrt(N // 2)\nprint(f\"Antithetic:       est={anti_est:.6f}  SE={anti_se:.4e}  \"\n      f\"speedup={mc_se/anti_se:.1f}x\")\n\n# 3. Control variate: g(x) = x, E[g] = 0.5\nx_cv = rng.uniform(0, 1, N)\nf_cv = f(x_cv)\ng_cv = x_cv\nE_g  = 0.5\n# Optimal c*: regress f on g\nc_star = np.cov(f_cv, g_cv)[0,1] / np.var(g_cv)\ncv_vals = f_cv - c_star * (g_cv - E_g)\ncv_est  = np.mean(cv_vals)\ncv_se   = np.std(cv_vals) / np.sqrt(N)\nprint(f\"Control variate:  est={cv_est:.6f}  SE={cv_se:.4e}  \"\n      f\"speedup={mc_se/cv_se:.1f}x  c*={c_star:.4f}\")\n\n# 4. Stratified sampling: 10 strata\nK = 10\nx_strat = np.concatenate([rng.uniform(k/K, (k+1)/K, N//K) for k in range(K)])\nstrat_est = np.mean(f(x_strat))\nstrat_se  = np.std([np.mean(f(rng.uniform(k/K, (k+1)/K, N//K))) for k in range(K)]) / np.sqrt(K)\nprint(f\"Stratified:       est={strat_est:.6f}  SE={strat_se:.4e}  speedup={mc_se/strat_se:.1f}x\")"}, {"type": "heading", "level": 2, "content": "Quasi-Monte Carlo and Low-Discrepancy Sequences"}, {"type": "text", "content": "Standard Monte Carlo uses pseudo-random samples that can cluster or leave gaps by chance, even with good random number generators. Quasi-Monte Carlo (QMC) replaces random samples with deterministic low-discrepancy sequences — sequences designed to cover the domain as uniformly as possible.\n\nSobol sequences are the most widely used: they achieve discrepancy O((log N)^d / N), leading to convergence rates approaching O(1/N) for smooth integrands — much faster than O(1/√N). However, the advantage diminishes in high dimensions (d > 20 or so) because the (log N)^d factor becomes large.\n\nHalton sequences use different primes for each dimension. Lattice rules (rank-1 lattices) are popular for Bayesian integration. PyTorch includes torch.quasirandom.SobolEngine for QMC sampling, making it easy to use in ML experiments (hyperparameter search, integration in normalizing flows)."}, {"type": "code", "language": "python", "content": "import numpy as np\nfrom scipy.stats.qmc import Sobol, Halton\nimport warnings; warnings.filterwarnings('ignore')\n\nrng = np.random.default_rng(42)\n\n# Compare random MC vs Sobol QMC for pi estimation\ndef estimate_pi(samples_2d):\n    x, y = samples_2d[:, 0], samples_2d[:, 1]\n    return 4 * np.mean(x**2 + y**2 <= 1)\n\nprint(\"=== MC vs QMC: estimating pi ===\")\nfor N in [256, 1024, 4096, 16384]:\n    # Random MC\n    mc_samples  = rng.uniform(0, 1, (N, 2))\n    mc_pi       = estimate_pi(mc_samples)\n    mc_err      = abs(mc_pi - np.pi)\n\n    # Sobol QMC\n    sobol = Sobol(d=2, scramble=True, seed=42)\n    qmc_samples = sobol.random(N)\n    qmc_pi  = estimate_pi(qmc_samples)\n    qmc_err = abs(qmc_pi - np.pi)\n\n    print(f\"  N={N:>6,}: MC_err={mc_err:.4f}  QMC_err={qmc_err:.4f}  ratio={mc_err/qmc_err:.1f}x\")\n\n# Sobol for hyperparameter search (better coverage than random grid)\nprint(\"\\n=== Sobol for 3D Hyperparameter Search ===\")\nsobol3 = Sobol(d=3, scramble=True, seed=0)\nhp_samples = sobol3.random(16)  # 16 configs in [0,1]^3\n# Map to actual hyperparameter ranges\nlr     = 10 ** (hp_samples[:, 0] * (-4) + (-2))  # [1e-4, 1e-2] log-scale\nwd     = 10 ** (hp_samples[:, 1] * (-6) + (-2))  # [1e-6, 1e-2] log-scale\ndrop   = hp_samples[:, 2] * 0.5                   # [0, 0.5]\nfor i in range(4):\n    print(f\"  config {i}: lr={lr[i]:.2e}  wd={wd[i]:.2e}  dropout={drop[i]:.3f}\")"}, {"type": "heading", "level": 2, "content": "Monte Carlo Policy Evaluation (RL)"}, {"type": "text", "content": "In reinforcement learning, Monte Carlo (MC) policy evaluation estimates the value function V^π(s) = E[G_t | S_t = s] by averaging the actual returns G_t observed from state s when following policy π. Unlike temporal difference (TD) methods, MC uses full episode returns and does not bootstrap.\n\nFor episodic MDPs:\n1. Generate episode: S₀, A₀, R₁, S₁, A₁, R₂, …, S_T following policy π\n2. Compute returns: G_t = R_{t+1} + γ R_{t+2} + … + γ^{T-t-1} R_T\n3. Update: V(S_t) ← V(S_t) + α(G_t − V(S_t))  [incremental mean]\n\nEvery-visit MC averages over all visits to state s in all episodes. First-visit MC averages only the first visit per episode (gives unbiased estimate of V^π(s)). MC is unbiased but high-variance; TD is biased but lower-variance. The bias-variance tradeoff between MC and TD is controlled by n-step returns and λ in TD(λ)."}, {"type": "code", "language": "python", "content": "import numpy as np\n\n# Simple GridWorld MDP for Monte Carlo policy evaluation\nclass GridWorld:\n    \"\"\"4x4 grid, absorbing corners at (0,0) and (3,3), reward -1 per step.\"\"\"\n    def __init__(self, size=4):\n        self.size = size\n        self.terminal = {(0,0), (size-1, size-1)}\n        self.actions = [(0,1),(0,-1),(1,0),(-1,0)]  # R,L,D,U\n\n    def step(self, state, action):\n        if state in self.terminal:\n            return state, 0.0, True\n        r, c = state\n        dr, dc = action\n        nr, nc = np.clip(r+dr, 0, self.size-1), np.clip(c+dc, 0, self.size-1)\n        new_state = (nr, nc)\n        done = new_state in self.terminal\n        return new_state, -1.0, done\n\ndef generate_episode(env, policy, max_steps=200):\n    \"\"\"Generate one episode following policy.\"\"\"\n    s = (np.random.randint(env.size), np.random.randint(env.size))\n    while s in env.terminal:\n        s = (np.random.randint(env.size), np.random.randint(env.size))\n    trajectory = []\n    for _ in range(max_steps):\n        a = policy(s)\n        s_next, r, done = env.step(s, a)\n        trajectory.append((s, a, r))\n        s = s_next\n        if done: break\n    return trajectory\n\ndef mc_policy_evaluation(env, policy, n_episodes=5000, gamma=0.99):\n    \"\"\"First-visit Monte Carlo policy evaluation.\"\"\"\n    V = {}; returns = {}\n    for ep in range(n_episodes):\n        traj = generate_episode(env, policy)\n        G = 0.0\n        visited = set()\n        for s, a, r in reversed(traj):\n            G = r + gamma * G\n            if s not in visited:  # first-visit\n                visited.add(s)\n                returns.setdefault(s, []).append(G)\n                V[s] = np.mean(returns[s])\n    return V\n\nnp.random.seed(42)\nenv = GridWorld(4)\n# Random policy: uniform over 4 actions\npolicy = lambda s: env.actions[np.random.randint(4)]\n\nV = mc_policy_evaluation(env, policy, n_episodes=10000)\nprint(\"=== Value Function (random policy, gamma=0.99) ===\")\ngrid = np.zeros((4, 4))\nfor (r, c), v in V.items():\n    grid[r, c] = v\nfor i, row in enumerate(grid):\n    print(f\"  row {i}: {[f'{v:6.1f}' for v in row]}\")\nprint(\"  (0,0) and (3,3) are terminal states with value 0)\")"}, {"type": "heading", "level": 2, "content": "Pitfalls"}, {"type": "text", "content": "Common Monte Carlo mistakes:\n\n1. **Insufficient samples for high-variance integrands**: if f(x) has heavy tails, the empirical variance estimate is unreliable and SE estimates are too optimistic. Check for outliers.\n\n2. **Correlated samples without accounting for it**: MCMC samples are correlated. Treating them as independent underestimates the true SE by up to √(2τ) where τ is the autocorrelation time.\n\n3. **Using QMC when samples are not i.i.d.**: Sobol and Halton sequences are designed for integration, not for probabilistic sampling. Using them as 'random' samples in probabilistic algorithms (e.g., Bayesian optimisation acquisition) can give overconfident estimates.\n\n4. **Forgetting that 1/√N convergence is slow**: going from 1% to 0.1% error requires 100× more samples. Variance reduction techniques or better estimators are often more cost-effective than brute-force sample increase."}, {"type": "heading", "level": 2, "content": "Practical Guidance"}, {"type": "text", "content": "Guidelines for Monte Carlo in ML:\n\n- **Always estimate the SE**: report SE = std(f(xᵢ)) / √N alongside the estimate. If SE > desired accuracy, increase N or apply variance reduction.\n- **For hyperparameter search**: use Sobol sequences instead of random search — same number of evaluations, better coverage, especially for d ≤ 20 dimensions.\n- **For integration in deep learning** (ELBO estimation, policy gradient): use control variates (e.g., baseline subtraction in REINFORCE) to reduce gradient variance.\n- **For MCMC**: compute the effective sample size ESS = N / (1 + 2 Σₖ ρₖ) where ρₖ is the lag-k autocorrelation. ESS << N indicates poor mixing and inflated SE."}, {"type": "callout", "variant": "tip", "title": "Control Variates in REINFORCE", "content": "The REINFORCE gradient estimator ∇θ E[R] = E[R ∇θ log π(a|s,θ)] has high variance. Subtracting a baseline b(s) (control variate): ∇θ E[R] = E[(R − b(s)) ∇θ log π(a|s,θ)]. The baseline does not bias the gradient because E[b(s) ∇θ log π] = 0. A common choice is the value function estimate V(s) as the baseline — this is the advantage actor-critic method."}, {"type": "table", "headers": ["Method", "Convergence", "Strengths", "Weaknesses"], "rows": [["Standard MC", "O(1/√N)", "Simple, unbiased, dimension-free", "High variance for smooth integrands"], ["Control variates", "Better O(1/√N)", "Can give 10x+ speedup", "Requires correlated estimator with known mean"], ["Antithetic variates", "Better O(1/√N)", "Easy to implement", "Only works for monotone integrands"], ["Stratified sampling", "O(1/N) for 1D", "Guaranteed coverage", "Hard to extend to high dimensions"], ["Sobol QMC", "~O(1/N)", "Best for d<20, smooth f", "Not probabilistically valid samples"], ["MCMC (Metropolis)", "O(1/√N_eff)", "Can sample from unnormalised p", "Correlated samples; slow mixing"]]}, {"type": "divider"}, {"type": "heading", "level": 2, "content": "Key Takeaways"}, {"type": "list", "ordered": false, "items": ["MC integration: Ê[f] = (1/N) Σ f(xᵢ) with xᵢ~p converges at O(1/√N) independent of dimension — the key advantage over classical quadrature.", "SE = σ_f / √N: to halve the error requires 4× samples; variance reduction is often more cost-effective than increasing N.", "Control variates (subtract a term with known expectation), antithetic variates (use paired reflections), and stratified sampling all reduce variance without increasing N.", "Sobol quasi-Monte Carlo achieves ~O(1/N) convergence for smooth d<20 integrands by replacing random samples with low-discrepancy deterministic sequences.", "In RL, first-visit Monte Carlo policy evaluation averages full episode returns from each first visit to a state — unbiased but high variance compared to TD methods.", "Always report SE alongside MC estimates; for MCMC samples compute ESS to account for autocorrelation before interpreting the SE.", "Control variates appear in RL as baselines (advantage actor-critic), in variational inference as variance reduction for ELBO gradient estimates."]}]"
---
# Monte Carlo Methods

Monte Carlo methods use random sampling to solve deterministic and stochastic problems that are analytically intractable. Their killer feature is dimension-independence: classical quadrature (trapezoidal rule, Gaussian quadrature) achieves O(N^{-k/d}) convergence where k is the order of the method and d is the dimension — this becomes catastrophically slow in high dimensions. Monte Carlo achieves O(1/√N) convergence independent of dimension, making it the only practical integration method for the high-dimensional integrals that appear throughout probabilistic ML, Bayesian inference, and reinforcement learning.

## Core Definition — Monte Carlo Integration

To estimate E_p[f(X)] = ∫ f(x) p(x) dx, draw N independent samples x₁, …, xₙ ~ p(X) and compute:

Ê[f] = (1/N) Σᵢ f(xᵢ)

By the Law of Large Numbers, Ê[f] → E[f] as N → ∞. By the Central Limit Theorem:

√N (Ê[f] − E[f]) → N(0, Var_p[f(X)])

So the standard error of the Monte Carlo estimate is:

SE = √(Var_p[f(X)] / N) = σ_f / √N

This O(1/√N) convergence rate is slow — to halve the error you need 4× as many samples — but crucially, it is independent of dimension d. For d = 100 features, classical numerical integration with 10 grid points per dimension requires 10^100 function evaluations; Monte Carlo needs the same N regardless of d.

```python
import numpy as np
import matplotlib
matplotlib.use('Agg')

rng = np.random.default_rng(42)

# Monte Carlo integration: E[X^2] where X ~ Uniform(0,1)
# True value: integral_0^1 x^2 dx = 1/3
true_val = 1.0 / 3.0
print("=== MC Integration: E[X^2], X~Uniform(0,1) ===")
print(f"True value: {true_val:.8f}")

for N in [100, 1_000, 10_000, 100_000, 1_000_000]:
    samples = rng.uniform(0, 1, N)
    estimate = np.mean(samples**2)
    se = np.std(samples**2, ddof=1) / np.sqrt(N)
    error = abs(estimate - true_val)
    print(f"  N={N:>9,}: estimate={estimate:.6f}  SE={se:.2e}  error={error:.2e}")

# Convergence rate: error ~ 1/sqrt(N)
print("\n=== Convergence Rate Verification ===")
N_vals = [100, 1000, 10000, 100000]
errors = []
for N in N_vals:
    n_reps = 200
    ests = [np.mean(rng.uniform(0,1,N)**2) for _ in range(n_reps)]
    errors.append(np.std(ests))

for N, err in zip(N_vals, errors):
    print(f"  N={N:>7,}: empirical SE={err:.4e}  theory={1/(3*np.sqrt(N)):.4e}")

# MC estimate of pi: fraction of points inside unit circle
print("\n=== Monte Carlo for pi ===")
N = 1_000_000
x, y = rng.uniform(-1, 1, N), rng.uniform(-1, 1, N)
pi_est = 4 * np.mean(x**2 + y**2 <= 1)
print(f"pi estimate (N={N:,}): {pi_est:.6f}  (true: {np.pi:.6f})")
```

## Variance Reduction Techniques

The Monte Carlo SE = σ_f / √N can be reduced by decreasing σ_f rather than increasing N. Several techniques achieve this:

**Control variates**: if we know E[g(X)] analytically and g is correlated with f, use the estimator:
Ê_CV[f] = (1/N) Σ [f(xᵢ) − c(g(xᵢ) − E[g(X)])]
The optimal constant c* = Cov(f, g) / Var(g) achieves variance reduction of factor 1 − ρ²(f,g).

**Antithetic variates**: use pairs (xᵢ, x̃ᵢ) where x̃ᵢ is the 'reflection' of xᵢ (e.g., for uniform samples, x̃ᵢ = 1 − xᵢ). If f(x) and f(x̃) are negatively correlated, Var(f(x) + f(x̃))/2 < Var(f(x)).

**Stratified sampling**: divide the domain into K strata and draw N/K samples from each. Variance of the estimator is reduced by eliminating between-stratum variability.

**Rao-Blackwellization**: condition on a sufficient statistic to reduce variance without introducing bias: E[f(X,Y)|Y] uses the conditional expectation, which always has variance ≤ Var(f(X,Y)).

```python
import numpy as np

rng = np.random.default_rng(42)

# Target: E[exp(X)] where X~Uniform(0,1)
# True value: integral_0^1 exp(x) dx = e - 1 ≈ 1.71828
true_val = np.e - 1.0
f = np.exp

print("=== Variance Reduction for E[exp(X)], X~U(0,1) ===")
print(f"True value: {true_val:.8f}")

N = 10_000

# 1. Standard MC
x_mc = rng.uniform(0, 1, N)
mc_est = np.mean(f(x_mc))
mc_se  = np.std(f(x_mc)) / np.sqrt(N)
print(f"\nStandard MC:      est={mc_est:.6f}  SE={mc_se:.4e}")

# 2. Antithetic variates: pair x with (1-x)
x_anti = rng.uniform(0, 1, N // 2)
y_anti = 1 - x_anti
anti_vals = (f(x_anti) + f(y_anti)) / 2
anti_est  = np.mean(anti_vals)
anti_se   = np.std(anti_vals) / np.sqrt(N // 2)
print(f"Antithetic:       est={anti_est:.6f}  SE={anti_se:.4e}  "
      f"speedup={mc_se/anti_se:.1f}x")

# 3. Control variate: g(x) = x, E[g] = 0.5
x_cv = rng.uniform(0, 1, N)
f_cv = f(x_cv)
g_cv = x_cv
E_g  = 0.5
# Optimal c*: regress f on g
c_star = np.cov(f_cv, g_cv)[0,1] / np.var(g_cv)
cv_vals = f_cv - c_star * (g_cv - E_g)
cv_est  = np.mean(cv_vals)
cv_se   = np.std(cv_vals) / np.sqrt(N)
print(f"Control variate:  est={cv_est:.6f}  SE={cv_se:.4e}  "
      f"speedup={mc_se/cv_se:.1f}x  c*={c_star:.4f}")

# 4. Stratified sampling: 10 strata
K = 10
x_strat = np.concatenate([rng.uniform(k/K, (k+1)/K, N//K) for k in range(K)])
strat_est = np.mean(f(x_strat))
strat_se  = np.std([np.mean(f(rng.uniform(k/K, (k+1)/K, N//K))) for k in range(K)]) / np.sqrt(K)
print(f"Stratified:       est={strat_est:.6f}  SE={strat_se:.4e}  speedup={mc_se/strat_se:.1f}x")
```

## Quasi-Monte Carlo and Low-Discrepancy Sequences

Standard Monte Carlo uses pseudo-random samples that can cluster or leave gaps by chance, even with good random number generators. Quasi-Monte Carlo (QMC) replaces random samples with deterministic low-discrepancy sequences — sequences designed to cover the domain as uniformly as possible.

Sobol sequences are the most widely used: they achieve discrepancy O((log N)^d / N), leading to convergence rates approaching O(1/N) for smooth integrands — much faster than O(1/√N). However, the advantage diminishes in high dimensions (d > 20 or so) because the (log N)^d factor becomes large.

Halton sequences use different primes for each dimension. Lattice rules (rank-1 lattices) are popular for Bayesian integration. PyTorch includes torch.quasirandom.SobolEngine for QMC sampling, making it easy to use in ML experiments (hyperparameter search, integration in normalizing flows).

```python
import numpy as np
from scipy.stats.qmc import Sobol, Halton
import warnings; warnings.filterwarnings('ignore')

rng = np.random.default_rng(42)

# Compare random MC vs Sobol QMC for pi estimation
def estimate_pi(samples_2d):
    x, y = samples_2d[:, 0], samples_2d[:, 1]
    return 4 * np.mean(x**2 + y**2 <= 1)

print("=== MC vs QMC: estimating pi ===")
for N in [256, 1024, 4096, 16384]:
    # Random MC
    mc_samples  = rng.uniform(0, 1, (N, 2))
    mc_pi       = estimate_pi(mc_samples)
    mc_err      = abs(mc_pi - np.pi)

    # Sobol QMC
    sobol = Sobol(d=2, scramble=True, seed=42)
    qmc_samples = sobol.random(N)
    qmc_pi  = estimate_pi(qmc_samples)
    qmc_err = abs(qmc_pi - np.pi)

    print(f"  N={N:>6,}: MC_err={mc_err:.4f}  QMC_err={qmc_err:.4f}  ratio={mc_err/qmc_err:.1f}x")

# Sobol for hyperparameter search (better coverage than random grid)
print("\n=== Sobol for 3D Hyperparameter Search ===")
sobol3 = Sobol(d=3, scramble=True, seed=0)
hp_samples = sobol3.random(16)  # 16 configs in [0,1]^3
# Map to actual hyperparameter ranges
lr     = 10 ** (hp_samples[:, 0] * (-4) + (-2))  # [1e-4, 1e-2] log-scale
wd     = 10 ** (hp_samples[:, 1] * (-6) + (-2))  # [1e-6, 1e-2] log-scale
drop   = hp_samples[:, 2] * 0.5                   # [0, 0.5]
for i in range(4):
    print(f"  config {i}: lr={lr[i]:.2e}  wd={wd[i]:.2e}  dropout={drop[i]:.3f}")
```

## Monte Carlo Policy Evaluation (RL)

In reinforcement learning, Monte Carlo (MC) policy evaluation estimates the value function V^π(s) = E[G_t | S_t = s] by averaging the actual returns G_t observed from state s when following policy π. Unlike temporal difference (TD) methods, MC uses full episode returns and does not bootstrap.

For episodic MDPs:
1. Generate episode: S₀, A₀, R₁, S₁, A₁, R₂, …, S_T following policy π
2. Compute returns: G_t = R_{t+1} + γ R_{t+2} + … + γ^{T-t-1} R_T
3. Update: V(S_t) ← V(S_t) + α(G_t − V(S_t))  [incremental mean]

Every-visit MC averages over all visits to state s in all episodes. First-visit MC averages only the first visit per episode (gives unbiased estimate of V^π(s)). MC is unbiased but high-variance; TD is biased but lower-variance. The bias-variance tradeoff between MC and TD is controlled by n-step returns and λ in TD(λ).

```python
import numpy as np

# Simple GridWorld MDP for Monte Carlo policy evaluation
class GridWorld:
    """4x4 grid, absorbing corners at (0,0) and (3,3), reward -1 per step."""
    def __init__(self, size=4):
        self.size = size
        self.terminal = {(0,0), (size-1, size-1)}
        self.actions = [(0,1),(0,-1),(1,0),(-1,0)]  # R,L,D,U

    def step(self, state, action):
        if state in self.terminal:
            return state, 0.0, True
        r, c = state
        dr, dc = action
        nr, nc = np.clip(r+dr, 0, self.size-1), np.clip(c+dc, 0, self.size-1)
        new_state = (nr, nc)
        done = new_state in self.terminal
        return new_state, -1.0, done

def generate_episode(env, policy, max_steps=200):
    """Generate one episode following policy."""
    s = (np.random.randint(env.size), np.random.randint(env.size))
    while s in env.terminal:
        s = (np.random.randint(env.size), np.random.randint(env.size))
    trajectory = []
    for _ in range(max_steps):
        a = policy(s)
        s_next, r, done = env.step(s, a)
        trajectory.append((s, a, r))
        s = s_next
        if done: break
    return trajectory

def mc_policy_evaluation(env, policy, n_episodes=5000, gamma=0.99):
    """First-visit Monte Carlo policy evaluation."""
    V = {}; returns = {}
    for ep in range(n_episodes):
        traj = generate_episode(env, policy)
        G = 0.0
        visited = set()
        for s, a, r in reversed(traj):
            G = r + gamma * G
            if s not in visited:  # first-visit
                visited.add(s)
                returns.setdefault(s, []).append(G)
                V[s] = np.mean(returns[s])
    return V

np.random.seed(42)
env = GridWorld(4)
# Random policy: uniform over 4 actions
policy = lambda s: env.actions[np.random.randint(4)]

V = mc_policy_evaluation(env, policy, n_episodes=10000)
print("=== Value Function (random policy, gamma=0.99) ===")
grid = np.zeros((4, 4))
for (r, c), v in V.items():
    grid[r, c] = v
for i, row in enumerate(grid):
    print(f"  row {i}: {[f'{v:6.1f}' for v in row]}")
print("  (0,0) and (3,3) are terminal states with value 0)")
```

## Pitfalls

Common Monte Carlo mistakes:

1. **Insufficient samples for high-variance integrands**: if f(x) has heavy tails, the empirical variance estimate is unreliable and SE estimates are too optimistic. Check for outliers.

2. **Correlated samples without accounting for it**: MCMC samples are correlated. Treating them as independent underestimates the true SE by up to √(2τ) where τ is the autocorrelation time.

3. **Using QMC when samples are not i.i.d.**: Sobol and Halton sequences are designed for integration, not for probabilistic sampling. Using them as 'random' samples in probabilistic algorithms (e.g., Bayesian optimisation acquisition) can give overconfident estimates.

4. **Forgetting that 1/√N convergence is slow**: going from 1% to 0.1% error requires 100× more samples. Variance reduction techniques or better estimators are often more cost-effective than brute-force sample increase.

## Practical Guidance

Guidelines for Monte Carlo in ML:

- **Always estimate the SE**: report SE = std(f(xᵢ)) / √N alongside the estimate. If SE > desired accuracy, increase N or apply variance reduction.
- **For hyperparameter search**: use Sobol sequences instead of random search — same number of evaluations, better coverage, especially for d ≤ 20 dimensions.
- **For integration in deep learning** (ELBO estimation, policy gradient): use control variates (e.g., baseline subtraction in REINFORCE) to reduce gradient variance.
- **For MCMC**: compute the effective sample size ESS = N / (1 + 2 Σₖ ρₖ) where ρₖ is the lag-k autocorrelation. ESS << N indicates poor mixing and inflated SE.

> **TIP: Control Variates in REINFORCE**
>
> The REINFORCE gradient estimator ∇θ E[R] = E[R ∇θ log π(a|s,θ)] has high variance. Subtracting a baseline b(s) (control variate): ∇θ E[R] = E[(R − b(s)) ∇θ log π(a|s,θ)]. The baseline does not bias the gradient because E[b(s) ∇θ log π] = 0. A common choice is the value function estimate V(s) as the baseline — this is the advantage actor-critic method.

| Method | Convergence | Strengths | Weaknesses |
| --- | --- | --- | --- |
| Standard MC | O(1/√N) | Simple, unbiased, dimension-free | High variance for smooth integrands |
| Control variates | Better O(1/√N) | Can give 10x+ speedup | Requires correlated estimator with known mean |
| Antithetic variates | Better O(1/√N) | Easy to implement | Only works for monotone integrands |
| Stratified sampling | O(1/N) for 1D | Guaranteed coverage | Hard to extend to high dimensions |
| Sobol QMC | ~O(1/N) | Best for d<20, smooth f | Not probabilistically valid samples |
| MCMC (Metropolis) | O(1/√N_eff) | Can sample from unnormalised p | Correlated samples; slow mixing |

---

## Key Takeaways

- MC integration: Ê[f] = (1/N) Σ f(xᵢ) with xᵢ~p converges at O(1/√N) independent of dimension — the key advantage over classical quadrature.
- SE = σ_f / √N: to halve the error requires 4× samples; variance reduction is often more cost-effective than increasing N.
- Control variates (subtract a term with known expectation), antithetic variates (use paired reflections), and stratified sampling all reduce variance without increasing N.
- Sobol quasi-Monte Carlo achieves ~O(1/N) convergence for smooth d<20 integrands by replacing random samples with low-discrepancy deterministic sequences.
- In RL, first-visit Monte Carlo policy evaluation averages full episode returns from each first visit to a state — unbiased but high variance compared to TD methods.
- Always report SE alongside MC estimates; for MCMC samples compute ESS to account for autocorrelation before interpreting the SE.
- Control variates appear in RL as baselines (advantage actor-critic), in variational inference as variance reduction for ELBO gradient estimates.
