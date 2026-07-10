---
title: "Beyond Chinchilla — Inference-Aware Training and the LLaMA Efficiency Insight"
slug: "beyond-chinchilla"
description: "Chinchilla optimizes training compute but ignores inference cost. When serving at scale, smaller models trained on far more tokens dominate — the insight behind LLaMA-1, LLaMA-3, and the broader shift to inference-optimal training."
tags: ["deep-learning", "llm"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"Chinchilla answers the question: given a fixed training compute budget C, how should you split it between model size N and training tokens D? The answer — N* proportional to C^0.5, D* = 20*N* — minimizes the final training loss. But this objective ignores what happens after training. At deployment scale, inference cost dwarfs training cost: a model serving 1 million queries per day runs more total FLOPs in a week of serving than were spent training it. The LLaMA insight (Touvron et al., 2023) was to optimize for inference efficiency by training smaller models on far more tokens than Chinchilla recommends."},{"type":"heading","level":2,"content":"Why Chinchilla Misses Half the Picture"},{"type":"text","content":"The total cost of a deployed language model has two components: C_total = C_train + C_inf, where C_train = 6*N*D (training cost) and C_inf = 2*N*Q (inference cost, Q = total queries served). For a 70B model serving 1M queries per day, the daily inference cost is 2 * 70e9 * 1e6 = 1.4e17 FLOPs — equivalent to training a 1B parameter model for 700 billion tokens. After one year of deployment, inference has consumed 5e19 FLOPs — likely exceeding the training cost. A 7B model trained 10x more would serve each query at 10x lower FLOP cost, dramatically reducing C_inf while achieving comparable quality."},{"type":"list","ordered":false,"items":["C_train = 6*N*D: one-time cost, paid once before deployment","C_inf = 2*N per query: scales linearly with total queries served, unbounded","At 1M queries/day a 70B model spends ~5e19 FLOPs/year on inference alone","A 7B model at same quality costs 10x less per query: 10x better inference economics","LLaMA insight: train 7B on 1T tokens instead of 50B on 100B tokens for same training C","LLaMA-3.1 8B trained on 15T tokens: 93x Chinchilla-optimal, optimized for serving"]},{"type":"heading","level":2,"content":"Code 1 — Inference-Optimal Allocation"},{"type":"code","language":"python","content":"import numpy as np\nfrom scipy.optimize import minimize_scalar\n\nE_CONST, A_CONST, B_CONST, ALPHA, BETA = 1.69, 406.4, 410.7, 0.34, 0.28\n\ndef tokens_for_target_loss(N, target_loss=2.5):\n    \u0027\u0027\u0027Find D such that L(N, D) = target_loss using Chinchilla formula.\u0027\u0027\u0027\n    residual = target_loss - E_CONST - A_CONST * N ** (-ALPHA)\n    if residual \u003c= 0:\n        return np.inf  # model too small to reach target regardless of data\n    return (B_CONST / residual) ** (1.0 / BETA)\n\ndef total_cost(N, Q_total, target_loss=2.5):\n    \u0027\u0027\u0027C_total = 6*N*D (training) + 2*N*Q (inference FLOPs).\u0027\u0027\u0027\n    D = tokens_for_target_loss(N, target_loss)\n    if np.isinf(D):\n        return np.inf\n    return 6.0 * N * D + 2.0 * N * Q_total\n\nN_range = np.logspace(8, 12, 300)  # 100M to 1T parameters\n\nquery_scenarios = [\n    (\u00271K queries (dev)\u0027,   1e3),\n    (\u00271M queries (prod)\u0027,  1e6),\n    (\u00271B queries (scale)\u0027, 1e9),\n]\n\nprint(\u0027{:\u003c22} {:\u003e14} {:\u003e20} {:\u003e8}\u0027.format(\u0027Query Scale\u0027, \u0027Optimal N* (B)\u0027, \u0027Optimal D* (B tokens)\u0027, \u0027D/N\u0027))\nprint(\u0027-\u0027 * 68)\nfor label, Q in query_scenarios:\n    costs = np.array([total_cost(N, Q) for N in N_range])\n    valid = np.isfinite(costs)\n    best_i = np.argmin(np.where(valid, costs, np.inf))\n    N_best = N_range[best_i]\n    D_best = tokens_for_target_loss(N_best)\n    print(\u0027{:\u003c22} {:\u003e14.2f} {:\u003e20.1f} {:\u003e8.1f}\u0027.format(label, N_best/1e9, D_best/1e9, D_best/N_best))"},{"type":"heading","level":2,"content":"The LLaMA Insight"},{"type":"text","content":"Touvron et al. (2023) observed that Chinchilla optimizes training compute but practitioners care more about inference cost at a target quality level. LLaMA-1 7B was trained on 1T tokens — approximately 7x the Chinchilla-optimal token count for a 7B model (which is ~140B tokens). This means LLaMA-1 7B achieves roughly the same quality as the Chinchilla-optimal model for a 50B parameter system, but runs inference at 7x lower cost per query. The model took longer to train (7x more tokens), but that one-time cost pays off after only a relatively small number of queries served."},{"type":"list","ordered":false,"items":["LLaMA-1 7B: 1T tokens (Chinchilla-optimal for 50B model) — 143 tokens/param","LLaMA-3.1 8B: 15T tokens — approximately 1,875 tokens/param, 93x Chinchilla-optimal","LLaMA-3.1 70B: 15T tokens — approximately 214 tokens/param, 10.7x Chinchilla-optimal","Phi-3 Mini (3.8B, 3.3T tokens): 868 tokens/param — extreme data-to-param ratio","Quality of over-trained small model often matches quality of Chinchilla-optimal larger model","Break-even queries: (C_over_train - C_chin_train) / (C_inf_large - C_inf_small)"]},{"type":"heading","level":2,"content":"Code 2 — Cost Comparison at Deployment Scale"},{"type":"code","language":"python","content":"import numpy as np\nimport matplotlib.pyplot as plt\n\nE_CONST, A_CONST, B_CONST, ALPHA, BETA = 1.69, 406.4, 410.7, 0.34, 0.28\n\ndef tokens_for_target(N, L_target=2.5):\n    \u0027\u0027\u0027Tokens needed to reach L_target with N parameters.\u0027\u0027\u0027\n    res = L_target - E_CONST - A_CONST * N ** (-ALPHA)\n    return (B_CONST / res) ** (1.0 / BETA) if res \u003e 0 else np.inf\n\nN_range   = np.logspace(8, 12, 150)  # 100M to 1T params\nscenarios = [\n    (\u00271K queries\u0027,  1e3,  \u0027#3498db\u0027),\n    (\u00271M queries\u0027,  1e6,  \u0027#e67e22\u0027),\n    (\u00271B queries\u0027,  1e9,  \u0027#e74c3c\u0027),\n]\n\nfig, ax = plt.subplots(figsize=(10, 6))\nfor label, Q, color in scenarios:\n    costs = []\n    for N in N_range:\n        D = tokens_for_target(N)\n        costs.append(6.0 * N * D + 2.0 * N * Q if np.isfinite(D) else np.inf)\n    costs = np.array(costs)\n    valid = np.isfinite(costs)\n    ax.semilogy(N_range[valid] / 1e9, costs[valid], color=color, lw=2, label=label)\n    best_i = int(np.argmin(np.where(valid, costs, np.inf)))\n    ax.axvline(N_range[best_i] / 1e9, color=color, ls=\u0027:\u0027, alpha=0.7)\n\nax.set_xlabel(\u0027Model Size N (billions of parameters)\u0027, fontsize=12)\nax.set_ylabel(\u0027Total Cost (train + inference FLOPs)\u0027, fontsize=12)\nax.set_title(\u0027Inference-Aware Total Cost vs Model Size at Different Deployment Scales\u0027, fontsize=11)\nax.legend(fontsize=11)\nax.grid(True, alpha=0.3)\nplt.tight_layout()\nplt.savefig(\u0027inference_cost_comparison.png\u0027, dpi=150)\nplt.show()\nprint(\u0027Dotted vertical lines mark inference-optimal N* for each deployment scale.\u0027)"},{"type":"heading","level":2,"content":"Multi-Epoch Training Effects"},{"type":"text","content":"When a model is trained beyond the Chinchilla-optimal token count, it will inevitably revisit tokens if the unique data corpus is smaller than D*. Multiple epochs over the same data exhibit diminishing returns: the effective data contribution from repeated tokens scales sub-linearly (roughly as epochs^0.5 empirically). At very high epoch counts — say, 100 passes over the same data — loss degradation can become significant, as the model begins to memorize rather than generalize. The practical mitigation is aggressive data curation, deduplication, and mixing in synthetic data (as with Phi-3 and related models) to maintain data diversity even at high token counts."},{"type":"heading","level":2,"content":"Code 3 — Multi-Epoch Training Degradation"},{"type":"code","language":"python","content":"import numpy as np\nimport matplotlib.pyplot as plt\n\ndef loss_with_repetition(N, D_unique, epochs,\n                         E=1.69, A=406.4, alpha=0.34, B=410.7, beta=0.28):\n    \u0027\u0027\u0027Model loss under data repetition: D_effective = D_unique * epochs^0.5\n    (sub-linear effective data gain from repeated tokens).\u0027\u0027\u0027\n    D_eff = D_unique * (epochs ** 0.5)\n    return E + A * N ** (-alpha) + B * D_eff ** (-beta)\n\nN        = 7e9    # 7B parameter model\nD_unique = 100e9  # 100B unique high-quality tokens\nepochs   = np.linspace(1.0, 25.0, 250)\nlosses   = [loss_with_repetition(N, D_unique, e) for e in epochs]\n\nchinchilla_D     = 20.0 * N         # 140B = Chinchilla-optimal\nchinchilla_epoch = chinchilla_D / D_unique   # 1.4 epochs\n\nfig, ax = plt.subplots(figsize=(9, 5))\nax.plot(epochs, losses, \u0027b-\u0027, lw=2, label=\u0027Test loss with data repetition\u0027)\nax.axvline(chinchilla_epoch, color=\u0027g\u0027, ls=\u0027--\u0027, lw=2,\n           label=\u0027Chinchilla-optimal ({:.1f} epochs)\u0027.format(chinchilla_epoch))\nax.axhline(min(losses), color=\u0027gray\u0027, ls=\u0027:\u0027, lw=1.5, label=\u0027Best achievable loss\u0027)\nax.set_xlabel(\u0027Training Epochs Over Unique Data\u0027, fontsize=12)\nax.set_ylabel(\u0027Predicted Test Loss (nats)\u0027, fontsize=12)\nax.set_title(\u0027Multi-Epoch Training: Diminishing Returns Past Chinchilla-Optimal\u0027, fontsize=12)\nax.legend(fontsize=11)\nax.grid(True, alpha=0.3)\nplt.tight_layout()\nplt.savefig(\u0027multi_epoch_degradation.png\u0027, dpi=150)\nplt.show()"},{"type":"heading","level":2,"content":"Code 4 — LLaMA vs Chinchilla-Optimal Comparison"},{"type":"code","language":"python","content":"import numpy as np\n\ndef chinchilla_optimal_tokens(N):\n    \u0027\u0027\u0027Chinchilla-optimal token count for N parameters: D* = 20 * N.\u0027\u0027\u0027\n    return 20.0 * N\n\n# Published model specs: (name, N_params, D_tokens_actual)\npublished_models = [\n    (\u0027LLaMA-1 7B\u0027,    7e9,    1.0e12),\n    (\u0027LLaMA-3.1 8B\u0027,  8e9,   15.0e12),\n    (\u0027LLaMA-2 70B\u0027,  70e9,    2.0e12),\n    (\u0027LLaMA-3.1 70B\u0027,70e9,   15.0e12),\n    (\u0027Mistral 7B\u0027,    7e9,    2.0e12),\n    (\u0027Phi-3 Mini\u0027,    3.8e9,  3.3e12),\n]\n\nprint(\u0027{:\u003c18} {:\u003e7} {:\u003e13} {:\u003e18} {:\u003e12} {:\u003e16}\u0027.format(\n    \u0027Model\u0027, \u0027N (B)\u0027, \u0027D actual (B)\u0027, \u0027D Chinchilla (B)\u0027, \u0027Multiplier\u0027, \u0027C_train (FLOPs)\u0027))\nprint(\u0027-\u0027 * 90)\nfor name, N, D in published_models:\n    D_ch = chinchilla_optimal_tokens(N)\n    mult = D / D_ch\n    C    = 6.0 * N * D\n    print(\u0027{:\u003c18} {:\u003e7.1f} {:\u003e13.1f} {:\u003e18.1f} {:\u003e12.1f}x {:\u003e16.2e}\u0027.format(\n        name, N/1e9, D/1e9, D_ch/1e9, mult, C))\nprint(\u0027\\nModels trained well beyond Chinchilla-optimal are inference-optimized for deployment.\u0027)"},{"type":"text","content":"The table below summarizes the inference-aware picture for notable models — showing how far each deviates from Chinchilla-optimal and what deployment context that choice serves."},{"type":"table","headers":["Model","Params (B)","Tokens (B)","D/N Ratio","Chinchilla Multiplier","Primary Use Case"],"rows":[["LLaMA-3.1 8B","8","15000","1875","93.75x","Edge / on-device inference"],["LLaMA-3.1 70B","70","15000","214","10.7x","High-quality hosted inference"],["Mistral 7B","7","2000","286","14.3x","Efficient local deployment"],["Phi-3 Mini","3.8","3300","868","43.4x","Mobile / edge device inference"],["Gemma 2 9B","9","8000","889","44.4x","Efficient fine-tuning base"]]},{"type":"text","content":"The Sardana / Chinchilla-inf framework (Sardana \u0026 Frankle, 2023) formalizes the inference-aware objective: minimize C_train + lambda * C_inf, where lambda represents the expected total query volume. Solving this modified optimization yields a new optimal N* that is strictly smaller than Chinchilla-optimal N* for any lambda \u003e 0. As lambda grows (more queries expected), the optimal model shrinks and the optimal token count grows. This explains the observed trend: frontier labs are converging on smaller, longer-trained models for public deployment."},{"type":"list","ordered":false,"items":["Sardana objective: minimize 6*N*D + lambda*2*N*Q subject to L(N,D) \u003c= L_target","For lambda = 0 (no inference): recovers Chinchilla-optimal N* and D*","For large lambda: optimal N* shrinks, optimal D* grows proportionally","Break-even: extra training cost / per-query savings = number of queries to recoup","LLaMA-3.1 8B vs 70B: 8B costs ~9x less per query, worth training longer for high-volume APIs","Synthetic data (Phi-3 approach) enables high token counts without web data repetition"]},{"type":"callout","variant":"tip","title":"Tip","content":"If you expect to serve a model for millions of queries, training a 2-4x smaller model on 4-8x more tokens often gives better total cost (train + serve) than the Chinchilla-optimal model — smaller models are dramatically cheaper per inference query."},{"type":"heading","level":2,"content":"The Shifting Frontier"},{"type":"text","content":"The field has moved decisively beyond Chinchilla-optimal training. LLaMA-3.1 8B (15T tokens, 93x Chinchilla-optimal) demonstrates that small models trained extremely long can match much larger Chinchilla-optimal models in quality while running at a fraction of the inference cost. The implication for practitioners: when choosing a base model for fine-tuning or deployment, prefer models that have been over-trained relative to Chinchilla — they will be smaller (cheaper to serve), faster (lower latency), and often comparable in quality to larger Chinchilla-optimal counterparts on standard benchmarks. The compute-optimal question is no longer just about training — it is about the full lifecycle cost from pre-training through millions of inference calls."}]"
---
# Beyond Chinchilla — Inference-Aware Training and the LLaMA Efficiency Insight

