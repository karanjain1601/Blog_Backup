---
title: "MoE Load Balancing"
slug: "moe-load-balancing"
description: "Techniques to prevent expert collapse where a few experts receive nearly all tokens — covering auxiliary losses, expert choice routing, and Z-loss regularization."
tags: ["deep-learning", "llm"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"In a Mixture-of-Experts model, the router is a small learned network that maps each token to a probability distribution over experts. Left unconstrained, the router quickly collapses: a few experts consistently win the softmax competition, receive the most tokens, accumulate the most gradient signal, and become even better — while the remaining experts starve. This failure mode, called expert collapse, is one of the central training challenges in MoE architectures. Addressing it requires explicit regularisation in the loss function, alternative routing strategies that remove the competitive dynamic, and careful monitoring throughout training. This note covers the full toolkit: auxiliary loss, expert choice routing, Z-loss, and capacity factors."},{"type":"heading","level":2,"content":"Overview"},{"type":"text","content":"Load balancing in MoE training is the problem of ensuring each expert processes approximately 1/N of all tokens throughout training, while still allowing the router to develop meaningful specialisation. Perfect balance (each expert sees exactly 1/N tokens) would require a combinatorial assignment that ignores token-expert affinity; pure affinity routing (each token always goes to its most preferred expert) collapses. Good load balancing methods find a middle ground: they allow the router to prefer certain experts for certain tokens while adding soft regularisation that discourages extreme imbalance. The main approaches are: (1) auxiliary loss on the routing distribution, (2) expert choice routing where experts select tokens rather than tokens selecting experts, (3) Z-loss to prevent router logit explosion, and (4) capacity factors with token dropping."},{"type":"heading","level":2,"content":"Expert Collapse Problem"},{"type":"text","content":"Expert collapse occurs because the softmax router is a winner-takes-all function in expectation. If expert 0 happens to be initialised with slightly larger weights, it receives slightly higher logits for many tokens, gets routed more tokens, receives more gradient, improves faster, and wins an ever-larger share of tokens. This creates a rich-get-richer dynamic that is reinforced at every gradient step. Once an expert dominates — receiving more than 50% of tokens — the other experts receive so little gradient that their weights barely change, effectively freezing them. Recovery from severe collapse is difficult because the dominant expert has already converged to a local optimum, and the auxiliary loss must push strongly enough against it to overcome this."},{"type":"list","ordered":false,"items":["Router logits for the dominant expert grow monotonically while others decay","Auxiliary loss becomes ineffective once collapse is severe (gradient flow to other experts is near zero)","Training loss may still decrease even during collapse — the LM objective does not detect it","Expert utilisation entropy drops from log(N) to near 0 over hundreds of steps","Recovery requires either very strong alpha or architectural changes to the router","Prevention (strong alpha from step 1) is far easier than cure"]},{"type":"heading","level":2,"content":"Auxiliary Load Balancing Loss"},{"type":"text","content":"The standard auxiliary loss (GShard, Switch Transformer) adds a differentiable penalty for expert imbalance to the training objective. It computes two per-expert quantities: f_i, the fraction of tokens dispatched to expert i (based on the discrete top-K selection), and P_i, the mean routing probability for expert i (the softmax output, which is differentiable). The product f_i * P_i is high when expert i both receives many tokens and has high routing probability — both conditions true for the dominant expert. The auxiliary loss is N * sum_i(f_i * P_i), scaled by a coefficient alpha (typically 1e-2). Note that f_i is not differentiable (it is based on argmax), but P_i is differentiable, so gradients flow back through P_i to the router weights."},{"type":"code","language":"python","content":"import torch\nimport torch.nn.functional as F\n\ndef gshard_auxiliary_loss(router_logits: torch.Tensor,\n                          n_experts: int, top_k: int,\n                          alpha: float = 1e-2) -\u003e torch.Tensor:\n    \"\"\"Auxiliary load-balancing loss from GShard and Switch Transformer.\n    router_logits: (batch*seq, n_experts) — raw router outputs before softmax.\"\"\"\n    probs   = F.softmax(router_logits, dim=-1)              # (N, E) differentiable\n    # Dispatch indices (not differentiable)\n    _, idx  = torch.topk(probs.detach(), top_k, dim=-1)    # (N, top_k)\n    # f_i: fraction of tokens dispatched to expert i (non-differentiable)\n    onehot  = F.one_hot(idx[:, 0], n_experts).float()      # use top-1 for f_i\n    f_i     = onehot.mean(dim=0)                           # (E,)\n    # P_i: mean routing probability (differentiable)\n    P_i     = probs.mean(dim=0)                            # (E,)\n    aux     = n_experts * (f_i * P_i).sum()\n    return alpha * aux\n\n# Observe aux_loss under different routing distributions\nfor name, logit_fn in [\n    (\"uniform\",  lambda: torch.zeros(64, 8)),\n    (\"balanced\", lambda: torch.randn(64, 8) * 0.5),\n    (\"collapse\", lambda: torch.cat([torch.full((64,1),5.0), torch.zeros(64,7)], -1)),\n]:\n    L = gshard_auxiliary_loss(logit_fn(), n_experts=8, top_k=2, alpha=1.0)\n    print(f\"{name:\u003e10}: raw_aux = {L.item():.4f}\")"},{"type":"heading","level":2,"content":"Expert Choice Routing"},{"type":"text","content":"Expert choice routing (Zhou et al., 2022) inverts the routing direction: instead of each token selecting its top-K experts, each expert selects its top-C tokens from the batch. With a capacity C = (batch_size * seq_len * K) / N tokens per expert, every expert processes exactly the same number of tokens — load balance is guaranteed by construction. The selection is done per expert independently: expert i scores all batch tokens with its own routing head and takes the top-C. A token may be selected by multiple experts (like top-K) or by none (unlike token-choice routing, where every token is guaranteed to be processed). The method eliminates the need for auxiliary loss entirely and removes the capacity-factor-and-drop problem, but requires a different implementation of the dispatch mechanism."},{"type":"code","language":"python","content":"import torch\nimport torch.nn.functional as F\n\ndef expert_choice_routing(x: torch.Tensor, W_router: torch.Tensor,\n                          n_experts: int, capacity_factor: float = 1.0) -\u003e tuple:\n    \"\"\"Expert choice: each expert selects top-C tokens.\n    x: (N, D)  W_router: (D, E)\n    Returns: (expert_outputs placeholder, token_assignments dict)\"\"\"\n    N, D = x.shape\n    # Capacity: each expert processes capacity_factor * N / n_experts tokens\n    C = max(1, int(capacity_factor * N / n_experts))\n    scores = x @ W_router                                   # (N, E)\n    scores = F.softmax(scores, dim=0)                       # softmax over tokens\n    # Each expert selects its top-C tokens\n    top_scores, top_indices = torch.topk(scores, C, dim=0) # (C, E)\n    assignments = {}\n    for e in range(n_experts):\n        token_ids = top_indices[:, e]                       # (C,) token indices\n        weights   = top_scores[:, e]                        # (C,) routing weights\n        assignments[e] = (token_ids, weights)\n    # Every expert processes exactly C tokens — load balance guaranteed\n    return assignments, C\n\nN, D, E = 128, 256, 8\nassign, cap = expert_choice_routing(torch.randn(N, D), torch.randn(D, E), E)\nfor e, (ids, wts) in assign.items():\n    print(f\"Expert {e}: {len(ids)} tokens, mean_weight={wts.mean():.3f}\")"},{"type":"heading","level":2,"content":"Z-Loss for Router Stability"},{"type":"text","content":"Z-loss (Zoph et al., 2022, from the ST-MoE paper) addresses a different instability: router logit explosion. During training, the router logits can grow to very large magnitudes (±30 or more), causing the softmax to saturate — one expert gets probability ~1.0 and all others get ~0.0. This saturation makes the auxiliary loss almost zero (since the softmax gradient vanishes at saturation), prevents the auxiliary loss from doing its job, and in practice leads to training instability or NaNs at large scale. Z-loss penalises large router logits directly: L_z = (1/N) * sum_i log(sum_j exp(h_ij))^2, where h_ij are the logits for token i. This is the squared log-sum-exp of the logits — zero when logits are near zero, large when logits are large in magnitude."},{"type":"code","language":"python","content":"import torch\nimport torch.nn.functional as F\n\ndef z_loss(router_logits: torch.Tensor, coeff: float = 1e-3) -\u003e torch.Tensor:\n    \"\"\"Z-loss: penalise large router logits to prevent softmax saturation.\n    router_logits: (batch*seq, n_experts) raw logits (before softmax).\n    Returns a scalar loss to add to the total training loss.\"\"\"\n    # log(sum(exp(h))) = logsumexp across experts for each token\n    log_z = torch.logsumexp(router_logits, dim=-1)          # (N,)\n    return coeff * (log_z ** 2).mean()\n\ndef router_stability_check(logits: torch.Tensor) -\u003e dict:\n    \"\"\"Check router logit health: large magnitudes indicate impending collapse.\"\"\"\n    abs_max  = logits.abs().max().item()\n    probs    = F.softmax(logits, dim=-1)\n    entropy  = -(probs * (probs + 1e-9).log()).sum(-1).mean().item()\n    max_prob = probs.max(-1).values.mean().item()\n    return {\"abs_max_logit\": abs_max, \"mean_entropy\": entropy,\n            \"mean_max_prob\": max_prob, \"z_loss\": z_loss(logits, 1.0).item()}\n\nfor name, logits in [\n    (\"healthy\",  torch.randn(32, 8) * 1.0),\n    (\"moderate\", torch.randn(32, 8) * 5.0),\n    (\"exploded\", torch.randn(32, 8) * 20.0),\n]:\n    s = router_stability_check(logits)\n    print(f\"{name:\u003e10}: max_logit={s[\u0027abs_max_logit\u0027]:.1f}  entropy={s[\u0027mean_entropy\u0027]:.3f}  z_loss={s[\u0027z_loss\u0027]:.2f}\")"},{"type":"heading","level":2,"content":"Capacity Factor"},{"type":"text","content":"Capacity factor is a hardware-level load-balancing mechanism used in both GShard and Switch Transformer. Each expert is allocated a fixed buffer of size C = capacity_factor * (batch_tokens / n_experts) tokens. If more than C tokens are routed to an expert, the overflow tokens are dropped (their representation passes through unchanged, or is zero-padded). The capacity factor is typically set to 1.0–1.25: 1.0 means perfect balance with zero slack, causing frequent dropping unless load is perfectly balanced; 1.25 provides a 25% buffer that absorbs mild imbalance without dropping. During training, dropped tokens still contribute to the LM loss (their target labels are unchanged) but do not pass through the expert, weakening their gradient. The capacity factor is usually reduced over training as the router learns to balance itself."},{"type":"table","headers":["Method","Load balance quality","Accuracy impact","Extra compute","Notes"],"rows":[["No balancing","Poor (collapse)","Severe (-3 to -5 PPL)","None","Fails without regularisation"],["Auxiliary loss (alpha=1e-2)","Good","Minimal (~0.1 PPL)","Negligible","Standard choice; Switch/GShard"],["Expert choice routing","Perfect (guaranteed)","None to slight gain","Moderate (softmax over tokens)","No aux loss needed; different dispatch logic"],["Z-loss (coeff=1e-3)","Good (prevents explosion)","Minimal","Negligible","Used alongside aux loss in ST-MoE"],["Token dropping (cap=1.0)","Good (bounded)","Slight (-0.2 to -0.5 PPL)","Negligible","Drops overflow tokens; hardware efficient"],["Buffer tokens","Moderate","Negligible","Small memory","Overflow tokens held in shared buffer"]]},{"type":"heading","level":2,"content":"Monitoring Expert Utilization"},{"type":"text","content":"Monitoring expert utilisation throughout training is essential because the LM loss is not a reliable indicator of load collapse — a model can produce good perplexity with only 2–3 active experts. The key metrics are: normalised entropy of the expert utilisation distribution (1.0 = perfectly balanced, 0.0 = full collapse); coefficient of variation (CV) of per-expert token counts (target \u003c 0.3); and fraction of tokens dropped due to capacity overflow (target \u003c 5%). These should be logged every 100–500 training steps. If normalised entropy drops below 0.7 or CV exceeds 0.5, increase alpha or inspect the router logits for saturation. A useful diagnostic is to plot the per-expert token fraction as a stacked bar chart over training — visual collapse is immediately obvious."},{"type":"code","language":"python","content":"import torch\nimport numpy as np\nfrom collections import deque\n\nclass ExpertLoadMonitor:\n    \"\"\"Monitor per-expert token load over a sliding window of batches.\"\"\"\n    def __init__(self, n_experts: int, window: int = 500):\n        self.n_experts = n_experts\n        self.history   = deque(maxlen=window)\n\n    def record(self, expert_indices: torch.Tensor) -\u003e dict:\n        \"\"\"expert_indices: (N, top_k). Records load and returns current stats.\"\"\"\n        counts = torch.zeros(self.n_experts)\n        for e in range(self.n_experts):\n            counts[e] = (expert_indices == e).sum().float()\n        load = counts / counts.sum()\n        self.history.append(load.numpy())\n        # Compute stats over history window\n        hist  = np.stack(self.history)                     # (W, E)\n        mean  = hist.mean(axis=0)\n        cv    = mean.std() / (mean.mean() + 1e-9)\n        ent   = -(mean * np.log(mean + 1e-9)).sum()\n        max_e = np.log(self.n_experts)\n        stats = {\"cv\": cv, \"norm_entropy\": ent / max_e,\n                 \"max_load\": mean.max(), \"min_load\": mean.min()}\n        if cv \u003e 0.5:\n            print(f\"  ALERT: CV={cv:.3f} \u003e 0.5 — possible expert collapse\")\n        return stats\n\nmonitor = ExpertLoadMonitor(n_experts=8, window=100)\nfor step in range(50):\n    idx = torch.randint(0, 8, (64, 2))\n    if step % 10 == 0:\n        s = monitor.record(idx)\n        print(f\"step {step:\u003e3}: norm_entropy={s[\u0027norm_entropy\u0027]:.3f}  cv={s[\u0027cv\u0027]:.3f}\")"},{"type":"callout","variant":"warning","title":"Expert Collapse is Not Self-Correcting","content":"Expert collapse is a training failure mode, not a convergence issue — once a few experts dominate, gradient signal stops flowing to others, making recovery difficult without strong auxiliary losses from the start. Monitor normalised entropy every 100 steps; if it drops below 0.7, increase alpha immediately."},{"type":"heading","level":2,"content":"Key Takeaways"},{"type":"text","content":"Load balancing is a first-class concern in MoE training, not an afterthought. The auxiliary loss (alpha ~ 1e-2) is the standard prevention mechanism and must be applied from the first training step. Z-loss (coeff ~ 1e-3) should be added alongside the auxiliary loss at large scale to prevent router logit explosion. Expert choice routing completely eliminates the load-imbalance problem at the cost of a different dispatch implementation. Capacity factor with token dropping is a hardware-efficiency tool, not a balancing solution — it caps damage from imbalance but does not prevent it. Monitor normalised entropy and CV throughout training, and alert when entropy drops below 0.7."},{"type":"list","ordered":false,"items":["Apply auxiliary load-balancing loss from step 1 with alpha ~ 1e-2 (Switch/GShard formula)","Add Z-loss (coeff ~ 1e-3) at large scale to prevent router logit saturation","Expert choice routing guarantees load balance by construction; no aux loss needed","Capacity factor 1.0–1.25 caps tokens per expert; overflow tokens are dropped","Monitor normalised entropy (target \u003e 0.8) and CV (target \u003c 0.3) every 100 steps","Recovery from collapse is hard — prevention with strong alpha from step 1 is essential"]}]"
---
# MoE Load Balancing

