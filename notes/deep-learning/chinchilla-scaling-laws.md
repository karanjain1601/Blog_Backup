---
title: "Chinchilla Scaling Laws — Compute-Optimal Token-to-Parameter Ratios"
slug: "chinchilla-scaling-laws"
description: "Hoffmann et al. (2022, DeepMind): by sweeping (N, D) at fixed compute, the true optimal D/N ratio is ~20 tokens per parameter — not ~1 as Kaplan suggested — showing GPT-3, Gopher, and most pre-2022 LLMs were severely undertrained on data."
tags: ["deep-learning", "llm"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"In 2022, Hoffmann et al. at DeepMind published the Chinchilla paper, overturning the prevailing Kaplan-derived wisdom that model size should scale faster than data. By training over 400 models ranging from 70M to 16B parameters on 5B to 500B tokens, they identified the true compute-optimal allocation: for a fixed compute budget C, both model size N* and token count D* should scale equally — proportional to C^0.5 each. The key result: D/N approximately 20 tokens per parameter at the optimal point, not 1 as Kaplan predicted."},{"type":"heading","level":2,"content":"The Compute-Optimal Insight"},{"type":"text","content":"Chinchilla (70B parameters, 1.4T training tokens) outperformed Gopher (280B parameters, 300B tokens) at the same compute budget, demonstrating that data quantity matters as much as model size. GPT-3 (175B parameters, 300B tokens) was undertrained by approximately 10x on data relative to its parameter count. The joint loss formula L(N, D) = E + A/N^alpha + B/D^beta was fitted with E=1.69, A=406.4, alpha=0.34, B=410.7, beta=0.28, enabling precise optimization of the N-D trade-off at any compute level."},{"type":"list","ordered":false,"items":["Optimal D/N = 20: train on 20 tokens per parameter at compute-optimal allocation","N* proportional to C^0.5 and D* proportional to C^0.5: equal scaling of model and data","Chinchilla (70B, 1.4T) beats Gopher (280B, 300B) at same compute — 4x smaller model, 5x more data","GPT-3 (175B, 300B tokens): D/N = 1.7, approximately 10x under-trained on data","C = 6*N*D approximation: 6 multiply-adds per parameter per token (2 forward + 4 backward)","LLaMA-1 (7B, 1T tokens): D/N = 143, approximately 7x over-trained — inference-optimized"]},{"type":"heading","level":2,"content":"Code 1 — Chinchilla Loss Formula"},{"type":"code","language":"python","content":"import numpy as np\nimport matplotlib.pyplot as plt\n\n# Chinchilla fitted constants (Hoffmann et al., 2022, Table 3)\nE_CONST = 1.69    # irreducible loss: entropy floor of natural language\nA_CONST = 406.4   # parameter scaling coefficient\nB_CONST = 410.7   # data scaling coefficient\nALPHA   = 0.34    # parameter scaling exponent\nBETA    = 0.28    # data scaling exponent\n\ndef chinchilla_loss(N, D):\n    \u0027\u0027\u0027L(N, D) = E + A/N^alpha + B/D^beta\u0027\u0027\u0027\n    return E_CONST + A_CONST * N ** (-ALPHA) + B_CONST * D ** (-BETA)\n\n# Fix compute C, sweep N while D = C / (6*N)\nC_fixed = 6e21   # ~30B model-scale compute budget\nN_range = np.logspace(8, 12, 300)  # 100M to 1T parameters\nD_range = C_fixed / (6.0 * N_range)\n\nL_range  = chinchilla_loss(N_range, D_range)\nbest_idx = np.argmin(L_range)\nN_opt, D_opt, L_min = N_range[best_idx], D_range[best_idx], L_range[best_idx]\nprint(\u0027Compute budget: {:.1e} FLOPs\u0027.format(C_fixed))\nprint(\u0027Optimal N*: {:.2f}B params | D*: {:.2f}B tokens | D/N: {:.1f} | L_min: {:.4f}\u0027.format(\n    N_opt/1e9, D_opt/1e9, D_opt/N_opt, L_min))\n\nplt.figure(figsize=(9, 5))\nplt.semilogx(N_range / 1e9, L_range, \u0027b-\u0027, lw=2, label=\u0027L(N, D) at fixed C\u0027)\nplt.axvline(N_opt / 1e9, color=\u0027r\u0027, ls=\u0027--\u0027, lw=2, label=\u0027Optimal N* = {:.1f}B\u0027.format(N_opt/1e9))\nplt.xlabel(\u0027Model Size N (billions of parameters)\u0027, fontsize=12)\nplt.ylabel(\u0027Predicted Loss L(N, D)\u0027, fontsize=12)\nplt.title(\u0027Chinchilla Loss vs N for Fixed Compute C = {:.1e} FLOPs\u0027.format(C_fixed), fontsize=12)\nplt.legend(fontsize=11)\nplt.grid(True, alpha=0.3)\nplt.tight_layout()\nplt.savefig(\u0027chinchilla_loss_curve.png\u0027, dpi=150)\nplt.show()"},{"type":"heading","level":2,"content":"Optimal Token-to-Parameter Ratio"},{"type":"text","content":"The 20:1 token-to-parameter ratio emerges from the symmetry of the Chinchilla loss formula when both alpha and beta are similar (0.34 vs 0.28). The optimal allocation minimizes L(N, D) = E + A/N^alpha + B/D^beta subject to C = 6ND. Taking partial derivatives and setting them equal gives the condition A*alpha/N^(alpha+1) = B*beta/D^(beta+1), which with alpha approximately beta leads to A/N^alpha approximately B/D^beta — roughly equal contributions from each term. Since A and B are nearly equal (406.4 vs 410.7), and alpha and beta are close, the optimal N and D end up roughly equal in their contribution, yielding D/N = 20 as the empirical ratio."},{"type":"heading","level":2,"content":"Code 2 — Compute-Optimal Frontier"},{"type":"code","language":"python","content":"import numpy as np\nimport matplotlib.pyplot as plt\n\ndef chinchilla_optimal(C):\n    \u0027\u0027\u0027Chinchilla: equal scaling, D* = 20*N*, C = 6*N*D* = 120*N*^2.\u0027\u0027\u0027\n    N_star = np.sqrt(C / 120.0)\n    D_star = 20.0 * N_star\n    return N_star, D_star\n\ndef kaplan_optimal(C, k_N=1.3e-5):\n    \u0027\u0027\u0027Kaplan: N scales faster than D (N* proportional to C^0.73).\u0027\u0027\u0027\n    N_star = k_N * (C ** 0.73)\n    D_star = C / (6.0 * N_star)\n    return N_star, D_star\n\nC_range = np.logspace(18, 24, 150)\nch_N, ch_D = chinchilla_optimal(C_range)\nkp_N, kp_D = kaplan_optimal(C_range)\n\nfig, axes = plt.subplots(1, 2, figsize=(13, 5))\naxes[0].loglog(C_range, ch_N/1e9, \u0027b-\u0027,  lw=2, label=\u0027Chinchilla N*\u0027)\naxes[0].loglog(C_range, kp_N/1e9, \u0027r--\u0027, lw=2, label=\u0027Kaplan N*\u0027)\naxes[0].set(xlabel=\u0027Compute C (FLOPs)\u0027, ylabel=\u0027Optimal N* (billions)\u0027,\n            title=\u0027Optimal Model Size vs Compute\u0027)\naxes[0].legend(); axes[0].grid(True, alpha=0.3)\n\naxes[1].loglog(C_range, ch_D/1e9, \u0027b-\u0027,  lw=2, label=\u0027Chinchilla D*\u0027)\naxes[1].loglog(C_range, kp_D/1e9, \u0027r--\u0027, lw=2, label=\u0027Kaplan D*\u0027)\naxes[1].set(xlabel=\u0027Compute C (FLOPs)\u0027, ylabel=\u0027Optimal D* (B tokens)\u0027,\n            title=\u0027Optimal Token Count vs Compute\u0027)\naxes[1].legend(); axes[1].grid(True, alpha=0.3)\n\nplt.suptitle(\u0027Kaplan vs Chinchilla: Compute-Optimal Frontier\u0027, fontsize=13)\nplt.tight_layout()\nplt.savefig(\u0027chinchilla_vs_kaplan_frontier.png\u0027, dpi=150)\nplt.show()"},{"type":"heading","level":2,"content":"Training FLOPs Estimation"},{"type":"text","content":"The C = 6ND approximation counts forward and backward passes through a transformer. Each multiply-add operation contributes 2 FLOPs (one multiply, one add). The forward pass requires roughly 2ND FLOPs (one pass through N parameters for each of D tokens). The backward pass requires roughly 4ND FLOPs (two passes: computing gradients with respect to weights and with respect to activations). Total: 6ND FLOPs. This approximation ignores attention FLOP contributions (O(T^2) per layer), embedding lookups, and layer norm — these add roughly 10-20% overhead for typical sequence lengths and architecture choices."},{"type":"heading","level":2,"content":"Code 3 — Training FLOPs Estimation"},{"type":"code","language":"python","content":"import numpy as np\n\n# C = 6 * N * D approximation (Chinchilla paper)\n# Factor of 6 = 2 (forward pass) + 4 (backward pass) per parameter per token\n\ndef training_flops(N_params, D_tokens):\n    \u0027\u0027\u0027Estimate training FLOPs: C = 6 * N * D.\u0027\u0027\u0027\n    return 6.0 * N_params * D_tokens\n\n# Known model specs: (name, N_params, D_tokens)\nmodels = [\n    (\u0027GPT-3 175B\u0027,      175e9,   300e9),\n    (\u0027Chinchilla 70B\u0027,   70e9,  1400e9),\n    (\u0027Gopher 280B\u0027,     280e9,   300e9),\n    (\u0027LLaMA-1 7B\u0027,        7e9,  1000e9),\n    (\u0027LLaMA-2 70B\u0027,      70e9,  2000e9),\n]\n\nchinchilla_ratio = 20.0  # compute-optimal D/N\n\nprint(\u0027{:\u003c20} {:\u003e8} {:\u003e10} {:\u003e8} {:\u003e15} {:\u003e15}\u0027.format(\n    \u0027Model\u0027, \u0027N (B)\u0027, \u0027D (B tok)\u0027, \u0027D/N\u0027, \u0027C (FLOPs)\u0027, \u0027vs Chinchilla\u0027))\nprint(\u0027-\u0027 * 82)\nfor name, N, D in models:\n    C   = training_flops(N, D)\n    dn  = D / N\n    ratio = dn / chinchilla_ratio\n    tag = \u0027optimal\u0027 if 0.8 \u003c= ratio \u003c= 1.2 else \u0027{:.1f}x over\u0027.format(ratio) if ratio \u003e 1 else \u0027{:.1f}x under\u0027.format(1/ratio)\n    print(\u0027{:\u003c20} {:\u003e8.0f} {:\u003e10.0f} {:\u003e8.1f} {:\u003e15.2e} {:\u003e15}\u0027.format(name, N/1e9, D/1e9, dn, C, tag))"},{"type":"heading","level":2,"content":"Code 4 — Model Comparison on Compute-Optimal Curve"},{"type":"code","language":"python","content":"import numpy as np\nimport matplotlib.pyplot as plt\n\nE_CONST, A_CONST, B_CONST, ALPHA, BETA = 1.69, 406.4, 410.7, 0.34, 0.28\n\ndef chinchilla_loss(N, D):\n    return E_CONST + A_CONST * N**(-ALPHA) + B_CONST * D**(-BETA)\n\n# Real models to plot: (name, N_params, D_tokens, color)\nmodels = [\n    (\u0027GPT-3 175B\u0027,      175e9,  300e9, \u0027#e74c3c\u0027),\n    (\u0027Gopher 280B\u0027,     280e9,  300e9, \u0027#e67e22\u0027),\n    (\u0027Chinchilla 70B\u0027,   70e9, 1400e9, \u0027#27ae60\u0027),\n    (\u0027LLaMA-1 7B\u0027,        7e9, 1000e9, \u0027#3498db\u0027),\n]\n\n# Compute-optimal frontier\nC_range = np.logspace(19, 24, 300)\nN_opt_f = np.sqrt(C_range / 120.0)\nD_opt_f = 20.0 * N_opt_f\nL_opt_f = chinchilla_loss(N_opt_f, D_opt_f)\n\nplt.figure(figsize=(9, 5))\nplt.plot(C_range, L_opt_f, \u0027k-\u0027, lw=2, label=\u0027Chinchilla-optimal frontier\u0027)\nfor name, N, D, col in models:\n    C_model = 6.0 * N * D\n    plt.scatter(C_model, chinchilla_loss(N, D), s=130, color=col, zorder=5, label=name)\nplt.xscale(\u0027log\u0027)\nplt.xlabel(\u0027Compute C (FLOPs)\u0027, fontsize=12)\nplt.ylabel(\u0027Predicted Test Loss (nats)\u0027, fontsize=12)\nplt.title(\u0027Models vs Chinchilla Compute-Optimal Frontier\u0027, fontsize=13)\nplt.legend(fontsize=10)\nplt.grid(True, alpha=0.3)\nplt.tight_layout()\nplt.savefig(\u0027model_frontier_comparison.png\u0027, dpi=150)\nplt.show()"},{"type":"text","content":"The table below compares pre-Chinchilla and post-Chinchilla models showing their parameter count, token count, D/N ratio, and how far each is from the compute-optimal allocation. Models above the compute-optimal D/N are inference-optimized (trained beyond Chinchilla-optimal to reduce per-query serving cost). Models below are training-compute-optimized."},{"type":"table","headers":["Model","Params (B)","Tokens (B)","D/N Ratio","Rel. to Compute-Optimal","Notes"],"rows":[["GPT-3","175","300","1.7","~10x under (data)","Pre-Chinchilla paradigm"],["Gopher","280","300","1.1","~18x under (data)","Pre-Chinchilla paradigm"],["Chinchilla","70","1400","20","Compute-optimal","Benchmark model"],["LLaMA-1 7B","7","1000","143","~7x over (data)","Inference-optimized"],["LLaMA-2 70B","70","2000","28.6","~1.4x over (data)","Near compute-optimal"],["Mistral 7B","7","2000","286","~14x over (data)","Inference-optimized"]]},{"type":"text","content":"The Chinchilla result immediately reframed the field. Models like GPT-4 and subsequent frontier systems shifted to training smaller architectures on vastly more tokens. The practical question changed from \u0027how large should the model be?\u0027 to \u0027how many tokens can we afford to train on, and what size model is compute-optimal for that data budget?\u0027"},{"type":"list","ordered":false,"items":["For any fixed compute budget C: train N* = sqrt(C/120) params on D* = 20*N* tokens","GPT-3 needed ~3T tokens to be compute-optimal at 175B params — it only saw 300B","Chinchilla 70B matches or beats GPT-3 175B at 4x fewer parameters and same compute","Post-Chinchilla models (LLaMA, Falcon, Mistral) intentionally over-train for inference savings","Optimal allocation depends on inference cost: if serving at scale, smaller models are better"]},{"type":"callout","variant":"info","title":"Info","content":"Chinchilla\u0027s 20:1 token-to-parameter ratio assumes training is done once for deployment — if you plan to serve a model at scale, training smaller models on more data reduces inference cost per query while matching the same compute budget."},{"type":"heading","level":2,"content":"Limitations and Caveats"},{"type":"text","content":"The Chinchilla results have important scope limitations. First, the optimal D/N ratio assumes all training compute is the constraint — if inference cost dominates (millions of queries per day), a smaller model trained on far more tokens is often better. Second, the fitted constants (A, B, alpha, beta) were measured on The Pile and may not transfer to domain-specific corpora such as code or math. Third, the approximation C = 6ND ignores attention complexity, embedding tables, and layer normalization. Fourth, the scaling laws describe pre-training only — instruction tuning, RLHF, and DPO post-training cost is not captured. Fifth, diminishing returns from data quality and deduplication mean that 1T tokens of web text may be equivalent to far fewer high-quality tokens."}]"
---
# Chinchilla Scaling Laws — Compute-Optimal Token-to-Parameter Ratios

