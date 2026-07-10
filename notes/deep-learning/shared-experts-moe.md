---
title: "Shared Experts in MoE Architectures"
slug: "shared-experts-moe"
description: "Combining a set of always-active shared expert(s) with conditionally-routed sparse experts to handle common knowledge while sparse experts specialize — as in DeepSeek-MoE and DS-MoE."
tags: ["deep-learning", "llm"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"Standard MoE routes every token to a small subset of experts, leaving common linguistic patterns to be learned redundantly across multiple experts. Shared experts address this by introducing a dedicated set of always-active experts that process every token unconditionally — they serve as a \u0027common knowledge store\u0027 for patterns that appear universally across all inputs. The remaining experts are sparse and conditionally routed as in standard MoE. This hybrid design, introduced in DeepSeek-MoE (Dai et al., 2024) and used in DeepSeek-V2, cleanly separates universal knowledge (shared experts) from specialised domain knowledge (routed experts), improving overall parameter efficiency and allowing routed experts to specialise more aggressively."},{"type":"heading","level":2,"content":"Overview"},{"type":"text","content":"In a shared-expert MoE layer, the output is the sum of two components: (1) the sum of outputs from N_s shared experts that always activate, and (2) the weighted sum of top-K_r selected outputs from N_r routed experts. The shared experts contribute a fixed, general transformation to every token; the routed experts contribute a token-specific, specialised transformation. The load-balancing auxiliary loss is applied only to the routed experts — since shared experts process all tokens equally, they need no balancing. The overall active-parameter count per token is N_s + K_r experts, compared to K_r in a pure sparse MoE. In DeepSeek-V2, N_s=2 shared and K_r=6 of N_r=160 routed experts activate per token, giving 8 active expert units per token with 236B total parameters."},{"type":"heading","level":2,"content":"Motivation for Shared Experts"},{"type":"text","content":"The motivation for shared experts comes from an empirical observation in coarse MoE: expert weight matrices show high pairwise cosine similarity for certain components. This suggests that multiple experts are learning the same transformation — wasting parameters on redundant common knowledge instead of developing unique specialisations. The redundancy arises because, in standard MoE, even though each expert processes only 1/N tokens on average, those tokens span many different linguistic patterns. An expert that processes diverse tokens must learn diverse functions, leading to a \u0027jack of all trades\u0027 representation that overlaps with other experts. By offloading the most universal patterns to dedicated shared experts, routed experts are free to specialise in narrower and more distinct domains."},{"type":"list","ordered":false,"items":["Expert weight cosine similarity in coarse MoE is higher than expected — experts learn redundant functions","Common linguistic patterns (function words, punctuation, basic grammar) appear in all token contexts","Shared experts learn these universal patterns once, not redundantly across multiple routed experts","Routed expert specialisation improves because they no longer need to cover common patterns","Load-balancing pressure on routed experts is reduced — they handle a more separable task","Ablations show that removing shared experts reduces downstream accuracy by 0.5–1.5 points"]},{"type":"heading","level":2,"content":"Architecture Design"},{"type":"text","content":"The shared-expert MoE layer has three components: a router, N_s shared experts, and N_r routed experts. The router is identical to standard MoE — a linear projection from d_model to N_r (not N_r + N_s, since shared experts need no routing). Shared experts are standard FFNs (Linear → GELU → Linear) with the same architecture as routed experts. On the forward pass, input x is processed by all N_s shared experts in parallel (sum their outputs), and independently processed by the top-K_r selected routed experts (weighted sum). The two components are added element-wise. Since shared expert outputs are not gated, no routing weight is applied — each shared expert contributes its full output. In DeepSeek-MoE, shared experts have the same hidden dimension as routed experts (d_ff/m for fine-grained variants)."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.nn.functional as F\n\nclass SharedExpertMoELayer(nn.Module):\n    \"\"\"MoE layer with always-active shared experts + top-K routed experts.\"\"\"\n    def __init__(self, d_model: int, d_ff: int,\n                 n_shared: int, n_routed: int, top_k: int):\n        super().__init__()\n        self.n_routed, self.top_k = n_routed, top_k\n        self.router = nn.Linear(d_model, n_routed, bias=False)\n        # Shared experts: always active, no routing weight\n        self.shared_experts = nn.ModuleList([\n            nn.Sequential(nn.Linear(d_model, d_ff), nn.GELU(),\n                          nn.Linear(d_ff, d_model)) for _ in range(n_shared)])\n        # Routed experts: sparse, conditionally activated\n        self.routed_experts = nn.ModuleList([\n            nn.Sequential(nn.Linear(d_model, d_ff), nn.GELU(),\n                          nn.Linear(d_ff, d_model)) for _ in range(n_routed)])\n\n    def forward(self, x: torch.Tensor) -\u003e torch.Tensor:\n        # 1. Shared expert pass (always active, no gating)\n        shared_out = sum(e(x) for e in self.shared_experts)  # (B, T, D)\n        # 2. Routed expert pass (top-K of N_r)\n        B, T, D = x.shape\n        xf = x.view(B * T, D)\n        probs, idx = torch.topk(F.softmax(self.router(xf), -1), self.top_k, -1)\n        probs = probs / probs.sum(-1, keepdim=True)\n        routed = torch.zeros_like(xf)\n        for k in range(self.top_k):\n            for e, expert in enumerate(self.routed_experts):\n                m = idx[:, k] == e\n                if m.any():\n                    routed[m] += probs[m, k:k+1] * expert(xf[m])\n        return shared_out + routed.view(B, T, D)\n\nlayer = SharedExpertMoELayer(512, 1024, n_shared=2, n_routed=32, top_k=4)\nprint(f\"Output: {layer(torch.randn(2, 8, 512)).shape}\")"},{"type":"heading","level":2,"content":"Routing with Shared + Routed"},{"type":"text","content":"The router in a shared-expert MoE only needs to score the N_r routed experts — the N_s shared experts are always active and require no score. This keeps the router smaller than it would be if shared experts were included in the routing decision. The routing mechanism is identical to standard top-K routing: softmax over N_r logits, take top-K_r, renormalise, weighted sum. Because the shared experts already provide a universal base transformation, the routed experts need only produce a residual specialised correction. This means the routing weights do not need to be as sharp — a moderate preference for certain routed experts is sufficient. In practice, this leads to more stable routing and less collapse compared to pure sparse MoE with the same number of routed experts."},{"type":"code","language":"python","content":"import torch\nimport torch.nn.functional as F\n\ndef knowledge_decomposition_analysis(shared_weights: torch.Tensor,\n                                     routed_weights: torch.Tensor) -\u003e dict:\n    \"\"\"Measure how different shared vs routed expert weights are.\n    shared_weights: (n_shared, d_in*d_out)  routed_weights: (n_routed, d_in*d_out)\n    Hypothesis: shared experts should differ from routed experts\n    (they capture different patterns), and routed experts differ from each other.\"\"\"\n    shared_norm = F.normalize(shared_weights, dim=-1)       # (n_s, D)\n    routed_norm = F.normalize(routed_weights, dim=-1)       # (n_r, D)\n    # Shared vs routed similarity (should be low — different functions)\n    sr_sim = (shared_norm.unsqueeze(1) * routed_norm.unsqueeze(0)).sum(-1)  # (n_s, n_r)\n    # Routed vs routed similarity (should be low — diverse specialisation)\n    rr_sim = routed_norm @ routed_norm.T                    # (n_r, n_r)\n    mask   = ~torch.eye(routed_norm.shape[0], dtype=torch.bool)\n    return {\n        \"shared_vs_routed_mean_sim\": sr_sim.mean().item(),\n        \"routed_vs_routed_mean_sim\": rr_sim[mask].mean().item(),\n        \"routed_diversity\": 1 - rr_sim[mask].mean().item(),\n    }\n\ntorch.manual_seed(0)\nshared = torch.randn(2, 512 * 256)\nrouted = torch.randn(32, 512 * 256)\nstats  = knowledge_decomposition_analysis(shared, routed)\nfor k, v in stats.items():\n    print(f\"{k}: {v:.4f}\")"},{"type":"heading","level":2,"content":"Knowledge Decomposition"},{"type":"text","content":"The theoretical motivation for shared experts is that the information processed by an MoE layer can be decomposed into two orthogonal components: general information that is context-independent and universal (such as basic token type transformations, positional context, and grammatical structure), and specialised information that depends on the specific domain, topic, or linguistic register of the input. Shared experts are responsible for the general component; routed experts handle the specialised component. This decomposition is not enforced explicitly — there is no loss term that separates these roles. Instead, it emerges from the gradient dynamics: shared expert weights receive gradients from all tokens and converge toward the mean transformation across the token distribution, while routed expert weights receive gradients only from their specific token cluster and converge toward the optimal transformation for that cluster."},{"type":"table","headers":["Design","Shared experts","Routed experts","Top-K","Always-active FLOPs","Notes"],"rows":[["Standard MoE (no shared)","0","8","2","2 experts","Baseline; all experts compete for routing"],["DeepSeek-MoE","2","64","6 routed","2 + 6 = 8 expert units","Fine-grained; shared handle universal patterns"],["DS-MoE variant","1","16","2 routed","1 + 2 = 3 expert units","Single shared expert; lighter overhead"],["Proposed shared=2","2","32","4 routed","2 + 4 = 6 expert units","Balance between shared coverage and routing"],["OpenMoE","0","32","2","2 experts","No shared; uses auxiliary loss only"]]},{"type":"heading","level":2,"content":"DeepSeek-V2 Implementation"},{"type":"text","content":"DeepSeek-V2 (DeepSeek-AI, 2024) is the largest public deployment of shared-expert MoE. It uses 236B total parameters with 21B active per token, achieved through 160 fine-grained routed experts plus 2 shared experts per MoE layer. Each MoE layer activates 6 of 160 routed experts plus both shared experts per token. The model was trained on 8.1T tokens with a cosine learning rate schedule. The load-balancing loss applies to the 160 routed experts only; the 2 shared experts are excluded since they process all tokens equally. DeepSeek-V2 demonstrates that this architecture matches or exceeds GPT-4-class performance on most benchmarks while activating only ~9% of total parameters per token, enabling efficient inference on fewer GPUs than a comparable dense model."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.nn.functional as F\n\ndef shared_moe_training_loss(lm_loss: torch.Tensor,\n                              router_logits: torch.Tensor,\n                              routed_indices: torch.Tensor,\n                              n_routed: int,\n                              alpha: float = 1e-2) -\u003e tuple:\n    \"\"\"Training loss for shared-expert MoE: LM loss + aux loss on routed only.\n    Shared experts are not included in the load-balancing loss.\"\"\"\n    probs  = F.softmax(router_logits, dim=-1)               # (N, E_routed)\n    onehot = F.one_hot(routed_indices[:, 0], n_routed).float()\n    f_i    = onehot.mean(0)                                 # fraction dispatched\n    P_i    = probs.mean(0)                                  # mean routing prob\n    aux    = n_routed * (f_i * P_i).sum()                  # imbalance penalty\n    total  = lm_loss + alpha * aux\n    return total, {\"lm\": lm_loss.item(), \"aux\": (alpha * aux).item()}\n\n# Simulate a training step\ntorch.manual_seed(0)\nlm   = torch.tensor(2.3)                                    # cross-entropy\nlogits = torch.randn(128, 32)                               # 128 tokens, 32 routed\nidx    = torch.topk(logits, 4, dim=-1).indices             # top-4 routing\ntotal, breakdown = shared_moe_training_loss(lm, logits, idx, 32)\nprint(f\"Total: {total.item():.4f}  LM: {breakdown[\u0027lm\u0027]:.4f}  Aux: {breakdown[\u0027aux\u0027]:.4f}\")"},{"type":"heading","level":2,"content":"Tradeoffs"},{"type":"text","content":"Shared experts improve parameter efficiency and routed expert specialisation but introduce additional always-active compute. With N_s=2 shared experts and K_r=6 routed experts, each token activates 8 expert units — equivalent to top-8 routing in a pure sparse MoE. If the goal is to minimise active FLOPs, shared experts consume a fixed overhead that scales with N_s but not with batch size or routing. At inference time, this overhead is constant and predictable, making latency more stable than pure sparse MoE where routing patterns vary by input. However, shared experts also increase memory bandwidth requirements at inference since their weights must be read for every token. The optimal N_s depends on how much universal knowledge exists in the training distribution — typically 1–4 shared experts is sufficient, with diminishing returns beyond that."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\n\ndef ablation_shared_experts(n_shared_list: list, d_model: int = 512,\n                            d_ff: int = 1024, n_routed: int = 32,\n                            top_k: int = 4) -\u003e None:\n    \"\"\"Ablation: measure total active params per token as n_shared varies.\"\"\"\n    print(f\"{\u0027n_shared\u0027:\u003e10} {\u0027n_routed\u0027:\u003e10} {\u0027top_k\u0027:\u003e8} \"\n          f\"{\u0027active_params_M\u0027:\u003e17} {\u0027shared_pct\u0027:\u003e12}\")\n    ffn_params = 2 * d_model * d_ff                         # params per expert\n    for ns in n_shared_list:\n        active = (ns + top_k) * ffn_params\n        shared_frac = ns / (ns + top_k) * 100\n        print(f\"{ns:\u003e10} {n_routed:\u003e10} {top_k:\u003e8} \"\n              f\"{active/1e6:\u003e17.2f} {shared_frac:\u003e11.1f}%\")\n\nablation_shared_experts([0, 1, 2, 4, 8])\n\n# Downstream accuracy proxy: shared=2 typically +0.5-1.5 points vs shared=0\nsimulated_accuracy = {0: 68.2, 1: 69.1, 2: 69.8, 4: 70.0, 8: 70.1}\nprint(\"\\nSimulated downstream accuracy vs n_shared:\")\nfor ns, acc in simulated_accuracy.items():\n    bar = \u0027|\u0027 * int((acc - 68) * 20)\n    print(f\"  n_shared={ns}: {acc:.1f}  {bar}\")"},{"type":"callout","variant":"info","title":"Common Knowledge Store","content":"Shared experts act like a \u0027common knowledge\u0027 store — they reduce the pressure on routed experts to cover universal language patterns, allowing routed experts to specialize more deeply in domain-specific knowledge. In DeepSeek-V2, just 2 shared experts (out of 162 total) improve benchmark accuracy by 0.7–1.2 points vs a baseline with 0 shared experts."},{"type":"heading","level":2,"content":"Key Takeaways"},{"type":"text","content":"Shared experts are a low-cost architectural addition that meaningfully improve MoE quality. By dedicating N_s always-active experts to universal knowledge, routed experts are freed to specialise more narrowly, reducing knowledge redundancy and improving parameter efficiency. The design is clean: the router only scores N_r routed experts; the auxiliary load-balancing loss applies only to routed experts; shared experts add a fixed per-token compute overhead of N_s expert forward passes. DeepSeek-V2 demonstrates that 2 shared experts out of 162 total is sufficient to materially improve quality at the 236B total parameter scale. For most applications, 1–4 shared experts is the practical sweet spot."},{"type":"list","ordered":false,"items":["N_s shared experts always activate for every token; their output is summed (not gated)","Router only covers N_r routed experts; auxiliary loss applies to routed experts only","Shared experts learn universal patterns; routed experts learn domain-specific specialisations","Active FLOPs = (N_s + K_r) expert forward passes per token — fixed overhead for shared","DeepSeek-V2: 2 shared + 6-of-160 routed = 8 active expert units per token, 236B total params","Optimal N_s is 1–4; beyond 4 shared experts, returns diminish and routing benefit shrinks"]}]"
---
# Shared Experts in MoE Architectures

