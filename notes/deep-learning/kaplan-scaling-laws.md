---
title: "Kaplan Scaling Laws — Power Laws for LLM Loss, Parameters, and Compute"
slug: "kaplan-scaling-laws"
description: "Kaplan et al. (2020): test loss scales as a power law in N (parameters), D (tokens), and C (compute) over seven orders of magnitude, with compute-optimal frontier predictions and irreducible loss estimation."
tags: ["deep-learning", "llm"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"In 2020, Kaplan et al. at OpenAI published a landmark empirical study showing that the test loss of language models follows smooth power laws over more than seven orders of magnitude in parameters N, tokens D, and compute C. Measured on WebText2 with GPT-style architectures, these scaling laws provided the first rigorous framework for predicting model performance before training and for allocating compute budgets across model size and training duration."},{"type":"heading","level":2,"content":"The Core Power Laws"},{"type":"text","content":"Three fundamental relationships govern LLM loss. Loss vs parameters: L(N) = a_N * N^(-alpha_N), alpha_N approximately 0.076 — doubling parameters reduces loss by roughly 5%. Loss vs tokens: L(D) = a_D * D^(-alpha_D), alpha_D approximately 0.095 — doubling tokens reduces loss by roughly 6%. Loss vs compute: L(C) = a_C * C^(-alpha_C), alpha_C approximately 0.057 — doubling compute reduces loss by roughly 4%. Each law holds when the other factors are not the binding constraint. The striking result is that all three hold over seven orders of magnitude with no observed saturation."},{"type":"list","ordered":false,"items":["L(N) proportional to N^(-0.076): parameters law, measured with unlimited data and compute","L(D) proportional to D^(-0.095): data law, measured with large enough models","L(C) proportional to C^(-0.057): compute law, traces the compute-optimal frontier","Architecture (depth, width, heads) contributes less than 5% of loss variance vs total N","Irreducible loss E approximately 1.69 nats on WebText — the entropy floor of natural language","Seven orders of magnitude of smooth scaling: from 1M to 10B parameters, 1B to 1T tokens"]},{"type":"heading","level":2,"content":"Code 1 — Power Law Fitting"},{"type":"code","language":"python","content":"import numpy as np\nfrom scipy.optimize import curve_fit\nimport matplotlib.pyplot as plt\n\n# Empirical loss vs parameter count (N in billions, L in nats)\nN_data = np.array([0.001, 0.003, 0.01, 0.03, 0.1, 0.3, 1.0, 3.0, 10.0, 30.0])\nL_data = np.array([4.20,  3.85,  3.55, 3.28, 3.02, 2.80, 2.60, 2.42,  2.27,  2.14])\n\ndef power_law(N, a, alpha):\n    \u0027\u0027\u0027L(N) = a * N^(-alpha) -- single-factor power law\u0027\u0027\u0027\n    return a * N ** (-alpha)\n\n# Fit via nonlinear least squares\npopt, pcov = curve_fit(power_law, N_data, L_data, p0=[5.0, 0.076], maxfev=5000)\na_fit, alpha_fit = popt\nperr = np.sqrt(np.diag(pcov))\nprint(\u0027Fitted: a = {:.4f} +/- {:.4f}\u0027.format(a_fit, perr[0]))\nprint(\u0027Fitted: alpha_N = {:.4f} +/- {:.4f}  (Kaplan paper: ~0.076)\u0027.format(alpha_fit, perr[1]))\n\n# Extrapolate to larger model sizes\nN_extrap = np.logspace(-3, 3, 200)  # 1M to 1T parameters\nL_pred   = power_law(N_extrap, a_fit, alpha_fit)\n\nplt.figure(figsize=(9, 5))\nplt.loglog(N_data, L_data, \u0027ko\u0027, markersize=8, label=\u0027Empirical data\u0027)\nplt.loglog(N_extrap, L_pred, \u0027b-\u0027, lw=2, label=\u0027Fit: L = {:.2f} * N^(-{:.3f})\u0027.format(a_fit, alpha_fit))\nplt.xlabel(\u0027Parameters N (billions)\u0027, fontsize=12)\nplt.ylabel(\u0027Test Loss L (nats)\u0027, fontsize=12)\nplt.title(\u0027Kaplan Power Law: L(N) proportional to N^(-alpha_N)\u0027, fontsize=13)\nplt.legend(fontsize=11)\nplt.grid(True, which=\u0027both\u0027, alpha=0.3)\nplt.tight_layout()\nplt.savefig(\u0027kaplan_power_law.png\u0027, dpi=150)\nplt.show()"},{"type":"heading","level":2,"content":"The Compute-Optimal Frontier"},{"type":"text","content":"Given a fixed compute budget C (FLOPs), the compute-optimal model size scales as N* proportional to C^0.73 and the compute-optimal token count as D* proportional to C^0.27. This asymmetry means model size should scale much faster than data: doubling compute should grow N by roughly 66% but D by only about 21%. The practical implication Kaplan drew: train the largest feasible model on relatively few tokens, stopping well before convergence. This was the paradigm used for GPT-3 (175B parameters on 300B tokens). The D/N ratio implied by Kaplan is approximately 1 — one token per parameter at the compute-optimal point."},{"type":"heading","level":2,"content":"Code 2 — Compute-Optimal N* Prediction"},{"type":"code","language":"python","content":"import numpy as np\n\n# Kaplan compute-optimal: N* proportional to C^0.73, D* = C / (6 * N*)\n# C = 6 * N * D approximation for transformer training FLOPs\nKAPLAN_EXP_N = 0.73\n\ndef kaplan_optimal(C_flops, k_N=1.3e-5):\n    \u0027\u0027\u0027Predict compute-optimal (N*, D*) for a given FLOP budget per Kaplan.\u0027\u0027\u0027\n    N_star = k_N * (C_flops ** KAPLAN_EXP_N)\n    D_star = C_flops / (6.0 * N_star)  # from C = 6ND\n    return N_star, D_star\n\ndef chinchilla_optimal(C_flops):\n    \u0027\u0027\u0027Chinchilla: D* = 20*N*, C = 6*N*D = 120*N^2 =\u003e N* = sqrt(C/120).\u0027\u0027\u0027\n    N_star = np.sqrt(C_flops / 120.0)\n    D_star = 20.0 * N_star\n    return N_star, D_star\n\nbudgets = [\n    (\u00276e18 (~1B-scale)\u0027,   6e18),\n    (\u00276e20 (~7B-scale)\u0027,   6e20),\n    (\u00276e22 (~70B-scale)\u0027, 6e22),\n    (\u00276e23 (GPT-4 est.)\u0027, 6e23),\n]\nprint(\u0027{:\u003c22} {:\u003e12} {:\u003e12} {:\u003e12} {:\u003e12}\u0027.format(\u0027Compute Budget\u0027, \u0027Kaplan N*(B)\u0027, \u0027Kaplan D*(B)\u0027, \u0027Chinch N*(B)\u0027, \u0027Chinch D*(B)\u0027))\nprint(\u0027-\u0027 * 74)\nfor name, C in budgets:\n    kN, kD = kaplan_optimal(C)\n    cN, cD = chinchilla_optimal(C)\n    print(\u0027{:\u003c22} {:\u003e12.2f} {:\u003e12.2f} {:\u003e12.2f} {:\u003e12.2f}\u0027.format(name, kN/1e9, kD/1e9, cN/1e9, cD/1e9))\nprint(\u0027\\nKaplan D/N ~ 1; Chinchilla D/N = 20 -- a 20x difference in data prescription.\u0027)"},{"type":"heading","level":2,"content":"Code 3 — Scaling Law Comparison Visualization"},{"type":"code","language":"python","content":"import numpy as np\nimport matplotlib.pyplot as plt\n\ndef kaplan_loss_C(C, a=4.0, alpha_c=0.057):\n    \u0027\u0027\u0027Kaplan compute scaling: L(C) = a * C^(-alpha_c)\u0027\u0027\u0027\n    return a * C ** (-alpha_c)\n\ndef chinchilla_loss_C(C, a=3.1, alpha_c=0.050):\n    \u0027\u0027\u0027Chinchilla compute scaling with slightly different exponent\u0027\u0027\u0027\n    return a * C ** (-alpha_c)\n\nC_range = np.logspace(17, 24, 200)  # 1e17 to 1e24 FLOPs\n\n# Approximate reference points from literature\nref_models = {\n    \u0027GPT-2 (1.5B)\u0027:     (1.5e21, 3.30),\n    \u0027GPT-3 (175B)\u0027:     (3.1e23, 2.88),\n    \u0027Chinchilla (70B)\u0027: (3.0e23, 2.55),\n}\n\nfig, ax = plt.subplots(figsize=(9, 5))\nax.loglog(C_range, kaplan_loss_C(C_range),     \u0027b-\u0027,  lw=2, label=\u0027Kaplan (alpha_c = 0.057)\u0027)\nax.loglog(C_range, chinchilla_loss_C(C_range), \u0027g--\u0027, lw=2, label=\u0027Chinchilla fit (alpha_c = 0.050)\u0027)\ncolors = [\u0027#e74c3c\u0027, \u0027#8e44ad\u0027, \u0027#27ae60\u0027]\nfor (name, (C, L)), col in zip(ref_models.items(), colors):\n    ax.scatter(C, L, s=150, color=col, zorder=5, label=name)\nax.set_xlabel(\u0027Compute Budget C (FLOPs)\u0027, fontsize=12)\nax.set_ylabel(\u0027Test Loss L (nats)\u0027, fontsize=12)\nax.set_title(\u0027Predicted vs Actual Loss: Kaplan vs Chinchilla Compute Scaling\u0027, fontsize=12)\nax.legend(fontsize=9)\nax.grid(True, which=\u0027both\u0027, alpha=0.3)\nplt.tight_layout()\nplt.savefig(\u0027scaling_comparison.png\u0027, dpi=150)\nplt.show()"},{"type":"heading","level":2,"content":"Irreducible Loss and the Entropy Floor"},{"type":"text","content":"The full joint scaling law is L(N, D) = E + A/N^alpha + B/D^beta, where E approximately 1.69 nats is the irreducible loss — the entropy of natural language itself, representing information no model can predict regardless of size. The term A/N^alpha captures capacity-limited loss (model too small) and B/D^beta captures data-limited loss (insufficient training tokens). Fitting this joint formula requires a grid of (N, D, L) observations. The Chinchilla paper fitted E=1.69, A=406.4, alpha=0.34, B=410.7, beta=0.28 across over 400 models ranging from 70M to 16B parameters."},{"type":"heading","level":2,"content":"Code 4 — Irreducible Loss Estimation"},{"type":"code","language":"python","content":"import numpy as np\nfrom scipy.optimize import minimize\n\ndef loss_model(params, N, D):\n    \u0027\u0027\u0027L(N, D) = E + A * N^(-alpha) + B * D^(-beta)\u0027\u0027\u0027\n    E, A, alpha, B, beta = params\n    return E + A * N ** (-alpha) + B * D ** (-beta)\n\ndef objective(params, N_arr, D_arr, L_obs):\n    \u0027\u0027\u0027Sum of squared residuals for least-squares fitting.\u0027\u0027\u0027\n    return np.sum((loss_model(params, N_arr, D_arr) - L_obs) ** 2)\n\n# Simulated loss grid: N in B params, D in B tokens\nnp.random.seed(42)\nN_vals = np.array([0.1, 0.3, 1.0, 3.0, 10.0])\nD_vals = np.array([10.0, 30.0, 100.0, 300.0])\nN_grid, D_grid = np.meshgrid(N_vals, D_vals, indexing=\u0027ij\u0027)\nN_flat, D_flat = N_grid.ravel(), D_grid.ravel()\n\n# Ground truth: Chinchilla constants\ntrue_p = [1.69, 406.4, 0.34, 410.7, 0.28]\nL_obs  = loss_model(true_p, N_flat, D_flat) + np.random.normal(0, 0.01, len(N_flat))\n\n# Jointly fit all 5 parameters using Nelder-Mead\nresult = minimize(objective, x0=[2.0, 300.0, 0.30, 300.0, 0.25],\n                  args=(N_flat, D_flat, L_obs), method=\u0027Nelder-Mead\u0027,\n                  options={\u0027maxiter\u0027: 20000, \u0027xatol\u0027: 1e-7})\nE_f, A_f, a_f, B_f, b_f = result.x\nprint(\u0027Fitted:  E={:.3f}, A={:.1f}, alpha={:.3f}, B={:.1f}, beta={:.3f}\u0027.format(E_f, A_f, a_f, B_f, b_f))\nprint(\u0027Target:  E=1.690, A=406.4, alpha=0.340, B=410.7, beta=0.280\u0027)\nprint(\u0027MSE per point: {:.6f}\u0027.format(result.fun / len(N_flat)))"},{"type":"text","content":"The table below compares compute-optimal model size N* and token count D* predicted by Kaplan (2020) versus Chinchilla (2022) for three representative compute budgets. The dramatic difference in D/N ratio — roughly 1x for Kaplan vs 20x for Chinchilla — explains why early large language models such as GPT-3 and Gopher were massively undertrained on data relative to their parameter counts."},{"type":"table","headers":["Compute Budget (FLOPs)","Kaplan N* (B params)","Kaplan D* (B tokens)","Kaplan D/N","Chinchilla N* (B params)","Chinchilla D* (B tokens)","Chinchilla D/N"],"rows":[["6e18 (~1B-scale)","1.0","1.0","~1x","0.22","4.5","~20x"],["6e20 (~7B-scale)","7.0","7.0","~1x","2.24","44.7","~20x"],["6e22 (~70B-scale)","70.0","70.0","~1x","22.4","447","~20x"]]},{"type":"heading","level":2,"content":"Three Regimes and Caveats"},{"type":"text","content":"Kaplan identified three limiting regimes for LLM training. The compute-limited regime applies when both N and D could grow freely but compute is fixed — L(C) law describes performance. The parameter-limited regime applies when the model is too small relative to data — the A/N^alpha term dominates loss and more parameters give rapid gains. The data-limited regime applies when data is exhausted or recycled — B/D^beta dominates and additional tokens degrade due to repetition. Important caveats: laws were measured on WebText2; transfer to code, math, or multilingual data may differ; architecture specifics matter less than total N; and Kaplan did not sweep D independently at each N, a confound that Chinchilla corrected."},{"type":"list","ordered":false,"items":["Compute-limited: grow N and D together along compute-optimal frontier using L(C) law","Parameter-limited: small model with ample data — more parameters give rapid improvement","Data-limited: data exhausted or recycled — diminishing returns, potential degradation","Measured on WebText2 — may not generalize to code, math, or multilingual corpora","Architecture (depth vs width, attention heads) contributes less than N to overall loss","Kaplan\u0027s experiments lacked sufficient data variation — Chinchilla corrected this confound"]},{"type":"callout","variant":"warning","title":"Warning","content":"Kaplan scaling laws predict scaling models faster than data (N* proportional to C^0.73) — Chinchilla later showed this was wrong due to insufficient data in Kaplan\u0027s experiments, and corrected the optimal token-to-parameter ratio to ~20:1."}]"
---
# Kaplan Scaling Laws — Power Laws for LLM Loss, Parameters, and Compute