In 2022, Hoffmann et al. at DeepMind published the Chinchilla paper, overturning the prevailing Kaplan-derived wisdom that model size should scale faster than data. By training over 400 models ranging from 70M to 16B parameters on 5B to 500B tokens, they identified the true compute-optimal allocation: for a fixed compute budget C, both model size N* and token count D* should scale equally — proportional to C^0.5 each. The key result: D/N approximately 20 tokens per parameter at the optimal point, not 1 as Kaplan predicted.

## The Compute-Optimal Insight

Chinchilla (70B parameters, 1.4T training tokens) outperformed Gopher (280B parameters, 300B tokens) at the same compute budget, demonstrating that data quantity matters as much as model size. GPT-3 (175B parameters, 300B tokens) was undertrained by approximately 10x on data relative to its parameter count. The joint loss formula L(N, D) = E + A/N^alpha + B/D^beta was fitted with E=1.69, A=406.4, alpha=0.34, B=410.7, beta=0.28, enabling precise optimization of the N-D trade-off at any compute level.

- Optimal D/N = 20: train on 20 tokens per parameter at compute-optimal allocation
- N* proportional to C^0.5 and D* proportional to C^0.5: equal scaling of model and data
- Chinchilla (70B, 1.4T) beats Gopher (280B, 300B) at same compute — 4x smaller model, 5x more data
- GPT-3 (175B, 300B tokens): D/N = 1.7, approximately 10x under-trained on data
- C = 6*N*D approximation: 6 multiply-adds per parameter per token (2 forward + 4 backward)
- LLaMA-1 (7B, 1T tokens): D/N = 143, approximately 7x over-trained — inference-optimized