In a Mixture-of-Experts model, the router is a small learned network that maps each token to a probability distribution over experts. Left unconstrained, the router quickly collapses: a few experts consistently win the softmax competition, receive the most tokens, accumulate the most gradient signal, and become even better — while the remaining experts starve. This failure mode, called expert collapse, is one of the central training challenges in MoE architectures. Addressing it requires explicit regularisation in the loss function, alternative routing strategies that remove the competitive dynamic, and careful monitoring throughout training. This note covers the full toolkit: auxiliary loss, expert choice routing, Z-loss, and capacity factors.

## Overview

Load balancing in MoE training is the problem of ensuring each expert processes approximately 1/N of all tokens throughout training, while still allowing the router to develop meaningful specialisation. Perfect balance (each expert sees exactly 1/N tokens) would require a combinatorial assignment that ignores token-expert affinity; pure affinity routing (each token always goes to its most preferred expert) collapses. Good load balancing methods find a middle ground: they allow the router to prefer certain experts for certain tokens while adding soft regularisation that discourages extreme imbalance. The main approaches are: (1) auxiliary loss on the routing distribution, (2) expert choice routing where experts select tokens rather than tokens selecting experts, (3) Z-loss to prevent router logit explosion, and (4) capacity factors with token dropping.

## Expert Collapse Problem

