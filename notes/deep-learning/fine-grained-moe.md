---
title: "Fine-Grained Mixture of Experts"
slug: "fine-grained-moe"
description: "Using many small experts instead of few large ones — as in DeepSeek-MoE and MiniMax — to improve expert specialization and routing granularity without increasing computation."
tags: ["deep-learning", "llm"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"Traditional MoE architectures use a small number of large experts — typically 8 or 16, each with the same hidden dimension as a dense FFN. Fine-grained MoE (Dai et al., 2024, DeepSeek-MoE; and subsequent work) challenges this default by splitting each expert into many smaller sub-experts. Instead of 8 experts each with hidden dimension d_ff, fine-grained MoE uses 64 or 128 experts each with hidden dimension d_ff/8. Total parameter count is identical, top-K active FLOPs are identical (routing top-16 of 128 small experts ≈ routing top-2 of 16 large experts), but the granularity of the routing decision is much finer. This finer granularity allows each expert to specialise more narrowly, reducing knowledge redundancy and improving the information efficiency of the parameter budget."},{"type":"heading","level":2,"content":"Overview"},{"type":"text","content":"Fine-grained MoE was introduced in the DeepSeek-MoE paper (Dai et al., 2024) and adopted in DeepSeek-V2 (236B total, 21B active). The key observation is that coarse MoE (8 large experts) forces each expert to be general — it cannot afford to specialise too narrowly because it must process 1/8 of all tokens including many for which it has no expertise. Fine-grained MoE (64–128 small experts) allows each expert to process only 1/64–1/128 of tokens, enabling much tighter specialisation. Routing top-K_r of N_r fine-grained experts (with K_r/N_r = K/N, same active fraction) produces identical compute while gaining routing precision. The practical benefit is measurable improvement in downstream task accuracy at the same FLOPs, with the main cost being more complex routing and load-balancing across many more experts."},{"type":"heading","level":2,"content":"Coarse vs Fine-Grained Experts"},{"type":"text","content":"The fundamental difference between coarse and fine-grained MoE is the granularity of the expert function. A coarse expert with hidden dimension d_ff learns a general transformation that applies to many token types. A fine-grained expert with hidden dimension d_ff/m (for m-fold splitting) learns a narrower transformation that applies to m times fewer tokens on average. The analogy is professional versus generalist: a coarse expert is like a generalist doctor who sees every patient; a fine-grained expert is like a specialist who sees only patients with a specific condition. The specialist can develop much deeper expertise in that narrow domain. The challenge is that with many small experts, the routing decision (which specialist?) becomes more critical — a misrouted token receives a less-applicable transformation."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.nn.functional as F\n\nclass FineGrainedMoELayer(nn.Module):\n    \"\"\"Fine-grained MoE: many small experts vs few large experts.\n    Same total params and same active FLOPs as coarse MoE.\"\"\"\n    def __init__(self, d_model: int, d_ff: int,\n                 n_experts: int, top_k: int):\n        super().__init__()\n        # Each expert has d_ff hidden units (same as coarse)\n        # but n_experts is much larger (e.g., 64 vs 8)\n        self.n_experts, self.top_k = n_experts, top_k\n        self.router  = nn.Linear(d_model, n_experts, bias=False)\n        self.w1 = nn.Parameter(torch.randn(n_experts, d_model, d_ff) * 0.02)\n        self.w2 = nn.Parameter(torch.randn(n_experts, d_ff, d_model) * 0.02)\n\n    def forward(self, x: torch.Tensor) -\u003e torch.Tensor:\n        N, D = x.shape[0] * x.shape[1], x.shape[2]\n        xf   = x.view(N, D)\n        probs, idx = torch.topk(F.softmax(self.router(xf), -1), self.top_k, -1)\n        probs = probs / probs.sum(-1, keepdim=True)\n        out   = torch.zeros_like(xf)\n        for k in range(self.top_k):\n            for e in range(self.n_experts):\n                m = idx[:, k] == e\n                if not m.any(): continue\n                h = F.gelu(xf[m] @ self.w1[e])\n                out[m] += probs[m, k:k+1] * (h @ self.w2[e])\n        return out.view_as(x)\n\n# Coarse: 8 experts, top-2 | Fine-grained: 64 experts, top-16 (same active fraction)\ncoarse = FineGrainedMoELayer(512, 2048, n_experts=8,  top_k=2)\nfine   = FineGrainedMoELayer(512, 2048, n_experts=64, top_k=16)\nprint(f\"Coarse params: {sum(p.numel() for p in coarse.parameters()):,}\")\nprint(f\"Fine   params: {sum(p.numel() for p in fine.parameters()):,}\")"},{"type":"heading","level":2,"content":"DeepSeek-MoE Design"},{"type":"text","content":"DeepSeek-MoE uses N_r=64 fine-grained routed experts (compared to Mixtral\u0027s 8), routing top-K_r=6 per token. Additionally, it adds N_s=2 shared experts that always activate for every token regardless of routing — these handle common knowledge that every token needs. The routing is: output = sum(shared_expert_i(x)) + sum_{k in top-K_r} g_k * E_k(x). The 64 small routed experts together with 2 always-active shared experts give DeepSeek-MoE significantly higher specialisation than a comparable 8-expert model. The paper demonstrates that the fine-grained experts develop more distinct weight matrices (lower cosine similarity between expert weight pairs) and show sharper token routing patterns than coarse experts trained with the same compute budget."},{"type":"code","language":"python","content":"import torch\nimport torch.nn.functional as F\nfrom itertools import combinations\n\ndef measure_knowledge_redundancy(expert_weights: torch.Tensor) -\u003e dict:\n    \"\"\"Measure cosine similarity between expert weight matrices.\n    Lower mean similarity = more specialisation = less redundancy.\n    expert_weights: (n_experts, d_in * d_out) flattened weight vectors.\"\"\"\n    n = expert_weights.shape[0]\n    norms  = F.normalize(expert_weights, dim=-1)            # (E, D)\n    sims   = []\n    for i, j in combinations(range(n), 2):\n        sims.append((norms[i] * norms[j]).sum().item())\n    sims = torch.tensor(sims)\n    return {\"mean_sim\": sims.mean().item(),\n            \"std_sim\":  sims.std().item(),\n            \"max_sim\":  sims.max().item()}\n\n# Simulate random expert weights for coarse (8) vs fine-grained (64)\ntorch.manual_seed(42)\nfor name, n_exp in [(\"coarse-8\", 8), (\"fine-64\", 64)]:\n    W = torch.randn(n_exp, 512 * 128)                      # flatten d_model x d_ff\n    r = measure_knowledge_redundancy(W)\n    print(f\"{name:\u003e10}: mean_sim={r[\u0027mean_sim\u0027]:.4f}  max_sim={r[\u0027max_sim\u0027]:.4f}\")"},{"type":"heading","level":2,"content":"Expert Granularity Tradeoffs"},{"type":"text","content":"Increasing the number of experts while holding total parameters and active FLOPs constant involves genuine tradeoffs. Smaller individual experts have lower hidden dimension (d_ff/m for m-fold split) and therefore lower representational capacity per expert. For very fine-grained experts (m=16, hidden dim reduced 16x), each expert may lack the capacity to learn complex transformations. Additionally, with many experts, routing becomes more critical: the router must correctly assign each token to its most appropriate expert among 64 or 128 options, a harder problem than choosing among 8. This requires the router to develop finer-grained representations and may require longer training to converge. The sweet spot in practice appears to be around 32–128 experts for most model scales, balancing specialisation benefits against per-expert capacity and routing difficulty."},{"type":"table","headers":["Config","N experts","Expert hidden dim","Top-K","Active params (M)","Specialisation"],"rows":[["GShard 2048E","2048","d_ff (full)","2","~2x dense FFN","Very high (but routing hard)"],["Switch-C 2048E","2048","d_ff (full)","1","~1x dense FFN","High"],["Mixtral 8E","8","d_ff (full)","2","~2x dense FFN","Moderate"],["DeepSeek-MoE 64E","64","d_ff/8","6 routed + 2 shared","~1x dense FFN","High"],["Fine-grained 128E","128","d_ff/16","16","~1x dense FFN","Very high"]]},{"type":"heading","level":2,"content":"Routing with Many Experts"},{"type":"text","content":"Routing among 64 or 128 experts introduces new challenges. The router is a linear layer of size d_model × n_experts; at n_experts=128, this is d_model × 128 parameters — still a small fraction of total params. The softmax over 128 logits is more diffuse than over 8, meaning the top-K probability mass is more spread out. This can make the router signal weaker and slower to develop. DeepSeek-MoE addresses this with a normalised top-K selection: after computing the top-K experts, the gating weights are renormalised to sum to 1, sharpening the signal. Additionally, the load-balancing challenge is harder with more experts — ensuring each of 128 experts receives roughly 1/128 of tokens requires stronger regularisation or expert choice routing."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.nn.functional as F\n\nclass DeepSeekMoEStyle(nn.Module):\n    \"\"\"Fine-grained MoE with shared + routed experts (DeepSeek-MoE style).\"\"\"\n    def __init__(self, d_model: int, d_ff: int,\n                 n_shared: int, n_routed: int, top_k: int):\n        super().__init__()\n        self.top_k = top_k\n        self.router = nn.Linear(d_model, n_routed, bias=False)\n        # Shared experts: always active for every token\n        self.shared = nn.ModuleList([\n            nn.Sequential(nn.Linear(d_model, d_ff), nn.GELU(),\n                          nn.Linear(d_ff, d_model)) for _ in range(n_shared)])\n        # Routed experts: fine-grained (smaller d_ff)\n        self.routed = nn.ModuleList([\n            nn.Sequential(nn.Linear(d_model, d_ff), nn.GELU(),\n                          nn.Linear(d_ff, d_model)) for _ in range(n_routed)])\n\n    def forward(self, x: torch.Tensor) -\u003e torch.Tensor:\n        # Shared expert output (always active)\n        shared_out = sum(e(x) for e in self.shared)\n        # Routed expert output (top-K of N_r)\n        N, D  = x.shape[0] * x.shape[1], x.shape[2]\n        xf    = x.view(N, D)\n        probs, idx = torch.topk(F.softmax(self.router(xf), -1), self.top_k, -1)\n        probs = probs / probs.sum(-1, keepdim=True)\n        routed_out = torch.zeros_like(xf)\n        for k in range(self.top_k):\n            for e, expert in enumerate(self.routed):\n                m = idx[:, k] == e\n                if m.any():\n                    routed_out[m] += probs[m, k:k+1] * expert(xf[m])\n        return shared_out + routed_out.view_as(x)\n\nmodel = DeepSeekMoEStyle(512, 256, n_shared=2, n_routed=64, top_k=6)\nprint(model(torch.randn(2, 8, 512)).shape)"},{"type":"heading","level":2,"content":"Knowledge Redundancy"},{"type":"text","content":"A key motivation for fine-grained MoE is reducing knowledge redundancy — the phenomenon where multiple experts in a coarse MoE learn similar functions because they each must cover a broad range of token types. When 8 experts each process 1/8 of tokens and the token distribution is not cleanly separable into 8 clusters, experts must generalise across multiple clusters, leading to overlapping weight matrices. Fine-grained MoE with 64 experts allows each expert to specialise in a tighter cluster, reducing weight matrix overlap. DeepSeek-MoE quantifies this by measuring pairwise cosine similarity between expert weight matrices: fine-grained models show lower mean similarity (more diverse expertise) than coarse models, even at identical total parameter count."},{"type":"callout","variant":"tip","title":"Fine-Grained Specialisation","content":"Fine-grained MoE with 64+ experts typically shows higher expert specialisation — different experts learn syntax vs semantics vs domain knowledge — than coarse MoE with 8 experts. But it requires careful load balancing across many more experts and a router that can distinguish among 64+ options."},{"type":"heading","level":2,"content":"Shared Expert Combination"},{"type":"text","content":"DeepSeek-MoE combines fine-grained routed experts with a small number of always-active shared experts. The shared experts handle common knowledge — patterns that appear in nearly every token type and therefore should not be \u0027wasted\u0027 on routed experts that specialise in narrow domains. By offloading common patterns to shared experts, the routed experts are freed to specialise more aggressively. This is analogous to having generalist staff who handle routine work while specialists focus on complex cases. In practice, 2–4 shared experts are sufficient; more shared experts reduce the specialisation benefit of routing. The load-balancing auxiliary loss is applied only to the routed experts (shared experts activate for all tokens, so they are always perfectly balanced)."},{"type":"code","language":"python","content":"import torch\nimport numpy as np\n\ndef expert_specialisation_sweep(n_experts_list: list, n_tokens: int = 10000,\n                                top_k: int = 2) -\u003e None:\n    \"\"\"Measure routing entropy as a proxy for specialisation across expert counts.\n    Higher entropy per expert = broader coverage = less specialisation.\"\"\"\n    print(f\"{\u0027N experts\u0027:\u003e12} {\u0027expert hidden\u0027:\u003e14} {\u0027top_k\u0027:\u003e7} \"\n          f\"{\u0027active frac\u0027:\u003e12} {\u0027load_cv_est\u0027:\u003e12}\")\n    for n in n_experts_list:\n        # Simulate uniform routing (best case for load balance)\n        counts = torch.zeros(n)\n        for _ in range(n_tokens):\n            chosen = torch.randperm(n)[:top_k]\n            counts[chosen] += 1\n        load = counts / counts.sum()\n        cv   = (load.std() / load.mean()).item()\n        active_frac = top_k / n\n        expert_hidden = f\"d_ff/{n//8}\" if n \u003e= 8 else \"d_ff\"\n        print(f\"{n:\u003e12} {expert_hidden:\u003e14} {top_k:\u003e7} \"\n              f\"{active_frac:\u003e12.3f} {cv:\u003e12.4f}\")\n\nexpert_specialisation_sweep([8, 16, 32, 64, 128], top_k=2)"},{"type":"heading","level":2,"content":"Key Takeaways"},{"type":"text","content":"Fine-grained MoE is an architectural refinement that improves expert specialisation without changing total parameter count or active FLOPs. By splitting each of N coarse experts into m fine-grained experts and increasing top-K proportionally, the active computation budget stays the same while the routing precision improves dramatically. DeepSeek-MoE demonstrates that 64 fine-grained routed experts plus 2 shared experts outperform 8 coarse experts at the same FLOPs on downstream benchmarks. The main costs are increased routing complexity, harder load balancing across more experts, and potentially weaker per-expert capacity if expert hidden dimension becomes too small. The optimal granularity depends on model scale and training data diversity."},{"type":"list","ordered":false,"items":["Fine-grained MoE: many small experts (64–128) vs few large ones (8–16), same total params and FLOPs","Experts specialise more narrowly, reducing weight matrix cosine similarity (knowledge redundancy)","DeepSeek-MoE uses 64 routed + 2 shared experts; routes top-6 routed experts per token","Load balancing is harder across 64+ experts — use stronger aux loss or expert choice routing","Shared experts handle common patterns; frees routed experts to specialise more aggressively","Sweet spot: 32–128 experts for typical LLM scales; beyond 256 routing quality degrades"]}]"
---
# Fine-Grained Mixture of Experts

