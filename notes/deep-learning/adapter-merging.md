---
title: "Adapter Merging — TIES, DARE, and Model Soup for Combining Fine-Tuned Models"
slug: "adapter-merging"
description: "Combine multiple fine-tuned models or adapters without additional training. Covers model soup weight averaging, TIES merging (trim, elect, disjoint merge), DARE random delta dropping, SLERP spherical interpolation, and LoRA merging in weight space."
tags: ["deep-learning", "llm"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"Model merging combines the capabilities of multiple fine-tuned models — or adapters — into a single model without any additional training. Instead of multi-task training from scratch, you start with task-specific fine-tunes and merge their weights. The resulting model inherits capabilities from all source models while requiring only a single inference deployment. Merging is especially useful with LoRA adapters: you can fine-tune dozens of specializations cheaply and merge the best subset on demand."},{"type":"heading","level":2,"content":"Why Merge Models Instead of Training Multi-Task"},{"type":"text","content":"Multi-task training requires all task data simultaneously, careful loss balancing, and is prone to task interference — where learning one task degrades another. Merging avoids these problems: each model is trained independently to its optimum, then combined. The merged model is also easy to update: swap one task\u0027s fine-tune for a newer version and re-merge rather than re-running the entire multi-task pipeline. Weight interpolation θ_merged = Σ αᵢθᵢ is the simplest form, with Σ αᵢ = 1 ensuring the merged model stays in the same weight magnitude regime as the originals."},{"type":"heading","level":2,"content":"Model Soup — Weight Averaging"},{"type":"text","content":"Model soup (Wortsman et al., 2022) averages the weights of models fine-tuned from the same pretrained base, typically with different hyperparameters or data augmentation seeds. The average outperforms any individual model on the held-out evaluation, because different fine-tunes explore different loss basin regions and their average lands in a flatter, higher-accuracy basin. The key constraint is that all models must be fine-tuned from the same pretrained checkpoint — averaging weights from different initializations produces incoherent results."},{"type":"code","language":"python","content":"import torch\nfrom collections import OrderedDict\n\ndef model_soup(base_state_dict, finetuned_state_dicts, weights=None):\n    \"\"\"Average weights from multiple fine-tuned models (model soup).\"\"\"\n    n = len(finetuned_state_dicts)\n    if weights is None:\n        weights = [1.0 / n] * n\n    assert abs(sum(weights) - 1.0) \u003c 1e-6, \"Weights must sum to 1\"\n    soup = OrderedDict()\n    for key in base_state_dict:\n        soup[key] = sum(\n            w * sd[key].float() for w, sd in zip(weights, finetuned_state_dicts)\n        )\n    return soup\n\n# Demo: simulate 3 fine-tuned checkpoints from same pretrained base\ntorch.manual_seed(42)\nbase = {\"enc.w\": torch.zeros(4, 4), \"head.w\": torch.zeros(4)}\nft_models = [\n    {\"enc.w\": base[\"enc.w\"] + torch.randn(4, 4) * 0.1,\n     \"head.w\": base[\"head.w\"] + torch.randn(4) * 0.1}\n    for _ in range(3)\n]\nsoup_sd = model_soup(base, ft_models)\nprint(f\"Soup weight norm (enc): {soup_sd[\u0027enc.w\u0027].norm():.4f}\")\nfor i, ft in enumerate(ft_models):\n    print(f\"Model {i+1} weight norm: {ft[\u0027enc.w\u0027].norm():.4f}\")\nprint(\"Soup averages across all fine-tuned checkpoints — lands in a flatter loss basin.\")"},{"type":"heading","level":2,"content":"TIES Merging — Trim, Elect, Disjoint Merge"},{"type":"text","content":"Simple weight averaging fails when models are fine-tuned on very different tasks, because opposing weight updates cancel each other out — a weight pushed positive by task A and negative by task B averages to near zero, losing both capabilities. TIES merging (Yadav et al., 2023) solves this with three steps: (1) Trim — set task vector deltas with small magnitude to zero, keeping only the top-k% by magnitude; (2) Elect — for each parameter, determine the dominant sign across all task vectors by majority vote; (3) Disjoint Merge — average only the parameters whose sign agrees with the elected sign, excluding conflicting updates."},{"type":"code","language":"python","content":"import torch\nfrom collections import OrderedDict\n\ndef ties_merge(task_vectors, base_state_dict, top_k=0.2, scale=1.0):\n    \"\"\"TIES merging: Trim, Elect, Disjoint Merge over task vector deltas.\"\"\"\n    merged = OrderedDict()\n    for key in base_state_dict:\n        deltas = torch.stack([tv[key].float() for tv in task_vectors], dim=0)  # (n, ...)\n        # Step 1: Trim — zero out small deltas, keep top-k% by magnitude\n        threshold = deltas.abs().quantile(1.0 - top_k, dim=0, keepdim=True)\n        trimmed = torch.where(deltas.abs() \u003e= threshold, deltas, torch.zeros_like(deltas))\n        # Step 2: Elect — majority vote on sign per parameter\n        sign_sum = trimmed.sign().sum(dim=0)\n        elected_sign = torch.where(sign_sum \u003e= 0,\n                                   torch.ones_like(sign_sum),\n                                   -torch.ones_like(sign_sum))\n        # Step 3: Disjoint Merge — average only parameters that agree with elected sign\n        agree = (trimmed.sign() == elected_sign.unsqueeze(0)) | (trimmed == 0)\n        agreed = trimmed * agree.float()\n        n_agree = agree.float().sum(dim=0).clamp(min=1)\n        merged[key] = base_state_dict[key].float() + scale * agreed.sum(dim=0) / n_agree\n    return merged\n\ntorch.manual_seed(0)\nbase = {\"w\": torch.zeros(6)}\ntvs = [{\"w\": torch.tensor([0.5, -0.3, 0.2, -0.1, 0.4, 0.0])},\n       {\"w\": torch.tensor([-0.2, 0.4, 0.3, 0.2, -0.1, 0.5])},\n       {\"w\": torch.tensor([0.3, 0.1, -0.2, 0.4, 0.3, -0.2])}]\nresult = ties_merge(tvs, base, top_k=0.5)\nprint(f\"TIES merged: {[round(v,3) for v in result[\u0027w\u0027].tolist()]}\")\nprint(\"Sign conflicts resolved; destructive interference eliminated.\")"},{"type":"heading","level":2,"content":"DARE — Random Delta Dropping"},{"type":"text","content":"DARE (Yu et al., 2023) addresses inter-model interference by randomly dropping task vector deltas before merging — analogous to dropout applied to weight differences rather than activations. Each delta element is dropped independently with probability p, and surviving elements are rescaled by 1/(1-p) to maintain the expected magnitude. This stochastic pruning reduces the number of conflicts between task vectors, especially for parameters where two models learned opposing updates. DARE can be combined with TIES for further improvement."},{"type":"code","language":"python","content":"import torch\nfrom collections import OrderedDict\n\ndef dare_merge(task_vectors, base_state_dict, drop_rate=0.5, scale=1.0, seed=42):\n    \"\"\"DARE: randomly drop task vector deltas, rescale, apply to base model.\"\"\"\n    torch.manual_seed(seed)\n    merged = OrderedDict()\n    for key in base_state_dict:\n        deltas = torch.stack([tv[key].float() for tv in task_vectors], dim=0)\n        # Randomly drop each delta element with probability drop_rate\n        keep_mask = (torch.rand_like(deltas) \u003e drop_rate).float()\n        # Rescale to maintain expected magnitude\n        rescaled = deltas * keep_mask / (1.0 - drop_rate + 1e-8)\n        merged[key] = base_state_dict[key].float() + scale * rescaled.mean(dim=0)\n    return merged\n\nbase = {\"w\": torch.zeros(8)}\ntvs = [\n    {\"w\": torch.tensor([0.4, -0.3, 0.5, -0.2, 0.1, 0.6, -0.4, 0.3])},\n    {\"w\": torch.tensor([-0.2, 0.5, -0.3, 0.4, -0.5, 0.2, 0.3, -0.1])},\n]\nfor drop in [0.0, 0.3, 0.5, 0.7]:\n    result = dare_merge(tvs, base, drop_rate=drop)\n    print(f\"drop_rate={drop:.1f}: merged norm={result[\u0027w\u0027].norm():.4f}  \"\n          f\"values={[round(v,2) for v in result[\u0027w\u0027].tolist()]}\")\nprint(\"DARE reduces interference; higher drop_rate means more regularization.\")"},{"type":"heading","level":2,"content":"SLERP — Spherical Linear Interpolation"},{"type":"text","content":"Linear interpolation between two model weight sets (LERP) travels in a straight line through parameter space, potentially passing through low-quality regions near the center. SLERP (Spherical Linear Interpolation) interpolates along the geodesic on the unit sphere: it maintains constant angular velocity and constant magnitude along the interpolation path. For two models θ₁ and θ₂ with angle ω between them, SLERP at interpolation parameter t returns sin((1-t)ω)/sin(ω) · θ₁ + sin(tω)/sin(ω) · θ₂. When ω ≈ 0 (nearly parallel), SLERP degenerates to LERP."},{"type":"code","language":"python","content":"import torch\nfrom collections import OrderedDict\n\ndef slerp(theta1, theta2, t=0.5):\n    \"\"\"Spherical Linear Interpolation between two model weight sets.\"\"\"\n    merged = OrderedDict()\n    for key in theta1:\n        v0 = theta1[key].float().flatten()\n        v1 = theta2[key].float().flatten()\n        v0_norm = v0 / (v0.norm() + 1e-8)\n        v1_norm = v1 / (v1.norm() + 1e-8)\n        dot = torch.clamp((v0_norm * v1_norm).sum(), -1.0, 1.0)\n        omega = torch.acos(dot)\n        if omega.abs() \u003c 1e-6:\n            # Vectors nearly parallel: fall back to linear interpolation\n            merged[key] = ((1 - t) * theta1[key].float() + t * theta2[key].float())\n        else:\n            s = torch.sin(omega)\n            merged[key] = (\n                (torch.sin((1 - t) * omega) / s) * v0 +\n                (torch.sin(t * omega) / s) * v1\n            ).reshape(theta1[key].shape)\n    return merged\n\ntorch.manual_seed(1)\nm1 = {\"enc\": torch.randn(4, 4), \"head\": torch.randn(2, 4)}\nm2 = {\"enc\": torch.randn(4, 4), \"head\": torch.randn(2, 4)}\nfor t_val in [0.0, 0.25, 0.5, 0.75, 1.0]:\n    blended = slerp(m1, m2, t=t_val)\n    enc_norm = blended[\"enc\"].norm().item()\n    print(f\"t={t_val}: enc_norm={enc_norm:.4f}\")\nprint(\"SLERP traces constant-speed path on unit sphere; LERP cuts through center.\")"},{"type":"heading","level":2,"content":"LoRA Merging in Weight Space vs Adapter Space"},{"type":"text","content":"LoRA adapters can be merged at two levels. In adapter space, the LoRA matrices A and B are averaged or combined before computing the update Δ W = BA. In weight space, each adapter\u0027s full weight update Δ Wᵢ = BᵢAᵢ is computed first, then the full-rank updates are merged (e.g., via TIES or DARE). Weight-space merging is more flexible — you can apply any merging algorithm — but loses the low-rank structure. Adapter-space merging preserves low rank but is limited to methods that operate on the factored matrices. For task arithmetic and TIES/DARE, weight-space merging is standard."},{"type":"heading","level":2,"content":"Practical Guidelines and Method Comparison"},{"type":"list","ordered":false,"items":["Model soup: use when merging checkpoints from the same training run with different hyperparameters or data seeds.","TIES: preferred when merging models fine-tuned on very different tasks — sign conflict resolution prevents destructive interference.","DARE: add when merging many models (4+); the random dropping reduces pairwise interference without needing explicit sign resolution.","SLERP: best for merging exactly two models when magnitude preservation matters (e.g., instruction-tuned + DPO-tuned versions).","Task arithmetic: use when you want additive composition — each task vector contributes independently with a tunable scale λ.","All methods require fine-tuning from the same pretrained base to avoid catastrophic interference from mismatched feature spaces."]},{"type":"table","headers":["Method","Conflict Resolution","Parameter Count","Quality vs Individual","Compute Cost","Best For"],"rows":[["Model Soup","None (simple average)","Same as one model","Better (flatter basin)","Trivial — one pass","Same-task hyperparameter ensembling"],["Task Arithmetic","None (additive)","Same as one model","Comparable at low scale","Trivial — vector add","Additive multi-task composition"],["TIES","Sign majority vote per param","Same as one model","Better than soup for cross-task","Low — one trimming pass","Different-task merging, up to ~8 models"],["DARE","Stochastic drop + rescale","Same as one model","Good for many models","Low — random mask","Merging 4+ models, high interference"],["SLERP","None (geodesic path)","Same as one model","Best for 2-model blend","Low — per-layer trig","Two-model interpolation, magnitude-sensitive"]]},{"type":"callout","variant":"tip","title":"TIES Outperforms Simple Averaging for Cross-Task Merging","content":"TIES merging outperforms simple weight averaging when merging models fine-tuned on very different tasks — the sign conflict resolution step prevents destructive interference between opposing weight updates that degrade both tasks. Use top-k=0.2 (keep 20% of deltas) as a starting point; larger k retains more task signal but increases interference. For LoRA merging, merge in weight space (compute BA first) so TIES can see the full-rank updates."},{"type":"divider"}]"
---
# Adapter Merging — TIES, DARE, and Model Soup for Combining Fine-Tuned Models