Standard MoE routes every token to a small subset of experts, leaving common linguistic patterns to be learned redundantly across multiple experts. Shared experts address this by introducing a dedicated set of always-active experts that process every token unconditionally — they serve as a 'common knowledge store' for patterns that appear universally across all inputs. The remaining experts are sparse and conditionally routed as in standard MoE. This hybrid design, introduced in DeepSeek-MoE (Dai et al., 2024) and used in DeepSeek-V2, cleanly separates universal knowledge (shared experts) from specialised domain knowledge (routed experts), improving overall parameter efficiency and allowing routed experts to specialise more aggressively.

## Overview

In a shared-expert MoE layer, the output is the sum of two components: (1) the sum of outputs from N_s shared experts that always activate, and (2) the weighted sum of top-K_r selected outputs from N_r routed experts. The shared experts contribute a fixed, general transformation to every token; the routed experts contribute a token-specific, specialised transformation. The load-balancing auxiliary loss is applied only to the routed experts — since shared experts process all tokens equally, they need no balancing. The overall active-parameter count per token is N_s + K_r experts, compared to K_r in a pure sparse MoE. In DeepSeek-V2, N_s=2 shared and K_r=6 of N_r=160 routed experts activate per token, giving 8 active expert units per token with 236B total parameters.

## Motivation for Shared Experts