In 2020, Kaplan et al. at OpenAI published a landmark empirical study showing that the test loss of language models follows smooth power laws over more than seven orders of magnitude in parameters N, tokens D, and compute C. Measured on WebText2 with GPT-style architectures, these scaling laws provided the first rigorous framework for predicting model performance before training and for allocating compute budgets across model size and training duration.

## The Core Power Laws

Three fundamental relationships govern LLM loss. Loss vs parameters: L(N) = a_N * N^(-alpha_N), alpha_N approximately 0.076 — doubling parameters reduces loss by roughly 5%. Loss vs tokens: L(D) = a_D * D^(-alpha_D), alpha_D approximately 0.095 — doubling tokens reduces loss by roughly 6%. Loss vs compute: L(C) = a_C * C^(-alpha_C), alpha_C approximately 0.057 — doubling compute reduces loss by roughly 4%. Each law holds when the other factors are not the binding constraint. The striking result is that all three hold over seven orders of magnitude with no observed saturation.

- L(N) proportional to N^(-0.076): parameters law, measured with unlimited data and compute
- L(D) proportional to D^(-0.095): data law, measured with large enough models
- L(C) proportional to C^(-0.057): compute law, traces the compute-optimal frontier
- Architecture (depth, width, heads) contributes less than 5% of loss variance vs total N
- Irreducible loss E approximately 1.69 nats on WebText — the entropy floor of natural language
- Seven orders of magnitude of smooth scaling: from 1M to 10B parameters, 1B to 1T tokens

