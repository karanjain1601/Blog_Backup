---
title: "Transformer Scaling Laws — Chinchilla and Compute-Optimal Training"
slug: "transformer-scaling-laws"
description: "Power-law relationships between model size, dataset size, and loss; Kaplan vs Chinchilla optimal training recipes; estimating FLOPs; and implications for training budget allocation."
tags: ["deep-learning", "transformers", "attention-efficiency"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"Neural language model performance follows remarkably smooth power laws in model size, dataset size, and compute budget. These scaling laws — first characterized systematically by Kaplan et al. (2020) and then corrected by Hoffmann et al. (2022, Chinchilla) — provide a principled framework for deciding how large to make a model and how many tokens to train on for a given compute budget. Understanding these relationships has reshaped how organizations allocate training resources and has driven the shift toward training smaller models on more data."},{"type":"heading","level":2,"content":"Kaplan et al. Power Laws (2020)"},{"type":"text","content":"Kaplan et al. found that language model loss follows power laws in isolation: L(N) ∝ N^{-α_N} with α_N ≈ 0.076 (parameters), L(D) ∝ D^{-α_D} with α_D ≈ 0.095 (tokens), and L(C) ∝ C^{-α_C} (compute). Key finding: for a fixed compute budget, most budget should go to model size (N), with relatively few training tokens — models were significantly undertrained. This led to GPT-3 (175B) being trained on only ~300B tokens, a ratio of ~1.7 tokens per parameter, well below what Chinchilla later identified as optimal."},{"type":"code","language":"python","content":"import numpy as np\nfrom scipy.optimize import curve_fit\nimport warnings\nwarnings.filterwarnings(\u0027ignore\u0027)\n\ndef power_law(x, a, alpha):\n    \"\"\"L = a * x^(-alpha)\"\"\"\n    return a * x ** (-alpha)\n\n# Simulate loss measurements across model sizes (illustrative)\nnp.random.seed(42)\nN_values = np.array([1e7, 3e7, 1e8, 3e8, 1e9, 3e9, 1e10])\n# True relationship: L(N) ~ 2.0 * N^{-0.076} + noise\ntrue_alpha, true_a = 0.076, 2.0\nnoise = np.random.normal(0, 0.005, len(N_values))\nL_values = true_a * N_values ** (-true_alpha) + noise\n\n# Fit power law\npopt, _ = curve_fit(power_law, N_values, L_values, p0=[2.0, 0.08])\na_fit, alpha_fit = popt\nprint(f\u0027Fitted a = {a_fit:.4f}, alpha_N = {alpha_fit:.4f} (true = {true_alpha})\u0027)\nprint()\nprint(f\u0027{\u0027Params\u0027:\u003e12} {\u0027True Loss\u0027:\u003e10} {\u0027Pred Loss\u0027:\u003e10}\u0027)\nfor N, L in zip(N_values, L_values):\n    pred = power_law(N, a_fit, alpha_fit)\n    print(f\u0027{N:\u003e12.1e} {L:\u003e10.4f} {pred:\u003e10.4f}\u0027)"},{"type":"heading","level":2,"content":"Chinchilla: Compute-Optimal Training (2022)"},{"type":"text","content":"Hoffmann et al. (2022) ran a rigorous ablation: train many models of different sizes on different token counts, all at the same compute budget. Finding: the compute-optimal model size scales as N_opt ∝ C^{0.5} and the optimal token count scales as D_opt ∝ C^{0.5} — both should scale equally with compute. The ratio is approximately 20 tokens per parameter for compute-optimal training. This showed that GPT-3 (175B on 300B tokens ≈ 1.7 tok/param) was severely undertrained. The 70B Chinchilla model trained on 1.4T tokens (20 tok/param) outperformed 280B Gopher at the same training compute."},{"type":"code","language":"python","content":"import numpy as np\n\ndef chinchilla_optimal(compute_budget_flops, tokens_per_param=20.0):\n    \"\"\"\n    Given a compute budget C (FLOPs), return optimal N and D.\n    Approximation: C = 6*N*D =\u003e N_opt = sqrt(C / (6 * tokens_per_param))\n    \"\"\"\n    N_opt = np.sqrt(compute_budget_flops / (6.0 * tokens_per_param))\n    D_opt = tokens_per_param * N_opt\n    return int(N_opt), int(D_opt)\n\n# Compute budgets in FLOPs (approximate for well-known models)\nmodels = {\n    \u0027GPT-3 (175B)\u0027:  (175e9,  300e9,   6 * 175e9 * 300e9),\n    \u0027Gopher (280B)\u0027: (280e9,  300e9,   6 * 280e9 * 300e9),\n    \u0027Chinchilla\u0027:    (70e9,   1.4e12,  6 * 70e9  * 1.4e12),\n    \u0027LLaMA-1 (65B)\u0027: (65e9,   1.4e12,  6 * 65e9  * 1.4e12),\n}\n\nprint(f\u0027{\u0027Model\u0027:\u003c20} {\u0027Actual N\u0027:\u003e12} {\u0027Actual D\u0027:\u003e12} {\u0027Chinchilla N_opt\u0027:\u003e16} {\u0027Chinchilla D_opt\u0027:\u003e16}\u0027)\nfor name, (N, D, C) in models.items():\n    n_opt, d_opt = chinchilla_optimal(C)\n    ratio = D / N\n    print(f\u0027{name:\u003c20} {N/1e9:\u003e10.0f}B {D/1e9:\u003e10.0f}B {n_opt/1e9:\u003e14.0f}B {d_opt/1e9:\u003e14.0f}B  (actual {ratio:.0f} tok/param)\u0027)"},{"type":"heading","level":2,"content":"Estimating Training Compute"},{"type":"text","content":"The rule of thumb for transformer training FLOPs is C ≈ 6ND, where N is the number of non-embedding parameters and D is the number of training tokens. The factor 6 accounts for: 2 for the forward pass (one multiply-add = 2 FLOPs per weight), and 4 for the backward pass (which requires storing activations and computing gradients for both weights and inputs, roughly 2× the forward pass FLOPs). This estimate is accurate to within ~10% for standard transformer architectures and ignores attention\u0027s O(T²) cost (often smaller than FFN for typical sequence lengths)."},{"type":"code","language":"python","content":"import numpy as np\n\ndef estimate_transformer_params(vocab_size, d_model, n_layers, n_heads,\n                                 ffn_mult=4, include_embeddings=True):\n    \"\"\"Estimate non-embedding transformer parameters.\"\"\"\n    # Attention: Q, K, V projections + output projection\n    attn_params = 4 * d_model * d_model  # per layer\n    # FFN: two linear layers with expansion factor ffn_mult\n    ffn_params = 2 * d_model * d_model * ffn_mult  # per layer\n    # LayerNorm: 2 * d_model per norm, 2 norms per block + 1 final\n    ln_params = (2 * n_layers + 1) * 2 * d_model\n    non_emb = n_layers * (attn_params + ffn_params) + ln_params\n    emb = vocab_size * d_model  # token embedding (tied with output)\n    return non_emb, non_emb + emb if include_embeddings else non_emb\n\nconfigs = [\n    (\u0027GPT-2 small\u0027,  50257, 768,   12, 12),\n    (\u0027GPT-2 XL\u0027,     50257, 1600,  48, 25),\n    (\u0027GPT-3\u0027,        50257, 12288, 96, 96),\n]\nprint(f\u0027{\u0027Model\u0027:\u003c15} {\u0027Non-emb N\u0027:\u003e12} {\u0027Total N\u0027:\u003e12} {\u0027C @ 300B tok\u0027:\u003e15} {\u0027C @ 1.4T tok\u0027:\u003e15}\u0027)\nfor name, V, d, L, H in configs:\n    non_emb, total = estimate_transformer_params(V, d, L, H)\n    c_300b = 6 * non_emb * 300e9\n    c_14t  = 6 * non_emb * 1.4e12\n    print(f\u0027{name:\u003c15} {non_emb/1e9:\u003e10.2f}B {total/1e9:\u003e10.2f}B {c_300b:.2e} {c_14t:.2e}\u0027)"},{"type":"heading","level":2,"content":"Scaling Law Extrapolation"},{"type":"text","content":"A key practical use of scaling laws is predicting the performance of a large model by running cheap small-model experiments. If loss follows L(N) = aN^{-α}, you can fit α and a from several small runs (1M–1B parameters) and extrapolate to 10B+. Reliability improves when experiments are run at the same token-to-parameter ratio as the target run. The IsoFLOP method — run multiple models at the same compute budget with varying sizes — is more accurate because it directly fits the Chinchilla two-variable curve."},{"type":"code","language":"python","content":"import numpy as np\nfrom scipy.optimize import curve_fit\n\nnp.random.seed(7)\n\n# Small model experiments (simulated)\nN_small = np.array([1e6, 3e6, 1e7, 3e7, 1e8, 3e8])\nalpha_true, a_true, L_irred = 0.076, 406.4, 1.69\n# Chinchilla-style: L(N) = (N_c / N)^alpha + L_irred\nN_c = 8.8e13\nL_small = (N_c / N_small) ** alpha_true + L_irred\nL_noisy = L_small + np.random.normal(0, 0.01, len(N_small))\n\ndef loss_model(N, L0, N_c, alpha):\n    return L0 + (N_c / N) ** alpha\n\npopt, _ = curve_fit(loss_model, N_small, L_noisy,\n                    p0=[1.7, 8e13, 0.076], maxfev=10000)\nL0_fit, Nc_fit, alpha_fit = popt\n\n# Extrapolate to large models\nN_targets = [1e9, 1e10, 1e11, 1e12]\nprint(f\u0027Fitted: L0={L0_fit:.4f}, N_c={Nc_fit:.2e}, alpha={alpha_fit:.4f}\u0027)\nprint(f\u0027\\n{\u0027Target N\u0027:\u003e12} {\u0027Pred Loss\u0027:\u003e10} {\u0027True Loss\u0027:\u003e10}\u0027)\nfor N in N_targets:\n    pred = loss_model(N, L0_fit, Nc_fit, alpha_fit)\n    true = loss_model(N, L_irred, N_c, alpha_true)\n    print(f\u0027{N:\u003e12.0e} {pred:\u003e10.4f} {true:\u003e10.4f}\u0027)"},{"type":"heading","level":2,"content":"Kaplan vs Chinchilla Comparison"},{"type":"table","headers":["Aspect","Kaplan et al. 2020","Chinchilla 2022"],"rows":[["Optimal N given C","N ∝ C^0.73 — scale model fast","N ∝ C^0.5 — scale model and data equally"],["Optimal tok/param ratio","~1.7 tokens per parameter","~20 tokens per parameter"],["Training duration","Short training, large model","Longer training, smaller model"],["Key prediction","GPT-3 style scaling is efficient","GPT-3 was severely undertrained"],["Validated by","GPT-3 training runs","Training Chinchilla-70B \u003e Gopher-280B"],["Implication for inference","Not considered — focus on pretraining","Smaller model = faster, cheaper inference"]]},{"type":"heading","level":2,"content":"Implications for Model Training Decisions"},{"type":"text","content":"Chinchilla optimal training maximizes perplexity at a fixed compute budget during training. But inference cost often matters more than training cost in production — a 7B model runs on a single GPU while 70B requires multi-GPU. LLaMA-1 explicitly adopted an inference-optimal strategy: train 65B and 7B models on 1T-1.4T tokens (exceeding Chinchilla optimal for these sizes), accepting slightly higher training compute in exchange for better inference quality per parameter. LLaMA-2 (2T tokens) and subsequent models pushed this further."},{"type":"callout","variant":"warning","title":"Scaling Laws Are Not Universal","content":"Published scaling laws are fit to specific architecture families, tokenizers, and data distributions. Exponents vary across studies (α_N ranges from 0.05 to 0.12 in different papers). Architectural changes (MoE, state-space models, better data curation) shift the curves. Always run your own small-scale isoFLOP experiments when making training decisions for a new architecture or data mixture."},{"type":"list","ordered":false,"items":["Compute budget C ≈ 6ND is the standard estimate; more precise formulas account for attention and embedding FLOPs.","Chinchilla ratio: 20 tok/param is optimal for minimizing loss at fixed pretraining compute.","Inference-optimal models trade extra training compute for smaller, faster-at-inference models.","Data quality matters: Chinchilla and LLaMA show that high-quality data is worth more than raw token counts.","Emergent abilities appear discontinuously at scale and are not predicted by smooth power-law extrapolation."]},{"type":"heading","level":2,"content":"LLaMA and Inference-Optimal Models"},{"type":"text","content":"LLaMA\u0027s training philosophy operationalized the inference-optimal insight: rather than training the largest compute-optimal model for a single run, train smaller models for far longer on higher-quality data. LLaMA-1-7B was trained on 1T tokens (Chinchilla-optimal for ~50B, so overtrained by 20×), yielding a model that matches or exceeds GPT-3-175B on many benchmarks while being 25× smaller. LLaMA-2 pushed to 2T tokens; LLaMA-3 to 15T tokens — far past Chinchilla optimal for their sizes. The community has adopted this pattern: train 7B–70B models on 1–15T tokens, accepting higher pretraining cost for dramatic inference savings."},{"type":"divider"}]"
---
# Transformer Scaling Laws — Chinchilla and Compute-Optimal Training