Model merging combines the capabilities of multiple fine-tuned models — or adapters — into a single model without any additional training. Instead of multi-task training from scratch, you start with task-specific fine-tunes and merge their weights. The resulting model inherits capabilities from all source models while requiring only a single inference deployment. Merging is especially useful with LoRA adapters: you can fine-tune dozens of specializations cheaply and merge the best subset on demand.

## Why Merge Models Instead of Training Multi-Task

Multi-task training requires all task data simultaneously, careful loss balancing, and is prone to task interference — where learning one task degrades another. Merging avoids these problems: each model is trained independently to its optimum, then combined. The merged model is also easy to update: swap one task's fine-tune for a newer version and re-merge rather than re-running the entire multi-task pipeline. Weight interpolation θ_merged = Σ αᵢθᵢ is the simplest form, with Σ αᵢ = 1 ensuring the merged model stays in the same weight magnitude regime as the originals.

## Model Soup — Weight Averaging

Model soup (Wortsman et al., 2022) averages the weights of models fine-tuned from the same pretrained base, typically with different hyperparameters or data augmentation seeds. The average outperforms any individual model on the held-out evaluation, because different fine-tunes explore different loss basin regions and their average lands in a flatter, higher-accuracy basin. The key constraint is that all models must be fine-tuned from the same pretrained checkpoint — averaging weights from different initializations produces incoherent results.