Traditional MoE architectures use a small number of large experts — typically 8 or 16, each with the same hidden dimension as a dense FFN. Fine-grained MoE (Dai et al., 2024, DeepSeek-MoE; and subsequent work) challenges this default by splitting each expert into many smaller sub-experts. Instead of 8 experts each with hidden dimension d_ff, fine-grained MoE uses 64 or 128 experts each with hidden dimension d_ff/8. Total parameter count is identical, top-K active FLOPs are identical (routing top-16 of 128 small experts ≈ routing top-2 of 16 large experts), but the granularity of the routing decision is much finer. This finer granularity allows each expert to specialise more narrowly, reducing knowledge redundancy and improving the information efficiency of the parameter budget.

## Overview

Fine-grained MoE was introduced in the DeepSeek-MoE paper (Dai et al., 2024) and adopted in DeepSeek-V2 (236B total, 21B active). The key observation is that coarse MoE (8 large experts) forces each expert to be general — it cannot afford to specialise too narrowly because it must process 1/8 of all tokens including many for which it has no expertise. Fine-grained MoE (64–128 small experts) allows each expert to process only 1/64–1/128 of tokens, enabling much tighter specialisation. Routing top-K_r of N_r fine-grained experts (with K_r/N_r = K/N, same active fraction) produces identical compute while gaining routing precision. The practical benefit is measurable improvement in downstream task accuracy at the same FLOPs, with the main cost being more complex routing and load-balancing across many more experts.