Neural language model performance follows remarkably smooth power laws in model size, dataset size, and compute budget. These scaling laws — first characterized systematically by Kaplan et al. (2020) and then corrected by Hoffmann et al. (2022, Chinchilla) — provide a principled framework for deciding how large to make a model and how many tokens to train on for a given compute budget. Understanding these relationships has reshaped how organizations allocate training resources and has driven the shift toward training smaller models on more data.

## Kaplan et al. Power Laws (2020)

Kaplan et al. found that language model loss follows power laws in isolation: L(N) ∝ N^{-α_N} with α_N ≈ 0.076 (parameters), L(D) ∝ D^{-α_D} with α_D ≈ 0.095 (tokens), and L(C) ∝ C^{-α_C} (compute). Key finding: for a fixed compute budget, most budget should go to model size (N), with relatively few training tokens — models were significantly undertrained. This led to GPT-3 (175B) being trained on only ~300B tokens, a ratio of ~1.7 tokens per parameter, well below what Chinchilla later identified as optimal.

```python
import numpy as np
from scipy.optimize import curve_fit
import warnings
warnings.filterwarnings('ignore')

def power_law(x, a, alpha):
    """L = a * x^(-alpha)"""
    return a * x ** (-alpha)

# Simulate loss measurements across model sizes (illustrative)
np.random.seed(42)
N_values = np.array([1e7, 3e7, 1e8, 3e8, 1e9, 3e9, 1e10])
# True relationship: L(N) ~ 2.0 * N^{-0.076} + noise
true_alpha, true_a = 0.076, 2.0
noise = np.random.normal(0, 0.005, len(N_values))
L_values = true_a * N_values ** (-true_alpha) + noise

# Fit power law
popt, _ = curve_fit(power_law, N_values, L_values, p0=[2.0, 0.08])
a_fit, alpha_fit = popt
print(f'Fitted a = {a_fit:.4f}, alpha_N = {alpha_fit:.4f} (true = {true_alpha})')
print()
print(f'{'Params':>12} {'True Loss':>10} {'Pred Loss':>10}')
for N, L in zip(N_values, L_values):
    pred = power_law(N, a_fit, alpha_fit)
    print(f'{N:>12.1e} {L:>10.4f} {pred:>10.4f}')
```