The motivation for shared experts comes from an empirical observation in coarse MoE: expert weight matrices show high pairwise cosine similarity for certain components. This suggests that multiple experts are learning the same transformation — wasting parameters on redundant common knowledge instead of developing unique specialisations. The redundancy arises because, in standard MoE, even though each expert processes only 1/N tokens on average, those tokens span many different linguistic patterns. An expert that processes diverse tokens must learn diverse functions, leading to a 'jack of all trades' representation that overlaps with other experts. By offloading the most universal patterns to dedicated shared experts, routed experts are free to specialise in narrower and more distinct domains.

- Expert weight cosine similarity in coarse MoE is higher than expected — experts learn redundant functions
- Common linguistic patterns (function words, punctuation, basic grammar) appear in all token contexts
- Shared experts learn these universal patterns once, not redundantly across multiple routed experts
- Routed expert specialisation improves because they no longer need to cover common patterns
- Load-balancing pressure on routed experts is reduced — they handle a more separable task
- Ablations show that removing shared experts reduces downstream accuracy by 0.5–1.5 points

## Architecture Design

The shared-expert MoE layer has three components: a router, N_s shared experts, and N_r routed experts. The router is identical to standard MoE — a linear projection from d_model to N_r (not N_r + N_s, since shared experts need no routing). Shared experts are standard FFNs (Linear → GELU → Linear) with the same architecture as routed experts. On the forward pass, input x is processed by all N_s shared experts in parallel (sum their outputs), and independently processed by the top-K_r selected routed experts (weighted sum). The two components are added element-wise. Since shared expert outputs are not gated, no routing weight is applied — each shared expert contributes its full output. In DeepSeek-MoE, shared experts have the same hidden dimension as routed experts (d_ff/m for fine-grained variants).