## Code 1 — Chinchilla Loss Formula

```python
import numpy as np
import matplotlib.pyplot as plt

# Chinchilla fitted constants (Hoffmann et al., 2022, Table 3)
E_CONST = 1.69    # irreducible loss: entropy floor of natural language
A_CONST = 406.4   # parameter scaling coefficient
B_CONST = 410.7   # data scaling coefficient
ALPHA   = 0.34    # parameter scaling exponent
BETA    = 0.28    # data scaling exponent

def chinchilla_loss(N, D):
    '''L(N, D) = E + A/N^alpha + B/D^beta'''
    return E_CONST + A_CONST * N ** (-ALPHA) + B_CONST * D ** (-BETA)

# Fix compute C, sweep N while D = C / (6*N)
C_fixed = 6e21   # ~30B model-scale compute budget
N_range = np.logspace(8, 12, 300)  # 100M to 1T parameters
D_range = C_fixed / (6.0 * N_range)

L_range  = chinchilla_loss(N_range, D_range)
best_idx = np.argmin(L_range)
N_opt, D_opt, L_min = N_range[best_idx], D_range[best_idx], L_range[best_idx]
print('Compute budget: {:.1e} FLOPs'.format(C_fixed))
print('Optimal N*: {:.2f}B params | D*: {:.2f}B tokens | D/N: {:.1f} | L_min: {:.4f}'.format(
    N_opt/1e9, D_opt/1e9, D_opt/N_opt, L_min))

plt.figure(figsize=(9, 5))
plt.semilogx(N_range / 1e9, L_range, 'b-', lw=2, label='L(N, D) at fixed C')
plt.axvline(N_opt / 1e9, color='r', ls='--', lw=2, label='Optimal N* = {:.1f}B'.format(N_opt/1e9))
plt.xlabel('Model Size N (billions of parameters)', fontsize=12)
plt.ylabel('Predicted Loss L(N, D)', fontsize=12)
plt.title('Chinchilla Loss vs N for Fixed Compute C = {:.1e} FLOPs'.format(C_fixed), fontsize=12)
plt.legend(fontsize=11)
plt.grid(True, alpha=0.3)
plt.tight_layout()
plt.savefig('chinchilla_loss_curve.png', dpi=150)
plt.show()
```