## Chinchilla: Compute-Optimal Training (2022)

Hoffmann et al. (2022) ran a rigorous ablation: train many models of different sizes on different token counts, all at the same compute budget. Finding: the compute-optimal model size scales as N_opt ∝ C^{0.5} and the optimal token count scales as D_opt ∝ C^{0.5} — both should scale equally with compute. The ratio is approximately 20 tokens per parameter for compute-optimal training. This showed that GPT-3 (175B on 300B tokens ≈ 1.7 tok/param) was severely undertrained. The 70B Chinchilla model trained on 1.4T tokens (20 tok/param) outperformed 280B Gopher at the same training compute.

```python
import numpy as np

def chinchilla_optimal(compute_budget_flops, tokens_per_param=20.0):
    """
    Given a compute budget C (FLOPs), return optimal N and D.
    Approximation: C = 6*N*D => N_opt = sqrt(C / (6 * tokens_per_param))
    """
    N_opt = np.sqrt(compute_budget_flops / (6.0 * tokens_per_param))
    D_opt = tokens_per_param * N_opt
    return int(N_opt), int(D_opt)

# Compute budgets in FLOPs (approximate for well-known models)
models = {
    'GPT-3 (175B)':  (175e9,  300e9,   6 * 175e9 * 300e9),
    'Gopher (280B)': (280e9,  300e9,   6 * 280e9 * 300e9),
    'Chinchilla':    (70e9,   1.4e12,  6 * 70e9  * 1.4e12),
    'LLaMA-1 (65B)': (65e9,   1.4e12,  6 * 65e9  * 1.4e12),
}

print(f'{'Model':<20} {'Actual N':>12} {'Actual D':>12} {'Chinchilla N_opt':>16} {'Chinchilla D_opt':>16}')
for name, (N, D, C) in models.items():
    n_opt, d_opt = chinchilla_optimal(C)
    ratio = D / N
    print(f'{name:<20} {N/1e9:>10.0f}B {D/1e9:>10.0f}B {n_opt/1e9:>14.0f}B {d_opt/1e9:>14.0f}B  (actual {ratio:.0f} tok/param)')
```