```python
import torch
import torch.nn as nn
import torch.nn.functional as F

class SharedExpertMoELayer(nn.Module):
    """MoE layer with always-active shared experts + top-K routed experts."""
    def __init__(self, d_model: int, d_ff: int,
                 n_shared: int, n_routed: int, top_k: int):
        super().__init__()
        self.n_routed, self.top_k = n_routed, top_k
        self.router = nn.Linear(d_model, n_routed, bias=False)
        # Shared experts: always active, no routing weight
        self.shared_experts = nn.ModuleList([
            nn.Sequential(nn.Linear(d_model, d_ff), nn.GELU(),
                          nn.Linear(d_ff, d_model)) for _ in range(n_shared)])
        # Routed experts: sparse, conditionally activated
        self.routed_experts = nn.ModuleList([
            nn.Sequential(nn.Linear(d_model, d_ff), nn.GELU(),
                          nn.Linear(d_ff, d_model)) for _ in range(n_routed)])

    def forward(self, x: torch.Tensor) -> torch.Tensor:
        # 1. Shared expert pass (always active, no gating)
        shared_out = sum(e(x) for e in self.shared_experts)  # (B, T, D)
        # 2. Routed expert pass (top-K of N_r)
        B, T, D = x.shape
        xf = x.view(B * T, D)
        probs, idx = torch.topk(F.softmax(self.router(xf), -1), self.top_k, -1)
        probs = probs / probs.sum(-1, keepdim=True)
        routed = torch.zeros_like(xf)
        for k in range(self.top_k):
            for e, expert in enumerate(self.routed_experts):
                m = idx[:, k] == e
                if m.any():
                    routed[m] += probs[m, k:k+1] * expert(xf[m])
        return shared_out + routed.view(B, T, D)

layer = SharedExpertMoELayer(512, 1024, n_shared=2, n_routed=32, top_k=4)
print(f"Output: {layer(torch.randn(2, 8, 512)).shape}")
```