## Code 1 — Power Law Fitting

```python
import numpy as np
from scipy.optimize import curve_fit
import matplotlib.pyplot as plt

# Empirical loss vs parameter count (N in billions, L in nats)
N_data = np.array([0.001, 0.003, 0.01, 0.03, 0.1, 0.3, 1.0, 3.0, 10.0, 30.0])
L_data = np.array([4.20,  3.85,  3.55, 3.28, 3.02, 2.80, 2.60, 2.42,  2.27,  2.14])

def power_law(N, a, alpha):
    '''L(N) = a * N^(-alpha) -- single-factor power law'''
    return a * N ** (-alpha)

# Fit via nonlinear least squares
popt, pcov = curve_fit(power_law, N_data, L_data, p0=[5.0, 0.076], maxfev=5000)
a_fit, alpha_fit = popt
perr = np.sqrt(np.diag(pcov))
print('Fitted: a = {:.4f} +/- {:.4f}'.format(a_fit, perr[0]))
print('Fitted: alpha_N = {:.4f} +/- {:.4f}  (Kaplan paper: ~0.076)'.format(alpha_fit, perr[1]))

# Extrapolate to larger model sizes
N_extrap = np.logspace(-3, 3, 200)  # 1M to 1T parameters
L_pred   = power_law(N_extrap, a_fit, alpha_fit)

plt.figure(figsize=(9, 5))
plt.loglog(N_data, L_data, 'ko', markersize=8, label='Empirical data')
plt.loglog(N_extrap, L_pred, 'b-', lw=2, label='Fit: L = {:.2f} * N^(-{:.3f})'.format(a_fit, alpha_fit))
plt.xlabel('Parameters N (billions)', fontsize=12)
plt.ylabel('Test Loss L (nats)', fontsize=12)
plt.title('Kaplan Power Law: L(N) proportional to N^(-alpha_N)', fontsize=13)
plt.legend(fontsize=11)
plt.grid(True, which='both', alpha=0.3)
plt.tight_layout()
plt.savefig('kaplan_power_law.png', dpi=150)
plt.show()
```