## Optimal Token-to-Parameter Ratio

The 20:1 token-to-parameter ratio emerges from the symmetry of the Chinchilla loss formula when both alpha and beta are similar (0.34 vs 0.28). The optimal allocation minimizes L(N, D) = E + A/N^alpha + B/D^beta subject to C = 6ND. Taking partial derivatives and setting them equal gives the condition A*alpha/N^(alpha+1) = B*beta/D^(beta+1), which with alpha approximately beta leads to A/N^alpha approximately B/D^beta — roughly equal contributions from each term. Since A and B are nearly equal (406.4 vs 410.7), and alpha and beta are close, the optimal N and D end up roughly equal in their contribution, yielding D/N = 20 as the empirical ratio.

## Code 2 — Compute-Optimal Frontier

```python
import numpy as np
import matplotlib.pyplot as plt

def chinchilla_optimal(C):
    '''Chinchilla: equal scaling, D* = 20*N*, C = 6*N*D* = 120*N*^2.'''
    N_star = np.sqrt(C / 120.0)
    D_star = 20.0 * N_star
    return N_star, D_star

def kaplan_optimal(C, k_N=1.3e-5):
    '''Kaplan: N scales faster than D (N* proportional to C^0.73).'''
    N_star = k_N * (C ** 0.73)
    D_star = C / (6.0 * N_star)
    return N_star, D_star

C_range = np.logspace(18, 24, 150)
ch_N, ch_D = chinchilla_optimal(C_range)
kp_N, kp_D = kaplan_optimal(C_range)

fig, axes = plt.subplots(1, 2, figsize=(13, 5))
axes[0].loglog(C_range, ch_N/1e9, 'b-',  lw=2, label='Chinchilla N*')
axes[0].loglog(C_range, kp_N/1e9, 'r--', lw=2, label='Kaplan N*')
axes[0].set(xlabel='Compute C (FLOPs)', ylabel='Optimal N* (billions)',
            title='Optimal Model Size vs Compute')
axes[0].legend(); axes[0].grid(True, alpha=0.3)

axes[1].loglog(C_range, ch_D/1e9, 'b-',  lw=2, label='Chinchilla D*')
axes[1].loglog(C_range, kp_D/1e9, 'r--', lw=2, label='Kaplan D*')
axes[1].set(xlabel='Compute C (FLOPs)', ylabel='Optimal D* (B tokens)',
            title='Optimal Token Count vs Compute')
axes[1].legend(); axes[1].grid(True, alpha=0.3)

plt.suptitle('Kaplan vs Chinchilla: Compute-Optimal Frontier', fontsize=13)
plt.tight_layout()
plt.savefig('chinchilla_vs_kaplan_frontier.png', dpi=150)
plt.show()
```