## Estimating Training Compute

The rule of thumb for transformer training FLOPs is C ≈ 6ND, where N is the number of non-embedding parameters and D is the number of training tokens. The factor 6 accounts for: 2 for the forward pass (one multiply-add = 2 FLOPs per weight), and 4 for the backward pass (which requires storing activations and computing gradients for both weights and inputs, roughly 2× the forward pass FLOPs). This estimate is accurate to within ~10% for standard transformer architectures and ignores attention's O(T²) cost (often smaller than FFN for typical sequence lengths).

```python
import numpy as np

def estimate_transformer_params(vocab_size, d_model, n_layers, n_heads,
                                 ffn_mult=4, include_embeddings=True):
    """Estimate non-embedding transformer parameters."""
    # Attention: Q, K, V projections + output projection
    attn_params = 4 * d_model * d_model  # per layer
    # FFN: two linear layers with expansion factor ffn_mult
    ffn_params = 2 * d_model * d_model * ffn_mult  # per layer
    # LayerNorm: 2 * d_model per norm, 2 norms per block + 1 final
    ln_params = (2 * n_layers + 1) * 2 * d_model
    non_emb = n_layers * (attn_params + ffn_params) + ln_params
    emb = vocab_size * d_model  # token embedding (tied with output)
    return non_emb, non_emb + emb if include_embeddings else non_emb

configs = [
    ('GPT-2 small',  50257, 768,   12, 12),
    ('GPT-2 XL',     50257, 1600,  48, 25),
    ('GPT-3',        50257, 12288, 96, 96),
]
print(f'{'Model':<15} {'Non-emb N':>12} {'Total N':>12} {'C @ 300B tok':>15} {'C @ 1.4T tok':>15}')
for name, V, d, L, H in configs:
    non_emb, total = estimate_transformer_params(V, d, L, H)
    c_300b = 6 * non_emb * 300e9
    c_14t  = 6 * non_emb * 1.4e12
    print(f'{name:<15} {non_emb/1e9:>10.2f}B {total/1e9:>10.2f}B {c_300b:.2e} {c_14t:.2e}')
```