Chinchilla answers the question: given a fixed training compute budget C, how should you split it between model size N and training tokens D? The answer — N* proportional to C^0.5, D* = 20*N* — minimizes the final training loss. But this objective ignores what happens after training. At deployment scale, inference cost dwarfs training cost: a model serving 1 million queries per day runs more total FLOPs in a week of serving than were spent training it. The LLaMA insight (Touvron et al., 2023) was to optimize for inference efficiency by training smaller models on far more tokens than Chinchilla recommends.

## Why Chinchilla Misses Half the Picture

The total cost of a deployed language model has two components: C_total = C_train + C_inf, where C_train = 6*N*D (training cost) and C_inf = 2*N*Q (inference cost, Q = total queries served). For a 70B model serving 1M queries per day, the daily inference cost is 2 * 70e9 * 1e6 = 1.4e17 FLOPs — equivalent to training a 1B parameter model for 700 billion tokens. After one year of deployment, inference has consumed 5e19 FLOPs — likely exceeding the training cost. A 7B model trained 10x more would serve each query at 10x lower FLOP cost, dramatically reducing C_inf while achieving comparable quality.

- C_train = 6*N*D: one-time cost, paid once before deployment
- C_inf = 2*N per query: scales linearly with total queries served, unbounded
- At 1M queries/day a 70B model spends ~5e19 FLOPs/year on inference alone
- A 7B model at same quality costs 10x less per query: 10x better inference economics
- LLaMA insight: train 7B on 1T tokens instead of 50B on 100B tokens for same training C
- LLaMA-3.1 8B trained on 15T tokens: 93x Chinchilla-optimal, optimized for serving