## Coarse vs Fine-Grained Experts

The fundamental difference between coarse and fine-grained MoE is the granularity of the expert function. A coarse expert with hidden dimension d_ff learns a general transformation that applies to many token types. A fine-grained expert with hidden dimension d_ff/m (for m-fold splitting) learns a narrower transformation that applies to m times fewer tokens on average. The analogy is professional versus generalist: a coarse expert is like a generalist doctor who sees every patient; a fine-grained expert is like a specialist who sees only patients with a specific condition. The specialist can develop much deeper expertise in that narrow domain. The challenge is that with many small experts, the routing decision (which specialist?) becomes more critical — a misrouted token receives a less-applicable transformation.

```python
import torch
import torch.nn as nn
import torch.nn.functional as F

class FineGrainedMoELayer(nn.Module):
    """Fine-grained MoE: many small experts vs few large experts.
    Same total params and same active FLOPs as coarse MoE."""
    def __init__(self, d_model: int, d_ff: int,
                 n_experts: int, top_k: int):
        super().__init__()
        # Each expert has d_ff hidden units (same as coarse)
        # but n_experts is much larger (e.g., 64 vs 8)
        self.n_experts, self.top_k = n_experts, top_k
        self.router  = nn.Linear(d_model, n_experts, bias=False)
        self.w1 = nn.Parameter(torch.randn(n_experts, d_model, d_ff) * 0.02)
        self.w2 = nn.Parameter(torch.randn(n_experts, d_ff, d_model) * 0.02)

    def forward(self, x: torch.Tensor) -> torch.Tensor:
        N, D = x.shape[0] * x.shape[1], x.shape[2]
        xf   = x.view(N, D)
        probs, idx = torch.topk(F.softmax(self.router(xf), -1), self.top_k, -1)
        probs = probs / probs.sum(-1, keepdim=True)
        out   = torch.zeros_like(xf)
        for k in range(self.top_k):
            for e in range(self.n_experts):
                m = idx[:, k] == e
                if not m.any(): continue
                h = F.gelu(xf[m] @ self.w1[e])
                out[m] += probs[m, k:k+1] * (h @ self.w2[e])
        return out.view_as(x)

# Coarse: 8 experts, top-2 | Fine-grained: 64 experts, top-16 (same active fraction)
coarse = FineGrainedMoELayer(512, 2048, n_experts=8,  top_k=2)
fine   = FineGrainedMoELayer(512, 2048, n_experts=64, top_k=16)
print(f"Coarse params: {sum(p.numel() for p in coarse.parameters()):,}")
print(f"Fine   params: {sum(p.numel() for p in fine.parameters()):,}")
```