## The Compute-Optimal Frontier

Given a fixed compute budget C (FLOPs), the compute-optimal model size scales as N* proportional to C^0.73 and the compute-optimal token count as D* proportional to C^0.27. This asymmetry means model size should scale much faster than data: doubling compute should grow N by roughly 66% but D by only about 21%. The practical implication Kaplan drew: train the largest feasible model on relatively few tokens, stopping well before convergence. This was the paradigm used for GPT-3 (175B parameters on 300B tokens). The D/N ratio implied by Kaplan is approximately 1 — one token per parameter at the compute-optimal point.

## Code 2 — Compute-Optimal N* Prediction

```python
import numpy as np

# Kaplan compute-optimal: N* proportional to C^0.73, D* = C / (6 * N*)
# C = 6 * N * D approximation for transformer training FLOPs
KAPLAN_EXP_N = 0.73

def kaplan_optimal(C_flops, k_N=1.3e-5):
    '''Predict compute-optimal (N*, D*) for a given FLOP budget per Kaplan.'''
    N_star = k_N * (C_flops ** KAPLAN_EXP_N)
    D_star = C_flops / (6.0 * N_star)  # from C = 6ND
    return N_star, D_star

def chinchilla_optimal(C_flops):
    '''Chinchilla: D* = 20*N*, C = 6*N*D = 120*N^2 => N* = sqrt(C/120).'''
    N_star = np.sqrt(C_flops / 120.0)
    D_star = 20.0 * N_star
    return N_star, D_star

budgets = [
    ('6e18 (~1B-scale)',   6e18),
    ('6e20 (~7B-scale)',   6e20),
    ('6e22 (~70B-scale)', 6e22),
    ('6e23 (GPT-4 est.)', 6e23),
]
print('{:<22} {:>12} {:>12} {:>12} {:>12}'.format('Compute Budget', 'Kaplan N*(B)', 'Kaplan D*(B)', 'Chinch N*(B)', 'Chinch D*(B)'))
print('-' * 74)
for name, C in budgets:
    kN, kD = kaplan_optimal(C)
    cN, cD = chinchilla_optimal(C)
    print('{:<22} {:>12.2f} {:>12.2f} {:>12.2f} {:>12.2f}'.format(name, kN/1e9, kD/1e9, cN/1e9, cD/1e9))
print('\nKaplan D/N ~ 1; Chinchilla D/N = 20 -- a 20x difference in data prescription.')
```