## Code 1 — Inference-Optimal Allocation

```python
import numpy as np
from scipy.optimize import minimize_scalar

E_CONST, A_CONST, B_CONST, ALPHA, BETA = 1.69, 406.4, 410.7, 0.34, 0.28

def tokens_for_target_loss(N, target_loss=2.5):
    '''Find D such that L(N, D) = target_loss using Chinchilla formula.'''
    residual = target_loss - E_CONST - A_CONST * N ** (-ALPHA)
    if residual <= 0:
        return np.inf  # model too small to reach target regardless of data
    return (B_CONST / residual) ** (1.0 / BETA)

def total_cost(N, Q_total, target_loss=2.5):
    '''C_total = 6*N*D (training) + 2*N*Q (inference FLOPs).'''
    D = tokens_for_target_loss(N, target_loss)
    if np.isinf(D):
        return np.inf
    return 6.0 * N * D + 2.0 * N * Q_total

N_range = np.logspace(8, 12, 300)  # 100M to 1T parameters

query_scenarios = [
    ('1K queries (dev)',   1e3),
    ('1M queries (prod)',  1e6),
    ('1B queries (scale)', 1e9),
]

print('{:<22} {:>14} {:>20} {:>8}'.format('Query Scale', 'Optimal N* (B)', 'Optimal D* (B tokens)', 'D/N'))
print('-' * 68)
for label, Q in query_scenarios:
    costs = np.array([total_cost(N, Q) for N in N_range])
    valid = np.isfinite(costs)
    best_i = np.argmin(np.where(valid, costs, np.inf))
    N_best = N_range[best_i]
    D_best = tokens_for_target_loss(N_best)
    print('{:<22} {:>14.2f} {:>20.1f} {:>8.1f}'.format(label, N_best/1e9, D_best/1e9, D_best/N_best))
```