## Training FLOPs Estimation

The C = 6ND approximation counts forward and backward passes through a transformer. Each multiply-add operation contributes 2 FLOPs (one multiply, one add). The forward pass requires roughly 2ND FLOPs (one pass through N parameters for each of D tokens). The backward pass requires roughly 4ND FLOPs (two passes: computing gradients with respect to weights and with respect to activations). Total: 6ND FLOPs. This approximation ignores attention FLOP contributions (O(T^2) per layer), embedding lookups, and layer norm — these add roughly 10-20% overhead for typical sequence lengths and architecture choices.

## Code 3 — Training FLOPs Estimation

```python
import numpy as np

# C = 6 * N * D approximation (Chinchilla paper)
# Factor of 6 = 2 (forward pass) + 4 (backward pass) per parameter per token

def training_flops(N_params, D_tokens):
    '''Estimate training FLOPs: C = 6 * N * D.'''
    return 6.0 * N_params * D_tokens

# Known model specs: (name, N_params, D_tokens)
models = [
    ('GPT-3 175B',      175e9,   300e9),
    ('Chinchilla 70B',   70e9,  1400e9),
    ('Gopher 280B',     280e9,   300e9),
    ('LLaMA-1 7B',        7e9,  1000e9),
    ('LLaMA-2 70B',      70e9,  2000e9),
]

chinchilla_ratio = 20.0  # compute-optimal D/N

print('{:<20} {:>8} {:>10} {:>8} {:>15} {:>15}'.format(
    'Model', 'N (B)', 'D (B tok)', 'D/N', 'C (FLOPs)', 'vs Chinchilla'))
print('-' * 82)
for name, N, D in models:
    C   = training_flops(N, D)
    dn  = D / N
    ratio = dn / chinchilla_ratio
    tag = 'optimal' if 0.8 <= ratio <= 1.2 else '{:.1f}x over'.format(ratio) if ratio > 1 else '{:.1f}x under'.format(1/ratio)
    print('{:<20} {:>8.0f} {:>10.0f} {:>8.1f} {:>15.2e} {:>15}'.format(name, N/1e9, D/1e9, dn, C, tag))
```