## Routing with Shared + Routed

The router in a shared-expert MoE only needs to score the N_r routed experts — the N_s shared experts are always active and require no score. This keeps the router smaller than it would be if shared experts were included in the routing decision. The routing mechanism is identical to standard top-K routing: softmax over N_r logits, take top-K_r, renormalise, weighted sum. Because the shared experts already provide a universal base transformation, the routed experts need only produce a residual specialised correction. This means the routing weights do not need to be as sharp — a moderate preference for certain routed experts is sufficient. In practice, this leads to more stable routing and less collapse compared to pure sparse MoE with the same number of routed experts.

```python
import torch
import torch.nn.functional as F

def knowledge_decomposition_analysis(shared_weights: torch.Tensor,
                                     routed_weights: torch.Tensor) -> dict:
    """Measure how different shared vs routed expert weights are.
    shared_weights: (n_shared, d_in*d_out)  routed_weights: (n_routed, d_in*d_out)
    Hypothesis: shared experts should differ from routed experts
    (they capture different patterns), and routed experts differ from each other."""
    shared_norm = F.normalize(shared_weights, dim=-1)       # (n_s, D)
    routed_norm = F.normalize(routed_weights, dim=-1)       # (n_r, D)
    # Shared vs routed similarity (should be low — different functions)
    sr_sim = (shared_norm.unsqueeze(1) * routed_norm.unsqueeze(0)).sum(-1)  # (n_s, n_r)
    # Routed vs routed similarity (should be low — diverse specialisation)
    rr_sim = routed_norm @ routed_norm.T                    # (n_r, n_r)
    mask   = ~torch.eye(routed_norm.shape[0], dtype=torch.bool)
    return {
        "shared_vs_routed_mean_sim": sr_sim.mean().item(),
        "routed_vs_routed_mean_sim": rr_sim[mask].mean().item(),
        "routed_diversity": 1 - rr_sim[mask].mean().item(),
    }

torch.manual_seed(0)
shared = torch.randn(2, 512 * 256)
routed = torch.randn(32, 512 * 256)
stats  = knowledge_decomposition_analysis(shared, routed)
for k, v in stats.items():
    print(f"{k}: {v:.4f}")
```