## The LLaMA Insight

Touvron et al. (2023) observed that Chinchilla optimizes training compute but practitioners care more about inference cost at a target quality level. LLaMA-1 7B was trained on 1T tokens — approximately 7x the Chinchilla-optimal token count for a 7B model (which is ~140B tokens). This means LLaMA-1 7B achieves roughly the same quality as the Chinchilla-optimal model for a 50B parameter system, but runs inference at 7x lower cost per query. The model took longer to train (7x more tokens), but that one-time cost pays off after only a relatively small number of queries served.

- LLaMA-1 7B: 1T tokens (Chinchilla-optimal for 50B model) — 143 tokens/param
- LLaMA-3.1 8B: 15T tokens — approximately 1,875 tokens/param, 93x Chinchilla-optimal
- LLaMA-3.1 70B: 15T tokens — approximately 214 tokens/param, 10.7x Chinchilla-optimal
- Phi-3 Mini (3.8B, 3.3T tokens): 868 tokens/param — extreme data-to-param ratio
- Quality of over-trained small model often matches quality of Chinchilla-optimal larger model
- Break-even queries: (C_over_train - C_chin_train) / (C_inf_large - C_inf_small)

## Code 2 — Cost Comparison at Deployment Scale

```python
import numpy as np
import matplotlib.pyplot as plt

E_CONST, A_CONST, B_CONST, ALPHA, BETA = 1.69, 406.4, 410.7, 0.34, 0.28

def tokens_for_target(N, L_target=2.5):
    '''Tokens needed to reach L_target with N parameters.'''
    res = L_target - E_CONST - A_CONST * N ** (-ALPHA)
    return (B_CONST / res) ** (1.0 / BETA) if res > 0 else np.inf

N_range   = np.logspace(8, 12, 150)  # 100M to 1T params
scenarios = [
    ('1K queries',  1e3,  '#3498db'),
    ('1M queries',  1e6,  '#e67e22'),
    ('1B queries',  1e9,  '#e74c3c'),
]

fig, ax = plt.subplots(figsize=(10, 6))
for label, Q, color in scenarios:
    costs = []
    for N in N_range:
        D = tokens_for_target(N)
        costs.append(6.0 * N * D + 2.0 * N * Q if np.isfinite(D) else np.inf)
    costs = np.array(costs)
    valid = np.isfinite(costs)
    ax.semilogy(N_range[valid] / 1e9, costs[valid], color=color, lw=2, label=label)
    best_i = int(np.argmin(np.where(valid, costs, np.inf)))
    ax.axvline(N_range[best_i] / 1e9, color=color, ls=':', alpha=0.7)

ax.set_xlabel('Model Size N (billions of parameters)', fontsize=12)
ax.set_ylabel('Total Cost (train + inference FLOPs)', fontsize=12)
ax.set_title('Inference-Aware Total Cost vs Model Size at Different Deployment Scales', fontsize=11)
ax.legend(fontsize=11)
ax.grid(True, alpha=0.3)
plt.tight_layout()
plt.savefig('inference_cost_comparison.png', dpi=150)
plt.show()
print('Dotted vertical lines mark inference-optimal N* for each deployment scale.')
```