## Code 4 — Model Comparison on Compute-Optimal Curve

```python
import numpy as np
import matplotlib.pyplot as plt

E_CONST, A_CONST, B_CONST, ALPHA, BETA = 1.69, 406.4, 410.7, 0.34, 0.28

def chinchilla_loss(N, D):
    return E_CONST + A_CONST * N**(-ALPHA) + B_CONST * D**(-BETA)

# Real models to plot: (name, N_params, D_tokens, color)
models = [
    ('GPT-3 175B',      175e9,  300e9, '#e74c3c'),
    ('Gopher 280B',     280e9,  300e9, '#e67e22'),
    ('Chinchilla 70B',   70e9, 1400e9, '#27ae60'),
    ('LLaMA-1 7B',        7e9, 1000e9, '#3498db'),
]

# Compute-optimal frontier
C_range = np.logspace(19, 24, 300)
N_opt_f = np.sqrt(C_range / 120.0)
D_opt_f = 20.0 * N_opt_f
L_opt_f = chinchilla_loss(N_opt_f, D_opt_f)

plt.figure(figsize=(9, 5))
plt.plot(C_range, L_opt_f, 'k-', lw=2, label='Chinchilla-optimal frontier')
for name, N, D, col in models:
    C_model = 6.0 * N * D
    plt.scatter(C_model, chinchilla_loss(N, D), s=130, color=col, zorder=5, label=name)
plt.xscale('log')
plt.xlabel('Compute C (FLOPs)', fontsize=12)
plt.ylabel('Predicted Test Loss (nats)', fontsize=12)
plt.title('Models vs Chinchilla Compute-Optimal Frontier', fontsize=13)
plt.legend(fontsize=10)
plt.grid(True, alpha=0.3)
plt.tight_layout()
plt.savefig('model_frontier_comparison.png', dpi=150)
plt.show()
```