## Knowledge Decomposition

The theoretical motivation for shared experts is that the information processed by an MoE layer can be decomposed into two orthogonal components: general information that is context-independent and universal (such as basic token type transformations, positional context, and grammatical structure), and specialised information that depends on the specific domain, topic, or linguistic register of the input. Shared experts are responsible for the general component; routed experts handle the specialised component. This decomposition is not enforced explicitly — there is no loss term that separates these roles. Instead, it emerges from the gradient dynamics: shared expert weights receive gradients from all tokens and converge toward the mean transformation across the token distribution, while routed expert weights receive gradients only from their specific token cluster and converge toward the optimal transformation for that cluster.

| Design | Shared experts | Routed experts | Top-K | Always-active FLOPs | Notes |
| --- | --- | --- | --- | --- | --- |
| Standard MoE (no shared) | 0 | 8 | 2 | 2 experts | Baseline; all experts compete for routing |
| DeepSeek-MoE | 2 | 64 | 6 routed | 2 + 6 = 8 expert units | Fine-grained; shared handle universal patterns |
| DS-MoE variant | 1 | 16 | 2 routed | 1 + 2 = 3 expert units | Single shared expert; lighter overhead |
| Proposed shared=2 | 2 | 32 | 4 routed | 2 + 4 = 6 expert units | Balance between shared coverage and routing |
| OpenMoE | 0 | 32 | 2 | 2 experts | No shared; uses auxiliary loss only |

## DeepSeek-V2 Implementation

DeepSeek-V2 (DeepSeek-AI, 2024) is the largest public deployment of shared-expert MoE. It uses 236B total parameters with 21B active per token, achieved through 160 fine-grained routed experts plus 2 shared experts per MoE layer. Each MoE layer activates 6 of 160 routed experts plus both shared experts per token. The model was trained on 8.1T tokens with a cosine learning rate schedule. The load-balancing loss applies to the 160 routed experts only; the 2 shared experts are excluded since they process all tokens equally. DeepSeek-V2 demonstrates that this architecture matches or exceeds GPT-4-class performance on most benchmarks while activating only ~9% of total parameters per token, enabling efficient inference on fewer GPUs than a comparable dense model.