## Multi-Epoch Training Effects

When a model is trained beyond the Chinchilla-optimal token count, it will inevitably revisit tokens if the unique data corpus is smaller than D*. Multiple epochs over the same data exhibit diminishing returns: the effective data contribution from repeated tokens scales sub-linearly (roughly as epochs^0.5 empirically). At very high epoch counts — say, 100 passes over the same data — loss degradation can become significant, as the model begins to memorize rather than generalize. The practical mitigation is aggressive data curation, deduplication, and mixing in synthetic data (as with Phi-3 and related models) to maintain data diversity even at high token counts.

## Code 3 — Multi-Epoch Training Degradation

```python
import numpy as np
import matplotlib.pyplot as plt

def loss_with_repetition(N, D_unique, epochs,
                         E=1.69, A=406.4, alpha=0.34, B=410.7, beta=0.28):
    '''Model loss under data repetition: D_effective = D_unique * epochs^0.5
    (sub-linear effective data gain from repeated tokens).'''
    D_eff = D_unique * (epochs ** 0.5)
    return E + A * N ** (-alpha) + B * D_eff ** (-beta)

N        = 7e9    # 7B parameter model
D_unique = 100e9  # 100B unique high-quality tokens
epochs   = np.linspace(1.0, 25.0, 250)
losses   = [loss_with_repetition(N, D_unique, e) for e in epochs]

chinchilla_D     = 20.0 * N         # 140B = Chinchilla-optimal
chinchilla_epoch = chinchilla_D / D_unique   # 1.4 epochs

fig, ax = plt.subplots(figsize=(9, 5))
ax.plot(epochs, losses, 'b-', lw=2, label='Test loss with data repetition')
ax.axvline(chinchilla_epoch, color='g', ls='--', lw=2,
           label='Chinchilla-optimal ({:.1f} epochs)'.format(chinchilla_epoch))
ax.axhline(min(losses), color='gray', ls=':', lw=1.5, label='Best achievable loss')
ax.set_xlabel('Training Epochs Over Unique Data', fontsize=12)
ax.set_ylabel('Predicted Test Loss (nats)', fontsize=12)
ax.set_title('Multi-Epoch Training: Diminishing Returns Past Chinchilla-Optimal', fontsize=12)
ax.legend(fontsize=11)
ax.grid(True, alpha=0.3)
plt.tight_layout()
plt.savefig('multi_epoch_degradation.png', dpi=150)
plt.show()
```