## Scaling Law Extrapolation

A key practical use of scaling laws is predicting the performance of a large model by running cheap small-model experiments. If loss follows L(N) = aN^{-α}, you can fit α and a from several small runs (1M–1B parameters) and extrapolate to 10B+. Reliability improves when experiments are run at the same token-to-parameter ratio as the target run. The IsoFLOP method — run multiple models at the same compute budget with varying sizes — is more accurate because it directly fits the Chinchilla two-variable curve.

```python
import numpy as np
from scipy.optimize import curve_fit

np.random.seed(7)

# Small model experiments (simulated)
N_small = np.array([1e6, 3e6, 1e7, 3e7, 1e8, 3e8])
alpha_true, a_true, L_irred = 0.076, 406.4, 1.69
# Chinchilla-style: L(N) = (N_c / N)^alpha + L_irred
N_c = 8.8e13
L_small = (N_c / N_small) ** alpha_true + L_irred
L_noisy = L_small + np.random.normal(0, 0.01, len(N_small))

def loss_model(N, L0, N_c, alpha):
    return L0 + (N_c / N) ** alpha

popt, _ = curve_fit(loss_model, N_small, L_noisy,
                    p0=[1.7, 8e13, 0.076], maxfev=10000)
L0_fit, Nc_fit, alpha_fit = popt

# Extrapolate to large models
N_targets = [1e9, 1e10, 1e11, 1e12]
print(f'Fitted: L0={L0_fit:.4f}, N_c={Nc_fit:.2e}, alpha={alpha_fit:.4f}')
print(f'\n{'Target N':>12} {'Pred Loss':>10} {'True Loss':>10}')
for N in N_targets:
    pred = loss_model(N, L0_fit, Nc_fit, alpha_fit)
    true = loss_model(N, L_irred, N_c, alpha_true)
    print(f'{N:>12.0e} {pred:>10.4f} {true:>10.4f}')
```