The table below compares pre-Chinchilla and post-Chinchilla models showing their parameter count, token count, D/N ratio, and how far each is from the compute-optimal allocation. Models above the compute-optimal D/N are inference-optimized (trained beyond Chinchilla-optimal to reduce per-query serving cost). Models below are training-compute-optimized.

| Model | Params (B) | Tokens (B) | D/N Ratio | Rel. to Compute-Optimal | Notes |
| --- | --- | --- | --- | --- | --- |
| GPT-3 | 175 | 300 | 1.7 | ~10x under (data) | Pre-Chinchilla paradigm |
| Gopher | 280 | 300 | 1.1 | ~18x under (data) | Pre-Chinchilla paradigm |
| Chinchilla | 70 | 1400 | 20 | Compute-optimal | Benchmark model |
| LLaMA-1 7B | 7 | 1000 | 143 | ~7x over (data) | Inference-optimized |
| LLaMA-2 70B | 70 | 2000 | 28.6 | ~1.4x over (data) | Near compute-optimal |
| Mistral 7B | 7 | 2000 | 286 | ~14x over (data) | Inference-optimized |

The Chinchilla result immediately reframed the field. Models like GPT-4 and subsequent frontier systems shifted to training smaller architectures on vastly more tokens. The practical question changed from 'how large should the model be?' to 'how many tokens can we afford to train on, and what size model is compute-optimal for that data budget?'

- For any fixed compute budget C: train N* = sqrt(C/120) params on D* = 20*N* tokens
- GPT-3 needed ~3T tokens to be compute-optimal at 175B params — it only saw 300B
- Chinchilla 70B matches or beats GPT-3 175B at 4x fewer parameters and same compute
- Post-Chinchilla models (LLaMA, Falcon, Mistral) intentionally over-train for inference savings
- Optimal allocation depends on inference cost: if serving at scale, smaller models are better

> **Info**: Chinchilla's 20:1 token-to-parameter ratio assumes training is done once for deployment — if you plan to serve a model at scale, training smaller models on more data reduces inference cost per query while matching the same compute budget.

## Limitations and Caveats

The Chinchilla results have important scope limitations. First, the optimal D/N ratio assumes all training compute is the constraint — if inference cost dominates (millions of queries per day), a smaller model trained on far more tokens is often better. Second, the fitted constants (A, B, alpha, beta) were measured on The Pile and may not transfer to domain-specific corpora such as code or math. Third, the approximation C = 6ND ignores attention complexity, embedding tables, and layer normalization. Fourth, the scaling laws describe pre-training only — instruction tuning, RLHF, and DPO post-training cost is not captured. Fifth, diminishing returns from data quality and deduplication mean that 1T tokens of web text may be equivalent to far fewer high-quality tokens.