```python
import torch
from collections import OrderedDict

def model_soup(base_state_dict, finetuned_state_dicts, weights=None):
    """Average weights from multiple fine-tuned models (model soup)."""
    n = len(finetuned_state_dicts)
    if weights is None:
        weights = [1.0 / n] * n
    assert abs(sum(weights) - 1.0) < 1e-6, "Weights must sum to 1"
    soup = OrderedDict()
    for key in base_state_dict:
        soup[key] = sum(
            w * sd[key].float() for w, sd in zip(weights, finetuned_state_dicts)
        )
    return soup

# Demo: simulate 3 fine-tuned checkpoints from same pretrained base
torch.manual_seed(42)
base = {"enc.w": torch.zeros(4, 4), "head.w": torch.zeros(4)}
ft_models = [
    {"enc.w": base["enc.w"] + torch.randn(4, 4) * 0.1,
     "head.w": base["head.w"] + torch.randn(4) * 0.1}
    for _ in range(3)
]
soup_sd = model_soup(base, ft_models)
print(f"Soup weight norm (enc): {soup_sd['enc.w'].norm():.4f}")
for i, ft in enumerate(ft_models):
    print(f"Model {i+1} weight norm: {ft['enc.w'].norm():.4f}")
print("Soup averages across all fine-tuned checkpoints — lands in a flatter loss basin.")
```