## Kaplan vs Chinchilla Comparison

| Aspect | Kaplan et al. 2020 | Chinchilla 2022 |
| --- | --- | --- |
| Optimal N given C | N ∝ C^0.73 — scale model fast | N ∝ C^0.5 — scale model and data equally |
| Optimal tok/param ratio | ~1.7 tokens per parameter | ~20 tokens per parameter |
| Training duration | Short training, large model | Longer training, smaller model |
| Key prediction | GPT-3 style scaling is efficient | GPT-3 was severely undertrained |
| Validated by | GPT-3 training runs | Training Chinchilla-70B > Gopher-280B |
| Implication for inference | Not considered — focus on pretraining | Smaller model = faster, cheaper inference |

## Implications for Model Training Decisions

Chinchilla optimal training maximizes perplexity at a fixed compute budget during training. But inference cost often matters more than training cost in production — a 7B model runs on a single GPU while 70B requires multi-GPU. LLaMA-1 explicitly adopted an inference-optimal strategy: train 65B and 7B models on 1T-1.4T tokens (exceeding Chinchilla optimal for these sizes), accepting slightly higher training compute in exchange for better inference quality per parameter. LLaMA-2 (2T tokens) and subsequent models pushed this further.

> **Scaling Laws Are Not Universal**: Published scaling laws are fit to specific architecture families, tokenizers, and data distributions. Exponents vary across studies (α_N ranges from 0.05 to 0.12 in different papers). Architectural changes (MoE, state-space models, better data curation) shift the curves. Always run your own small-scale isoFLOP experiments when making training decisions for a new architecture or data mixture.

- Compute budget C ≈ 6ND is the standard estimate; more precise formulas account for attention and embedding FLOPs.
- Chinchilla ratio: 20 tok/param is optimal for minimizing loss at fixed pretraining compute.
- Inference-optimal models trade extra training compute for smaller, faster-at-inference models.
- Data quality matters: Chinchilla and LLaMA show that high-quality data is worth more than raw token counts.
- Emergent abilities appear discontinuously at scale and are not predicted by smooth power-law extrapolation.

## LLaMA and Inference-Optimal Models

LLaMA's training philosophy operationalized the inference-optimal insight: rather than training the largest compute-optimal model for a single run, train smaller models for far longer on higher-quality data. LLaMA-1-7B was trained on 1T tokens (Chinchilla-optimal for ~50B, so overtrained by 20×), yielding a model that matches or exceeds GPT-3-175B on many benchmarks while being 25× smaller. LLaMA-2 pushed to 2T tokens; LLaMA-3 to 15T tokens — far past Chinchilla optimal for their sizes. The community has adopted this pattern: train 7B–70B models on 1–15T tokens, accepting higher pretraining cost for dramatic inference savings.

---