Expert collapse occurs because the softmax router is a winner-takes-all function in expectation. If expert 0 happens to be initialised with slightly larger weights, it receives slightly higher logits for many tokens, gets routed more tokens, receives more gradient, improves faster, and wins an ever-larger share of tokens. This creates a rich-get-richer dynamic that is reinforced at every gradient step. Once an expert dominates — receiving more than 50% of tokens — the other experts receive so little gradient that their weights barely change, effectively freezing them. Recovery from severe collapse is difficult because the dominant expert has already converged to a local optimum, and the auxiliary loss must push strongly enough against it to overcome this.

- Router logits for the dominant expert grow monotonically while others decay
- Auxiliary loss becomes ineffective once collapse is severe (gradient flow to other experts is near zero)
- Training loss may still decrease even during collapse — the LM objective does not detect it
- Expert utilisation entropy drops from log(N) to near 0 over hundreds of steps
- Recovery requires either very strong alpha or architectural changes to the router
- Prevention (strong alpha from step 1) is far easier than cure

## Auxiliary Load Balancing Loss

The standard auxiliary loss (GShard, Switch Transformer) adds a differentiable penalty for expert imbalance to the training objective. It computes two per-expert quantities: f_i, the fraction of tokens dispatched to expert i (based on the discrete top-K selection), and P_i, the mean routing probability for expert i (the softmax output, which is differentiable). The product f_i * P_i is high when expert i both receives many tokens and has high routing probability — both conditions true for the dominant expert. The auxiliary loss is N * sum_i(f_i * P_i), scaled by a coefficient alpha (typically 1e-2). Note that f_i is not differentiable (it is based on argmax), but P_i is differentiable, so gradients flow back through P_i to the router weights.