## DeepSeek-MoE Design

DeepSeek-MoE uses N_r=64 fine-grained routed experts (compared to Mixtral's 8), routing top-K_r=6 per token. Additionally, it adds N_s=2 shared experts that always activate for every token regardless of routing — these handle common knowledge that every token needs. The routing is: output = sum(shared_expert_i(x)) + sum_{k in top-K_r} g_k * E_k(x). The 64 small routed experts together with 2 always-active shared experts give DeepSeek-MoE significantly higher specialisation than a comparable 8-expert model. The paper demonstrates that the fine-grained experts develop more distinct weight matrices (lower cosine similarity between expert weight pairs) and show sharper token routing patterns than coarse experts trained with the same compute budget.

```python
import torch
import torch.nn.functional as F
from itertools import combinations

def measure_knowledge_redundancy(expert_weights: torch.Tensor) -> dict:
    """Measure cosine similarity between expert weight matrices.
    Lower mean similarity = more specialisation = less redundancy.
    expert_weights: (n_experts, d_in * d_out) flattened weight vectors."""
    n = expert_weights.shape[0]
    norms  = F.normalize(expert_weights, dim=-1)            # (E, D)
    sims   = []
    for i, j in combinations(range(n), 2):
        sims.append((norms[i] * norms[j]).sum().item())
    sims = torch.tensor(sims)
    return {"mean_sim": sims.mean().item(),
            "std_sim":  sims.std().item(),
            "max_sim":  sims.max().item()}

# Simulate random expert weights for coarse (8) vs fine-grained (64)
torch.manual_seed(42)
for name, n_exp in [("coarse-8", 8), ("fine-64", 64)]:
    W = torch.randn(n_exp, 512 * 128)                      # flatten d_model x d_ff
    r = measure_knowledge_redundancy(W)
    print(f"{name:>10}: mean_sim={r['mean_sim']:.4f}  max_sim={r['max_sim']:.4f}")
```

## Expert Granularity Tradeoffs

Increasing the number of experts while holding total parameters and active FLOPs constant involves genuine tradeoffs. Smaller individual experts have lower hidden dimension (d_ff/m for m-fold split) and therefore lower representational capacity per expert. For very fine-grained experts (m=16, hidden dim reduced 16x), each expert may lack the capacity to learn complex transformations. Additionally, with many experts, routing becomes more critical: the router must correctly assign each token to its most appropriate expert among 64 or 128 options, a harder problem than choosing among 8. This requires the router to develop finer-grained representations and may require longer training to converge. The sweet spot in practice appears to be around 32–128 experts for most model scales, balancing specialisation benefits against per-expert capacity and routing difficulty.

| Config | N experts | Expert hidden dim | Top-K | Active params (M) | Specialisation |
| --- | --- | --- | --- | --- | --- |
| GShard 2048E | 2048 | d_ff (full) | 2 | ~2x dense FFN | Very high (but routing hard) |
| Switch-C 2048E | 2048 | d_ff (full) | 1 | ~1x dense FFN | High |
| Mixtral 8E | 8 | d_ff (full) | 2 | ~2x dense FFN | Moderate |
| DeepSeek-MoE 64E | 64 | d_ff/8 | 6 routed + 2 shared | ~1x dense FFN | High |
| Fine-grained 128E | 128 | d_ff/16 | 16 | ~1x dense FFN | Very high |

## Routing with Many Experts

Routing among 64 or 128 experts introduces new challenges. The router is a linear layer of size d_model × n_experts; at n_experts=128, this is d_model × 128 parameters — still a small fraction of total params. The softmax over 128 logits is more diffuse than over 8, meaning the top-K probability mass is more spread out. This can make the router signal weaker and slower to develop. DeepSeek-MoE addresses this with a normalised top-K selection: after computing the top-K experts, the gating weights are renormalised to sum to 1, sharpening the signal. Additionally, the load-balancing challenge is harder with more experts — ensuring each of 128 experts receives roughly 1/128 of tokens requires stronger regularisation or expert choice routing.

```python
import torch
import torch.nn as nn
import torch.nn.functional as F

class DeepSeekMoEStyle(nn.Module):
    """Fine-grained MoE with shared + routed experts (DeepSeek-MoE style)."""
    def __init__(self, d_model: int, d_ff: int,
                 n_shared: int, n_routed: int, top_k: int):
        super().__init__()
        self.top_k = top_k
        self.router = nn.Linear(d_model, n_routed, bias=False)
        # Shared experts: always active for every token
        self.shared = nn.ModuleList([
            nn.Sequential(nn.Linear(d_model, d_ff), nn.GELU(),
                          nn.Linear(d_ff, d_model)) for _ in range(n_shared)])
        # Routed experts: fine-grained (smaller d_ff)
        self.routed = nn.ModuleList([
            nn.Sequential(nn.Linear(d_model, d_ff), nn.GELU(),
                          nn.Linear(d_ff, d_model)) for _ in range(n_routed)])

    def forward(self, x: torch.Tensor) -> torch.Tensor:
        # Shared expert output (always active)
        shared_out = sum(e(x) for e in self.shared)
        # Routed expert output (top-K of N_r)
        N, D  = x.shape[0] * x.shape[1], x.shape[2]
        xf    = x.view(N, D)
        probs, idx = torch.topk(F.softmax(self.router(xf), -1), self.top_k, -1)
        probs = probs / probs.sum(-1, keepdim=True)
        routed_out = torch.zeros_like(xf)
        for k in range(self.top_k):
            for e, expert in enumerate(self.routed):
                m = idx[:, k] == e
                if m.any():
                    routed_out[m] += probs[m, k:k+1] * expert(xf[m])
        return shared_out + routed_out.view_as(x)

model = DeepSeekMoEStyle(512, 256, n_shared=2, n_routed=64, top_k=6)
print(model(torch.randn(2, 8, 512)).shape)
```

## Knowledge Redundancy

A key motivation for fine-grained MoE is reducing knowledge redundancy — the phenomenon where multiple experts in a coarse MoE learn similar functions because they each must cover a broad range of token types. When 8 experts each process 1/8 of tokens and the token distribution is not cleanly separable into 8 clusters, experts must generalise across multiple clusters, leading to overlapping weight matrices. Fine-grained MoE with 64 experts allows each expert to specialise in a tighter cluster, reducing weight matrix overlap. DeepSeek-MoE quantifies this by measuring pairwise cosine similarity between expert weight matrices: fine-grained models show lower mean similarity (more diverse expertise) than coarse models, even at identical total parameter count.

> **Fine-Grained Specialisation**: Fine-grained MoE with 64+ experts typically shows higher expert specialisation — different experts learn syntax vs semantics vs domain knowledge — than coarse MoE with 8 experts. But it requires careful load balancing across many more experts and a router that can distinguish among 64+ options.

## Shared Expert Combination

DeepSeek-MoE combines fine-grained routed experts with a small number of always-active shared experts. The shared experts handle common knowledge — patterns that appear in nearly every token type and therefore should not be 'wasted' on routed experts that specialise in narrow domains. By offloading common patterns to shared experts, the routed experts are freed to specialise more aggressively. This is analogous to having generalist staff who handle routine work while specialists focus on complex cases. In practice, 2–4 shared experts are sufficient; more shared experts reduce the specialisation benefit of routing. The load-balancing auxiliary loss is applied only to the routed experts (shared experts activate for all tokens, so they are always perfectly balanced).

```python
import torch
import numpy as np

def expert_specialisation_sweep(n_experts_list: list, n_tokens: int = 10000,
                                top_k: int = 2) -> None:
    """Measure routing entropy as a proxy for specialisation across expert counts.
    Higher entropy per expert = broader coverage = less specialisation."""
    print(f"{'N experts':>12} {'expert hidden':>14} {'top_k':>7} "
          f"{'active frac':>12} {'load_cv_est':>12}")
    for n in n_experts_list:
        # Simulate uniform routing (best case for load balance)
        counts = torch.zeros(n)
        for _ in range(n_tokens):
            chosen = torch.randperm(n)[:top_k]
            counts[chosen] += 1
        load = counts / counts.sum()
        cv   = (load.std() / load.mean()).item()
        active_frac = top_k / n
        expert_hidden = f"d_ff/{n//8}" if n >= 8 else "d_ff"
        print(f"{n:>12} {expert_hidden:>14} {top_k:>7} "
              f"{active_frac:>12.3f} {cv:>12.4f}")

expert_specialisation_sweep([8, 16, 32, 64, 128], top_k=2)
```

## Key Takeaways

Fine-grained MoE is an architectural refinement that improves expert specialisation without changing total parameter count or active FLOPs. By splitting each of N coarse experts into m fine-grained experts and increasing top-K proportionally, the active computation budget stays the same while the routing precision improves dramatically. DeepSeek-MoE demonstrates that 64 fine-grained routed experts plus 2 shared experts outperform 8 coarse experts at the same FLOPs on downstream benchmarks. The main costs are increased routing complexity, harder load balancing across more experts, and potentially weaker per-expert capacity if expert hidden dimension becomes too small. The optimal granularity depends on model scale and training data diversity.

- Fine-grained MoE: many small experts (64–128) vs few large ones (8–16), same total params and FLOPs
- Experts specialise more narrowly, reducing weight matrix cosine similarity (knowledge redundancy)
- DeepSeek-MoE uses 64 routed + 2 shared experts; routes top-6 routed experts per token
- Load balancing is harder across 64+ experts — use stronger aux loss or expert choice routing
- Shared experts handle common patterns; frees routed experts to specialise more aggressively
- Sweet spot: 32–128 experts for typical LLM scales; beyond 256 routing quality degrades