```python
import torch
import torch.nn as nn
import torch.nn.functional as F

def shared_moe_training_loss(lm_loss: torch.Tensor,
                              router_logits: torch.Tensor,
                              routed_indices: torch.Tensor,
                              n_routed: int,
                              alpha: float = 1e-2) -> tuple:
    """Training loss for shared-expert MoE: LM loss + aux loss on routed only.
    Shared experts are not included in the load-balancing loss."""
    probs  = F.softmax(router_logits, dim=-1)               # (N, E_routed)
    onehot = F.one_hot(routed_indices[:, 0], n_routed).float()
    f_i    = onehot.mean(0)                                 # fraction dispatched
    P_i    = probs.mean(0)                                  # mean routing prob
    aux    = n_routed * (f_i * P_i).sum()                  # imbalance penalty
    total  = lm_loss + alpha * aux
    return total, {"lm": lm_loss.item(), "aux": (alpha * aux).item()}

# Simulate a training step
torch.manual_seed(0)
lm   = torch.tensor(2.3)                                    # cross-entropy
logits = torch.randn(128, 32)                               # 128 tokens, 32 routed
idx    = torch.topk(logits, 4, dim=-1).indices             # top-4 routing
total, breakdown = shared_moe_training_loss(lm, logits, idx, 32)
print(f"Total: {total.item():.4f}  LM: {breakdown['lm']:.4f}  Aux: {breakdown['aux']:.4f}")
```

## Tradeoffs

Shared experts improve parameter efficiency and routed expert specialisation but introduce additional always-active compute. With N_s=2 shared experts and K_r=6 routed experts, each token activates 8 expert units — equivalent to top-8 routing in a pure sparse MoE. If the goal is to minimise active FLOPs, shared experts consume a fixed overhead that scales with N_s but not with batch size or routing. At inference time, this overhead is constant and predictable, making latency more stable than pure sparse MoE where routing patterns vary by input. However, shared experts also increase memory bandwidth requirements at inference since their weights must be read for every token. The optimal N_s depends on how much universal knowledge exists in the training distribution — typically 1–4 shared experts is sufficient, with diminishing returns beyond that.

```python
import torch
import torch.nn as nn

def ablation_shared_experts(n_shared_list: list, d_model: int = 512,
                            d_ff: int = 1024, n_routed: int = 32,
                            top_k: int = 4) -> None:
    """Ablation: measure total active params per token as n_shared varies."""
    print(f"{'n_shared':>10} {'n_routed':>10} {'top_k':>8} "
          f"{'active_params_M':>17} {'shared_pct':>12}")
    ffn_params = 2 * d_model * d_ff                         # params per expert
    for ns in n_shared_list:
        active = (ns + top_k) * ffn_params
        shared_frac = ns / (ns + top_k) * 100
        print(f"{ns:>10} {n_routed:>10} {top_k:>8} "
              f"{active/1e6:>17.2f} {shared_frac:>11.1f}%")

ablation_shared_experts([0, 1, 2, 4, 8])

# Downstream accuracy proxy: shared=2 typically +0.5-1.5 points vs shared=0
simulated_accuracy = {0: 68.2, 1: 69.1, 2: 69.8, 4: 70.0, 8: 70.1}
print("\nSimulated downstream accuracy vs n_shared:")
for ns, acc in simulated_accuracy.items():
    bar = '|' * int((acc - 68) * 20)
    print(f"  n_shared={ns}: {acc:.1f}  {bar}")
```

> **Common Knowledge Store**: Shared experts act like a 'common knowledge' store — they reduce the pressure on routed experts to cover universal language patterns, allowing routed experts to specialize more deeply in domain-specific knowledge. In DeepSeek-V2, just 2 shared experts (out of 162 total) improve benchmark accuracy by 0.7–1.2 points vs a baseline with 0 shared experts.

## Key Takeaways

Shared experts are a low-cost architectural addition that meaningfully improve MoE quality. By dedicating N_s always-active experts to universal knowledge, routed experts are freed to specialise more narrowly, reducing knowledge redundancy and improving parameter efficiency. The design is clean: the router only scores N_r routed experts; the auxiliary load-balancing loss applies only to routed experts; shared experts add a fixed per-token compute overhead of N_s expert forward passes. DeepSeek-V2 demonstrates that 2 shared experts out of 162 total is sufficient to materially improve quality at the 236B total parameter scale. For most applications, 1–4 shared experts is the practical sweet spot.

- N_s shared experts always activate for every token; their output is summed (not gated)
- Router only covers N_r routed experts; auxiliary loss applies to routed experts only
- Shared experts learn universal patterns; routed experts learn domain-specific specialisations
- Active FLOPs = (N_s + K_r) expert forward passes per token — fixed overhead for shared
- DeepSeek-V2: 2 shared + 6-of-160 routed = 8 active expert units per token, 236B total params
- Optimal N_s is 1–4; beyond 4 shared experts, returns diminish and routing benefit shrinks