## TIES Merging — Trim, Elect, Disjoint Merge

Simple weight averaging fails when models are fine-tuned on very different tasks, because opposing weight updates cancel each other out — a weight pushed positive by task A and negative by task B averages to near zero, losing both capabilities. TIES merging (Yadav et al., 2023) solves this with three steps: (1) Trim — set task vector deltas with small magnitude to zero, keeping only the top-k% by magnitude; (2) Elect — for each parameter, determine the dominant sign across all task vectors by majority vote; (3) Disjoint Merge — average only the parameters whose sign agrees with the elected sign, excluding conflicting updates.

```python
import torch
from collections import OrderedDict

def ties_merge(task_vectors, base_state_dict, top_k=0.2, scale=1.0):
    """TIES merging: Trim, Elect, Disjoint Merge over task vector deltas."""
    merged = OrderedDict()
    for key in base_state_dict:
        deltas = torch.stack([tv[key].float() for tv in task_vectors], dim=0)  # (n, ...)
        # Step 1: Trim — zero out small deltas, keep top-k% by magnitude
        threshold = deltas.abs().quantile(1.0 - top_k, dim=0, keepdim=True)
        trimmed = torch.where(deltas.abs() >= threshold, deltas, torch.zeros_like(deltas))
        # Step 2: Elect — majority vote on sign per parameter
        sign_sum = trimmed.sign().sum(dim=0)
        elected_sign = torch.where(sign_sum >= 0,
                                   torch.ones_like(sign_sum),
                                   -torch.ones_like(sign_sum))
        # Step 3: Disjoint Merge — average only parameters that agree with elected sign
        agree = (trimmed.sign() == elected_sign.unsqueeze(0)) | (trimmed == 0)
        agreed = trimmed * agree.float()
        n_agree = agree.float().sum(dim=0).clamp(min=1)
        merged[key] = base_state_dict[key].float() + scale * agreed.sum(dim=0) / n_agree
    return merged

torch.manual_seed(0)
base = {"w": torch.zeros(6)}
tvs = [{"w": torch.tensor([0.5, -0.3, 0.2, -0.1, 0.4, 0.0])},
       {"w": torch.tensor([-0.2, 0.4, 0.3, 0.2, -0.1, 0.5])},
       {"w": torch.tensor([0.3, 0.1, -0.2, 0.4, 0.3, -0.2])}]
result = ties_merge(tvs, base, top_k=0.5)
print(f"TIES merged: {[round(v,3) for v in result['w'].tolist()]}")
print("Sign conflicts resolved; destructive interference eliminated.")
```