## Code 3 — Scaling Law Comparison Visualization

```python
import numpy as np
import matplotlib.pyplot as plt

def kaplan_loss_C(C, a=4.0, alpha_c=0.057):
    '''Kaplan compute scaling: L(C) = a * C^(-alpha_c)'''
    return a * C ** (-alpha_c)

def chinchilla_loss_C(C, a=3.1, alpha_c=0.050):
    '''Chinchilla compute scaling with slightly different exponent'''
    return a * C ** (-alpha_c)

C_range = np.logspace(17, 24, 200)  # 1e17 to 1e24 FLOPs

# Approximate reference points from literature
ref_models = {
    'GPT-2 (1.5B)':     (1.5e21, 3.30),
    'GPT-3 (175B)':     (3.1e23, 2.88),
    'Chinchilla (70B)': (3.0e23, 2.55),
}

fig, ax = plt.subplots(figsize=(9, 5))
ax.loglog(C_range, kaplan_loss_C(C_range),     'b-',  lw=2, label='Kaplan (alpha_c = 0.057)')
ax.loglog(C_range, chinchilla_loss_C(C_range), 'g--', lw=2, label='Chinchilla fit (alpha_c = 0.050)')
colors = ['#e74c3c', '#8e44ad', '#27ae60']
for (name, (C, L)), col in zip(ref_models.items(), colors):
    ax.scatter(C, L, s=150, color=col, zorder=5, label=name)
ax.set_xlabel('Compute Budget C (FLOPs)', fontsize=12)
ax.set_ylabel('Test Loss L (nats)', fontsize=12)
ax.set_title('Predicted vs Actual Loss: Kaplan vs Chinchilla Compute Scaling', fontsize=12)
ax.legend(fontsize=9)
ax.grid(True, which='both', alpha=0.3)
plt.tight_layout()
plt.savefig('scaling_comparison.png', dpi=150)
plt.show()
```