## Code 4 — LLaMA vs Chinchilla-Optimal Comparison

```python
import numpy as np

def chinchilla_optimal_tokens(N):
    '''Chinchilla-optimal token count for N parameters: D* = 20 * N.'''
    return 20.0 * N

# Published model specs: (name, N_params, D_tokens_actual)
published_models = [
    ('LLaMA-1 7B',    7e9,    1.0e12),
    ('LLaMA-3.1 8B',  8e9,   15.0e12),
    ('LLaMA-2 70B',  70e9,    2.0e12),
    ('LLaMA-3.1 70B',70e9,   15.0e12),
    ('Mistral 7B',    7e9,    2.0e12),
    ('Phi-3 Mini',    3.8e9,  3.3e12),
]

print('{:<18} {:>7} {:>13} {:>18} {:>12} {:>16}'.format(
    'Model', 'N (B)', 'D actual (B)', 'D Chinchilla (B)', 'Multiplier', 'C_train (FLOPs)'))
print('-' * 90)
for name, N, D in published_models:
    D_ch = chinchilla_optimal_tokens(N)
    mult = D / D_ch
    C    = 6.0 * N * D
    print('{:<18} {:>7.1f} {:>13.1f} {:>18.1f} {:>12.1f}x {:>16.2e}'.format(
        name, N/1e9, D/1e9, D_ch/1e9, mult, C))
print('\nModels trained well beyond Chinchilla-optimal are inference-optimized for deployment.')
```