## DARE — Random Delta Dropping

DARE (Yu et al., 2023) addresses inter-model interference by randomly dropping task vector deltas before merging — analogous to dropout applied to weight differences rather than activations. Each delta element is dropped independently with probability p, and surviving elements are rescaled by 1/(1-p) to maintain the expected magnitude. This stochastic pruning reduces the number of conflicts between task vectors, especially for parameters where two models learned opposing updates. DARE can be combined with TIES for further improvement.

```python
import torch
from collections import OrderedDict

def dare_merge(task_vectors, base_state_dict, drop_rate=0.5, scale=1.0, seed=42):
    """DARE: randomly drop task vector deltas, rescale, apply to base model."""
    torch.manual_seed(seed)
    merged = OrderedDict()
    for key in base_state_dict:
        deltas = torch.stack([tv[key].float() for tv in task_vectors], dim=0)
        # Randomly drop each delta element with probability drop_rate
        keep_mask = (torch.rand_like(deltas) > drop_rate).float()
        # Rescale to maintain expected magnitude
        rescaled = deltas * keep_mask / (1.0 - drop_rate + 1e-8)
        merged[key] = base_state_dict[key].float() + scale * rescaled.mean(dim=0)
    return merged

base = {"w": torch.zeros(8)}
tvs = [
    {"w": torch.tensor([0.4, -0.3, 0.5, -0.2, 0.1, 0.6, -0.4, 0.3])},
    {"w": torch.tensor([-0.2, 0.5, -0.3, 0.4, -0.5, 0.2, 0.3, -0.1])},
]
for drop in [0.0, 0.3, 0.5, 0.7]:
    result = dare_merge(tvs, base, drop_rate=drop)
    print(f"drop_rate={drop:.1f}: merged norm={result['w'].norm():.4f}  "
          f"values={[round(v,2) for v in result['w'].tolist()]}")
print("DARE reduces interference; higher drop_rate means more regularization.")
```

## SLERP — Spherical Linear Interpolation

Linear interpolation between two model weight sets (LERP) travels in a straight line through parameter space, potentially passing through low-quality regions near the center. SLERP (Spherical Linear Interpolation) interpolates along the geodesic on the unit sphere: it maintains constant angular velocity and constant magnitude along the interpolation path. For two models θ₁ and θ₂ with angle ω between them, SLERP at interpolation parameter t returns sin((1-t)ω)/sin(ω) · θ₁ + sin(tω)/sin(ω) · θ₂. When ω ≈ 0 (nearly parallel), SLERP degenerates to LERP.