```python
import torch
import torch.nn.functional as F

def gshard_auxiliary_loss(router_logits: torch.Tensor,
                          n_experts: int, top_k: int,
                          alpha: float = 1e-2) -> torch.Tensor:
    """Auxiliary load-balancing loss from GShard and Switch Transformer.
    router_logits: (batch*seq, n_experts) — raw router outputs before softmax."""
    probs   = F.softmax(router_logits, dim=-1)              # (N, E) differentiable
    # Dispatch indices (not differentiable)
    _, idx  = torch.topk(probs.detach(), top_k, dim=-1)    # (N, top_k)
    # f_i: fraction of tokens dispatched to expert i (non-differentiable)
    onehot  = F.one_hot(idx[:, 0], n_experts).float()      # use top-1 for f_i
    f_i     = onehot.mean(dim=0)                           # (E,)
    # P_i: mean routing probability (differentiable)
    P_i     = probs.mean(dim=0)                            # (E,)
    aux     = n_experts * (f_i * P_i).sum()
    return alpha * aux

# Observe aux_loss under different routing distributions
for name, logit_fn in [
    ("uniform",  lambda: torch.zeros(64, 8)),
    ("balanced", lambda: torch.randn(64, 8) * 0.5),
    ("collapse", lambda: torch.cat([torch.full((64,1),5.0), torch.zeros(64,7)], -1)),
]:
    L = gshard_auxiliary_loss(logit_fn(), n_experts=8, top_k=2, alpha=1.0)
    print(f"{name:>10}: raw_aux = {L.item():.4f}")
```