The table below summarizes the inference-aware picture for notable models — showing how far each deviates from Chinchilla-optimal and what deployment context that choice serves.

| Model | Params (B) | Tokens (B) | D/N Ratio | Chinchilla Multiplier | Primary Use Case |
| --- | --- | --- | --- | --- | --- |
| LLaMA-3.1 8B | 8 | 15000 | 1875 | 93.75x | Edge / on-device inference |
| LLaMA-3.1 70B | 70 | 15000 | 214 | 10.7x | High-quality hosted inference |
| Mistral 7B | 7 | 2000 | 286 | 14.3x | Efficient local deployment |
| Phi-3 Mini | 3.8 | 3300 | 868 | 43.4x | Mobile / edge device inference |
| Gemma 2 9B | 9 | 8000 | 889 | 44.4x | Efficient fine-tuning base |

The Sardana / Chinchilla-inf framework (Sardana & Frankle, 2023) formalizes the inference-aware objective: minimize C_train + lambda * C_inf, where lambda represents the expected total query volume. Solving this modified optimization yields a new optimal N* that is strictly smaller than Chinchilla-optimal N* for any lambda > 0. As lambda grows (more queries expected), the optimal model shrinks and the optimal token count grows. This explains the observed trend: frontier labs are converging on smaller, longer-trained models for public deployment.

- Sardana objective: minimize 6*N*D + lambda*2*N*Q subject to L(N,D) <= L_target
- For lambda = 0 (no inference): recovers Chinchilla-optimal N* and D*
- For large lambda: optimal N* shrinks, optimal D* grows proportionally
- Break-even: extra training cost / per-query savings = number of queries to recoup
- LLaMA-3.1 8B vs 70B: 8B costs ~9x less per query, worth training longer for high-volume APIs
- Synthetic data (Phi-3 approach) enables high token counts without web data repetition

> **Tip**: If you expect to serve a model for millions of queries, training a 2-4x smaller model on 4-8x more tokens often gives better total cost (train + serve) than the Chinchilla-optimal model — smaller models are dramatically cheaper per inference query.

## The Shifting Frontier

The field has moved decisively beyond Chinchilla-optimal training. LLaMA-3.1 8B (15T tokens, 93x Chinchilla-optimal) demonstrates that small models trained extremely long can match much larger Chinchilla-optimal models in quality while running at a fraction of the inference cost. The implication for practitioners: when choosing a base model for fine-tuning or deployment, prefer models that have been over-trained relative to Chinchilla — they will be smaller (cheaper to serve), faster (lower latency), and often comparable in quality to larger Chinchilla-optimal counterparts on standard benchmarks. The compute-optimal question is no longer just about training — it is about the full lifecycle cost from pre-training through millions of inference calls.