```python
import torch
from collections import OrderedDict

def slerp(theta1, theta2, t=0.5):
    """Spherical Linear Interpolation between two model weight sets."""
    merged = OrderedDict()
    for key in theta1:
        v0 = theta1[key].float().flatten()
        v1 = theta2[key].float().flatten()
        v0_norm = v0 / (v0.norm() + 1e-8)
        v1_norm = v1 / (v1.norm() + 1e-8)
        dot = torch.clamp((v0_norm * v1_norm).sum(), -1.0, 1.0)
        omega = torch.acos(dot)
        if omega.abs() < 1e-6:
            # Vectors nearly parallel: fall back to linear interpolation
            merged[key] = ((1 - t) * theta1[key].float() + t * theta2[key].float())
        else:
            s = torch.sin(omega)
            merged[key] = (
                (torch.sin((1 - t) * omega) / s) * v0 +
                (torch.sin(t * omega) / s) * v1
            ).reshape(theta1[key].shape)
    return merged

torch.manual_seed(1)
m1 = {"enc": torch.randn(4, 4), "head": torch.randn(2, 4)}
m2 = {"enc": torch.randn(4, 4), "head": torch.randn(2, 4)}
for t_val in [0.0, 0.25, 0.5, 0.75, 1.0]:
    blended = slerp(m1, m2, t=t_val)
    enc_norm = blended["enc"].norm().item()
    print(f"t={t_val}: enc_norm={enc_norm:.4f}")
print("SLERP traces constant-speed path on unit sphere; LERP cuts through center.")
```

## LoRA Merging in Weight Space vs Adapter Space

LoRA adapters can be merged at two levels. In adapter space, the LoRA matrices A and B are averaged or combined before computing the update Δ W = BA. In weight space, each adapter's full weight update Δ Wᵢ = BᵢAᵢ is computed first, then the full-rank updates are merged (e.g., via TIES or DARE). Weight-space merging is more flexible — you can apply any merging algorithm — but loses the low-rank structure. Adapter-space merging preserves low rank but is limited to methods that operate on the factored matrices. For task arithmetic and TIES/DARE, weight-space merging is standard.

## Practical Guidelines and Method Comparison

- Model soup: use when merging checkpoints from the same training run with different hyperparameters or data seeds.
- TIES: preferred when merging models fine-tuned on very different tasks — sign conflict resolution prevents destructive interference.
- DARE: add when merging many models (4+); the random dropping reduces pairwise interference without needing explicit sign resolution.
- SLERP: best for merging exactly two models when magnitude preservation matters (e.g., instruction-tuned + DPO-tuned versions).
- Task arithmetic: use when you want additive composition — each task vector contributes independently with a tunable scale λ.
- All methods require fine-tuning from the same pretrained base to avoid catastrophic interference from mismatched feature spaces.

| Method | Conflict Resolution | Parameter Count | Quality vs Individual | Compute Cost | Best For |
| --- | --- | --- | --- | --- | --- |
| Model Soup | None (simple average) | Same as one model | Better (flatter basin) | Trivial — one pass | Same-task hyperparameter ensembling |
| Task Arithmetic | None (additive) | Same as one model | Comparable at low scale | Trivial — vector add | Additive multi-task composition |
| TIES | Sign majority vote per param | Same as one model | Better than soup for cross-task | Low — one trimming pass | Different-task merging, up to ~8 models |
| DARE | Stochastic drop + rescale | Same as one model | Good for many models | Low — random mask | Merging 4+ models, high interference |
| SLERP | None (geodesic path) | Same as one model | Best for 2-model blend | Low — per-layer trig | Two-model interpolation, magnitude-sensitive |

> **TIES Outperforms Simple Averaging for Cross-Task Merging**: TIES merging outperforms simple weight averaging when merging models fine-tuned on very different tasks — the sign conflict resolution step prevents destructive interference between opposing weight updates that degrade both tasks. Use top-k=0.2 (keep 20% of deltas) as a starting point; larger k retains more task signal but increases interference. For LoRA merging, merge in weight space (compute BA first) so TIES can see the full-rank updates.

---