## Expert Choice Routing

Expert choice routing (Zhou et al., 2022) inverts the routing direction: instead of each token selecting its top-K experts, each expert selects its top-C tokens from the batch. With a capacity C = (batch_size * seq_len * K) / N tokens per expert, every expert processes exactly the same number of tokens — load balance is guaranteed by construction. The selection is done per expert independently: expert i scores all batch tokens with its own routing head and takes the top-C. A token may be selected by multiple experts (like top-K) or by none (unlike token-choice routing, where every token is guaranteed to be processed). The method eliminates the need for auxiliary loss entirely and removes the capacity-factor-and-drop problem, but requires a different implementation of the dispatch mechanism.

```python
import torch
import torch.nn.functional as F

def expert_choice_routing(x: torch.Tensor, W_router: torch.Tensor,
                          n_experts: int, capacity_factor: float = 1.0) -> tuple:
    """Expert choice: each expert selects top-C tokens.
    x: (N, D)  W_router: (D, E)
    Returns: (expert_outputs placeholder, token_assignments dict)"""
    N, D = x.shape
    # Capacity: each expert processes capacity_factor * N / n_experts tokens
    C = max(1, int(capacity_factor * N / n_experts))
    scores = x @ W_router                                   # (N, E)
    scores = F.softmax(scores, dim=0)                       # softmax over tokens
    # Each expert selects its top-C tokens
    top_scores, top_indices = torch.topk(scores, C, dim=0) # (C, E)
    assignments = {}
    for e in range(n_experts):
        token_ids = top_indices[:, e]                       # (C,) token indices
        weights   = top_scores[:, e]                        # (C,) routing weights
        assignments[e] = (token_ids, weights)
    # Every expert processes exactly C tokens — load balance guaranteed
    return assignments, C

N, D, E = 128, 256, 8
assign, cap = expert_choice_routing(torch.randn(N, D), torch.randn(D, E), E)
for e, (ids, wts) in assign.items():
    print(f"Expert {e}: {len(ids)} tokens, mean_weight={wts.mean():.3f}")
```