## Irreducible Loss and the Entropy Floor

The full joint scaling law is L(N, D) = E + A/N^alpha + B/D^beta, where E approximately 1.69 nats is the irreducible loss — the entropy of natural language itself, representing information no model can predict regardless of size. The term A/N^alpha captures capacity-limited loss (model too small) and B/D^beta captures data-limited loss (insufficient training tokens). Fitting this joint formula requires a grid of (N, D, L) observations. The Chinchilla paper fitted E=1.69, A=406.4, alpha=0.34, B=410.7, beta=0.28 across over 400 models ranging from 70M to 16B parameters.

## Code 4 — Irreducible Loss Estimation

```python
import numpy as np
from scipy.optimize import minimize

def loss_model(params, N, D):
    '''L(N, D) = E + A * N^(-alpha) + B * D^(-beta)'''
    E, A, alpha, B, beta = params
    return E + A * N ** (-alpha) + B * D ** (-beta)

def objective(params, N_arr, D_arr, L_obs):
    '''Sum of squared residuals for least-squares fitting.'''
    return np.sum((loss_model(params, N_arr, D_arr) - L_obs) ** 2)

# Simulated loss grid: N in B params, D in B tokens
np.random.seed(42)
N_vals = np.array([0.1, 0.3, 1.0, 3.0, 10.0])
D_vals = np.array([10.0, 30.0, 100.0, 300.0])
N_grid, D_grid = np.meshgrid(N_vals, D_vals, indexing='ij')
N_flat, D_flat = N_grid.ravel(), D_grid.ravel()

# Ground truth: Chinchilla constants
true_p = [1.69, 406.4, 0.34, 410.7, 0.28]
L_obs  = loss_model(true_p, N_flat, D_flat) + np.random.normal(0, 0.01, len(N_flat))

# Jointly fit all 5 parameters using Nelder-Mead
result = minimize(objective, x0=[2.0, 300.0, 0.30, 300.0, 0.25],
                  args=(N_flat, D_flat, L_obs), method='Nelder-Mead',
                  options={'maxiter': 20000, 'xatol': 1e-7})
E_f, A_f, a_f, B_f, b_f = result.x
print('Fitted:  E={:.3f}, A={:.1f}, alpha={:.3f}, B={:.1f}, beta={:.3f}'.format(E_f, A_f, a_f, B_f, b_f))
print('Target:  E=1.690, A=406.4, alpha=0.340, B=410.7, beta=0.280')
print('MSE per point: {:.6f}'.format(result.fun / len(N_flat)))
```