## Z-Loss for Router Stability

Z-loss (Zoph et al., 2022, from the ST-MoE paper) addresses a different instability: router logit explosion. During training, the router logits can grow to very large magnitudes (±30 or more), causing the softmax to saturate — one expert gets probability ~1.0 and all others get ~0.0. This saturation makes the auxiliary loss almost zero (since the softmax gradient vanishes at saturation), prevents the auxiliary loss from doing its job, and in practice leads to training instability or NaNs at large scale. Z-loss penalises large router logits directly: L_z = (1/N) * sum_i log(sum_j exp(h_ij))^2, where h_ij are the logits for token i. This is the squared log-sum-exp of the logits — zero when logits are near zero, large when logits are large in magnitude.

```python
import torch
import torch.nn.functional as F

def z_loss(router_logits: torch.Tensor, coeff: float = 1e-3) -> torch.Tensor:
    """Z-loss: penalise large router logits to prevent softmax saturation.
    router_logits: (batch*seq, n_experts) raw logits (before softmax).
    Returns a scalar loss to add to the total training loss."""
    # log(sum(exp(h))) = logsumexp across experts for each token
    log_z = torch.logsumexp(router_logits, dim=-1)          # (N,)
    return coeff * (log_z ** 2).mean()

def router_stability_check(logits: torch.Tensor) -> dict:
    """Check router logit health: large magnitudes indicate impending collapse."""
    abs_max  = logits.abs().max().item()
    probs    = F.softmax(logits, dim=-1)
    entropy  = -(probs * (probs + 1e-9).log()).sum(-1).mean().item()
    max_prob = probs.max(-1).values.mean().item()
    return {"abs_max_logit": abs_max, "mean_entropy": entropy,
            "mean_max_prob": max_prob, "z_loss": z_loss(logits, 1.0).item()}

for name, logits in [
    ("healthy",  torch.randn(32, 8) * 1.0),
    ("moderate", torch.randn(32, 8) * 5.0),
    ("exploded", torch.randn(32, 8) * 20.0),
]:
    s = router_stability_check(logits)
    print(f"{name:>10}: max_logit={s['abs_max_logit']:.1f}  entropy={s['mean_entropy']:.3f}  z_loss={s['z_loss']:.2f}")
```

## Capacity Factor

Capacity factor is a hardware-level load-balancing mechanism used in both GShard and Switch Transformer. Each expert is allocated a fixed buffer of size C = capacity_factor * (batch_tokens / n_experts) tokens. If more than C tokens are routed to an expert, the overflow tokens are dropped (their representation passes through unchanged, or is zero-padded). The capacity factor is typically set to 1.0–1.25: 1.0 means perfect balance with zero slack, causing frequent dropping unless load is perfectly balanced; 1.25 provides a 25% buffer that absorbs mild imbalance without dropping. During training, dropped tokens still contribute to the LM loss (their target labels are unchanged) but do not pass through the expert, weakening their gradient. The capacity factor is usually reduced over training as the router learns to balance itself.

| Method | Load balance quality | Accuracy impact | Extra compute | Notes |
| --- | --- | --- | --- | --- |
| No balancing | Poor (collapse) | Severe (-3 to -5 PPL) | None | Fails without regularisation |
| Auxiliary loss (alpha=1e-2) | Good | Minimal (~0.1 PPL) | Negligible | Standard choice; Switch/GShard |
| Expert choice routing | Perfect (guaranteed) | None to slight gain | Moderate (softmax over tokens) | No aux loss needed; different dispatch logic |
| Z-loss (coeff=1e-3) | Good (prevents explosion) | Minimal | Negligible | Used alongside aux loss in ST-MoE |
| Token dropping (cap=1.0) | Good (bounded) | Slight (-0.2 to -0.5 PPL) | Negligible | Drops overflow tokens; hardware efficient |
| Buffer tokens | Moderate | Negligible | Small memory | Overflow tokens held in shared buffer |

## Monitoring Expert Utilization

Monitoring expert utilisation throughout training is essential because the LM loss is not a reliable indicator of load collapse — a model can produce good perplexity with only 2–3 active experts. The key metrics are: normalised entropy of the expert utilisation distribution (1.0 = perfectly balanced, 0.0 = full collapse); coefficient of variation (CV) of per-expert token counts (target < 0.3); and fraction of tokens dropped due to capacity overflow (target < 5%). These should be logged every 100–500 training steps. If normalised entropy drops below 0.7 or CV exceeds 0.5, increase alpha or inspect the router logits for saturation. A useful diagnostic is to plot the per-expert token fraction as a stacked bar chart over training — visual collapse is immediately obvious.

```python
import torch
import numpy as np
from collections import deque

class ExpertLoadMonitor:
    """Monitor per-expert token load over a sliding window of batches."""
    def __init__(self, n_experts: int, window: int = 500):
        self.n_experts = n_experts
        self.history   = deque(maxlen=window)

    def record(self, expert_indices: torch.Tensor) -> dict:
        """expert_indices: (N, top_k). Records load and returns current stats."""
        counts = torch.zeros(self.n_experts)
        for e in range(self.n_experts):
            counts[e] = (expert_indices == e).sum().float()
        load = counts / counts.sum()
        self.history.append(load.numpy())
        # Compute stats over history window
        hist  = np.stack(self.history)                     # (W, E)
        mean  = hist.mean(axis=0)
        cv    = mean.std() / (mean.mean() + 1e-9)
        ent   = -(mean * np.log(mean + 1e-9)).sum()
        max_e = np.log(self.n_experts)
        stats = {"cv": cv, "norm_entropy": ent / max_e,
                 "max_load": mean.max(), "min_load": mean.min()}
        if cv > 0.5:
            print(f"  ALERT: CV={cv:.3f} > 0.5 — possible expert collapse")
        return stats

monitor = ExpertLoadMonitor(n_experts=8, window=100)
for step in range(50):
    idx = torch.randint(0, 8, (64, 2))
    if step % 10 == 0:
        s = monitor.record(idx)
        print(f"step {step:>3}: norm_entropy={s['norm_entropy']:.3f}  cv={s['cv']:.3f}")
```

> **Expert Collapse is Not Self-Correcting**: Expert collapse is a training failure mode, not a convergence issue — once a few experts dominate, gradient signal stops flowing to others, making recovery difficult without strong auxiliary losses from the start. Monitor normalised entropy every 100 steps; if it drops below 0.7, increase alpha immediately.

## Key Takeaways

Load balancing is a first-class concern in MoE training, not an afterthought. The auxiliary loss (alpha ~ 1e-2) is the standard prevention mechanism and must be applied from the first training step. Z-loss (coeff ~ 1e-3) should be added alongside the auxiliary loss at large scale to prevent router logit explosion. Expert choice routing completely eliminates the load-imbalance problem at the cost of a different dispatch implementation. Capacity factor with token dropping is a hardware-efficiency tool, not a balancing solution — it caps damage from imbalance but does not prevent it. Monitor normalised entropy and CV throughout training, and alert when entropy drops below 0.7.

- Apply auxiliary load-balancing loss from step 1 with alpha ~ 1e-2 (Switch/GShard formula)
- Add Z-loss (coeff ~ 1e-3) at large scale to prevent router logit saturation
- Expert choice routing guarantees load balance by construction; no aux loss needed
- Capacity factor 1.0–1.25 caps tokens per expert; overflow tokens are dropped
- Monitor normalised entropy (target > 0.8) and CV (target < 0.3) every 100 steps
- Recovery from collapse is hard — prevention with strong alpha from step 1 is essential