The table below compares compute-optimal model size N* and token count D* predicted by Kaplan (2020) versus Chinchilla (2022) for three representative compute budgets. The dramatic difference in D/N ratio — roughly 1x for Kaplan vs 20x for Chinchilla — explains why early large language models such as GPT-3 and Gopher were massively undertrained on data relative to their parameter counts.

| Compute Budget (FLOPs) | Kaplan N* (B params) | Kaplan D* (B tokens) | Kaplan D/N | Chinchilla N* (B params) | Chinchilla D* (B tokens) | Chinchilla D/N |
| --- | --- | --- | --- | --- | --- | --- |
| 6e18 (~1B-scale) | 1.0 | 1.0 | ~1x | 0.22 | 4.5 | ~20x |
| 6e20 (~7B-scale) | 7.0 | 7.0 | ~1x | 2.24 | 44.7 | ~20x |
| 6e22 (~70B-scale) | 70.0 | 70.0 | ~1x | 22.4 | 447 | ~20x |

## Three Regimes and Caveats

Kaplan identified three limiting regimes for LLM training. The compute-limited regime applies when both N and D could grow freely but compute is fixed — L(C) law describes performance. The parameter-limited regime applies when the model is too small relative to data — the A/N^alpha term dominates loss and more parameters give rapid gains. The data-limited regime applies when data is exhausted or recycled — B/D^beta dominates and additional tokens degrade due to repetition. Important caveats: laws were measured on WebText2; transfer to code, math, or multilingual data may differ; architecture specifics matter less than total N; and Kaplan did not sweep D independently at each N, a confound that Chinchilla corrected.

- Compute-limited: grow N and D together along compute-optimal frontier using L(C) law
- Parameter-limited: small model with ample data — more parameters give rapid improvement
- Data-limited: data exhausted or recycled — diminishing returns, potential degradation
- Measured on WebText2 — may not generalize to code, math, or multilingual corpora
- Architecture (depth vs width, attention heads) contributes less than N to overall loss
- Kaplan's experiments lacked sufficient data variation — Chinchilla corrected this confound

> **Warning**: Kaplan scaling laws predict scaling models faster than data (N* proportional to C^0.73) — Chinchilla later showed this was wrong due to insufficient data in Kaplan's experiments, and corrected the optimal token-to-parameter ratio to ~20:1.

