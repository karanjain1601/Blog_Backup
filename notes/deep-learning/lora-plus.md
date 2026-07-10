---
title: "LoRA+ — Different Learning Rates for A and B Matrices"
slug: "lora-plus"
description: "LoRA+ (Hayou et al. 2024) sets a higher learning rate for the B matrix than A, following maximal update parameterization theory. Achieves 1–2% benchmark improvement at zero extra compute by treating A and B as evolving at different timescales."
tags: ["deep-learning", "llm"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"Standard LoRA decomposes a weight update as ΔW = B·A where A ∈ ℝ^{r×d_in} and B ∈ ℝ^{d_out×r}. By default, both matrices are trained with the same learning rate using a single optimizer parameter group. LoRA+ (Hayou et al., 2024) identifies this as a suboptimal choice: A and B play fundamentally different roles in the adapter and should evolve at different timescales. Setting η_B = λ·η_A with λ=16 yields consistent 1–2% benchmark gains at zero additional compute cost."},{"type":"heading","level":2,"content":"The Problem with Standard LoRA Learning Rates"},{"type":"text","content":"In LoRA, A is initialized with a Gaussian distribution (random projection, input-side) and B is initialized to zero (output-side, starts contributing nothing). During training, A functions as a feature extractor that adapts the direction in which inputs are projected, while B scales and combines those projected features into the output space. These two roles require different learning dynamics: B must move quickly from zero to useful values while A should update more carefully to preserve the learned projection structure."},{"type":"heading","level":2,"content":"Feature Learning Theory and Maximal Update Parameterization"},{"type":"text","content":"Maximal update parameterization (muP, Yang et al., 2022) provides a principled framework for setting per-layer learning rates in infinite-width networks. Under muP, \u0027last-layer\u0027 parameters — those closest to the output — should receive a larger learning rate to ensure feature learning (as opposed to lazy training). In LoRA\u0027s context, B is the output-proximal matrix and should have a larger LR. A is the input-proximal matrix and benefits from a smaller LR. LoRA+ formalizes this with the ratio η_B/η_A = λ, where λ=16 is the empirically validated default."},{"type":"heading","level":2,"content":"LoRA+ Optimizer Setup"},{"type":"text","content":"The key implementation detail is creating separate parameter groups for A and B matrices. PyTorch\u0027s AdamW optimizer accepts a list of parameter group dictionaries, each with its own learning rate. By iterating over named parameters and routing A-suffix parameters to one group and B-suffix parameters to another, LoRA+ requires only a small wrapper around standard optimizer construction."},{"type":"code","language":"python","content":"import torch\nimport torch.optim as optim\nfrom peft import LoraConfig, get_peft_model\nfrom transformers import AutoModelForCausalLM\n\ndef create_lora_plus_optimizer(\n    model: torch.nn.Module,\n    lr_A: float = 1e-4,\n    lambda_ratio: float = 16.0,\n    weight_decay: float = 0.01,\n) -\u003e optim.AdamW:\n    \"\"\"Create AdamW with separate LRs for LoRA A and B matrices.\"\"\"\n    lr_B = lr_A * lambda_ratio\n    group_A, group_B, group_other = [], [], []\n    for name, param in model.named_parameters():\n        if not param.requires_grad:\n            continue\n        if \u0027lora_A\u0027 in name:\n            group_A.append(param)\n        elif \u0027lora_B\u0027 in name:\n            group_B.append(param)\n        else:\n            group_other.append(param)\n    param_groups = [\n        {\u0027params\u0027: group_A, \u0027lr\u0027: lr_A, \u0027weight_decay\u0027: weight_decay},\n        {\u0027params\u0027: group_B, \u0027lr\u0027: lr_B, \u0027weight_decay\u0027: weight_decay},\n        {\u0027params\u0027: group_other, \u0027lr\u0027: lr_A, \u0027weight_decay\u0027: weight_decay},\n    ]\n    print(f\u0027LoRA+ optimizer: lr_A={lr_A:.2e}, lr_B={lr_B:.2e} (λ={lambda_ratio})\u0027)\n    print(f\u0027  A params: {len(group_A)}, B params: {len(group_B)}, other: {len(group_other)}\u0027)\n    return optim.AdamW(param_groups)"},{"type":"heading","level":2,"content":"LoRA+ Layer Implementation"},{"type":"text","content":"A self-contained LoRA+ module stores A and B as separate named attributes matching the peft library convention (lora_A, lora_B). The forward pass is identical to standard LoRA — the difference is entirely in the optimizer configuration. The scaling factor α/r is applied to the B·A product to normalize the initialization variance regardless of rank."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport math\n\nclass LoRAPlusLinear(nn.Module):\n    \"\"\"Linear layer with LoRA+ adapter (separate LR groups for A and B).\"\"\"\n\n    def __init__(self, in_features: int, out_features: int, rank: int = 16,\n                 alpha: float = 16.0, dropout: float = 0.05):\n        super().__init__()\n        self.rank = rank\n        self.scaling = alpha / rank\n        # Base weight frozen\n        self.weight = nn.Parameter(torch.randn(out_features, in_features), requires_grad=False)\n        self.bias = nn.Parameter(torch.zeros(out_features), requires_grad=False)\n        # LoRA adapters: A=Gaussian init, B=zero init\n        self.lora_A = nn.Parameter(torch.empty(rank, in_features))\n        self.lora_B = nn.Parameter(torch.zeros(out_features, rank))\n        nn.init.kaiming_uniform_(self.lora_A, a=math.sqrt(5))\n        self.dropout = nn.Dropout(dropout)\n\n    def forward(self, x: torch.Tensor) -\u003e torch.Tensor:\n        base_out = nn.functional.linear(x, self.weight, self.bias)\n        lora_out = nn.functional.linear(\n            self.dropout(x), self.lora_A\n        )  # (batch, rank)\n        lora_out = nn.functional.linear(lora_out, self.lora_B)  # (batch, out)\n        return base_out + lora_out * self.scaling\n\n    def get_param_groups(self, lr_A: float, lambda_ratio: float = 16.0):\n        return [\n            {\u0027params\u0027: [self.lora_A], \u0027lr\u0027: lr_A},\n            {\u0027params\u0027: [self.lora_B], \u0027lr\u0027: lr_A * lambda_ratio},\n        ]\n\nlayer = LoRAPlusLinear(768, 768, rank=16)\nx = torch.randn(4, 768)\nprint(f\u0027Output shape: {layer(x).shape}\u0027)\nprint(f\u0027lora_A shape: {layer.lora_A.shape}, lora_B shape: {layer.lora_B.shape}\u0027)"},{"type":"heading","level":2,"content":"Lambda Sensitivity Analysis"},{"type":"text","content":"The choice of λ determines the ratio η_B/η_A. Hayou et al. perform a sweep across λ ∈ {1, 2, 4, 8, 16, 32} on commonsense reasoning and math benchmarks. λ=1 is equivalent to standard LoRA. The results show a clear optimum around λ=16 with diminishing returns beyond, and slight degradation at λ=32 due to B moving too fast and overshooting good solutions."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.optim as optim\nfrom torch.utils.data import DataLoader, TensorDataset\n\ndef lr_ratio_sweep(lambdas=(1, 2, 4, 8, 16, 32), n_steps=200,\n                   in_dim=128, out_dim=32, rank=8, seed=42):\n    \"\"\"Sweep LR ratio lambda and measure final validation loss.\"\"\"\n    torch.manual_seed(seed)\n    X = torch.randn(512, in_dim)\n    y = torch.randint(0, out_dim, (512,))\n    loader = DataLoader(TensorDataset(X, y), batch_size=64, shuffle=True)\n    results = {}\n    for lam in lambdas:\n        torch.manual_seed(seed)\n        lora_A = nn.Parameter(torch.randn(rank, in_dim) * 0.02)\n        lora_B = nn.Parameter(torch.zeros(out_dim, rank))\n        base_W = torch.randn(out_dim, in_dim)\n        opt = optim.AdamW([\n            {\u0027params\u0027: [lora_A], \u0027lr\u0027: 1e-3},\n            {\u0027params\u0027: [lora_B], \u0027lr\u0027: 1e-3 * lam},\n        ], weight_decay=0.01)\n        criterion = nn.CrossEntropyLoss()\n        for step, (xb, yb) in zip(range(n_steps), loader):\n            opt.zero_grad()\n            out = (xb @ base_W.T) + (xb @ lora_A.T) @ lora_B.T\n            loss = criterion(out, yb)\n            loss.backward()\n            opt.step()\n        results[lam] = loss.item()\n        print(f\u0027  lambda={lam:\u003e2}: final loss = {loss.item():.4f}\u0027)\n    best = min(results, key=results.get)\n    print(f\u0027Best lambda: {best} (loss={results[best]:.4f})\u0027)\n    return results\n\nprint(\u0027LR ratio sweep:\u0027)\nlr_ratio_sweep()"},{"type":"heading","level":2,"content":"A vs B Gradient Analysis"},{"type":"text","content":"To understand why different LRs help, we can track gradient norms and effective update magnitudes for A and B throughout training. With the same LR, B\u0027s gradient norm is typically much larger in early training (it starts at zero and needs to catch up), while A\u0027s gradient norm is more stable. LoRA+ explicitly compensates by scaling the B update upward, matching what the natural gradient would suggest."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.optim as optim\n\ndef track_ab_gradients(n_steps=100, rank=16, in_dim=256, out_dim=64, lambda_ratio=16):\n    \"\"\"Track gradient norms and update magnitudes for A and B matrices.\"\"\"\n    lora_A = nn.Parameter(torch.randn(rank, in_dim) * 0.02)\n    lora_B = nn.Parameter(torch.zeros(out_dim, rank))\n    opt = optim.AdamW([\n        {\u0027params\u0027: [lora_A], \u0027lr\u0027: 1e-4},\n        {\u0027params\u0027: [lora_B], \u0027lr\u0027: 1e-4 * lambda_ratio},\n    ])\n    history = {\u0027grad_A\u0027: [], \u0027grad_B\u0027: [], \u0027norm_A\u0027: [], \u0027norm_B\u0027: []}\n    for step in range(n_steps):\n        x = torch.randn(32, in_dim)\n        out = x @ lora_A.T @ lora_B.T\n        loss = out.pow(2).mean()\n        opt.zero_grad()\n        loss.backward()\n        if lora_A.grad is not None:\n            history[\u0027grad_A\u0027].append(lora_A.grad.norm().item())\n            history[\u0027grad_B\u0027].append(lora_B.grad.norm().item())\n        history[\u0027norm_A\u0027].append(lora_A.data.norm().item())\n        history[\u0027norm_B\u0027].append(lora_B.data.norm().item())\n        opt.step()\n    final = {k: round(v[-1], 5) for k, v in history.items()}\n    print(f\u0027Final grad norms  — A: {final[\"grad_A\"]:.5f}, B: {final[\"grad_B\"]:.5f}\u0027)\n    print(f\u0027Final param norms — A: {final[\"norm_A\"]:.4f}, B: {final[\"norm_B\"]:.4f}\u0027)\n    return history\n\ntrack_ab_gradients()"},{"type":"heading","level":2,"content":"LoRA Learning Rate Strategy Comparison"},{"type":"table","headers":["Strategy","LR for A","LR for B","Extra Compute","Typical Improvement","Notes"],"rows":[["Standard LoRA","η","η","None","Baseline","Same LR for both; simple but suboptimal"],["LoRA+ (λ=16)","η","16·η","None","+1–2% on most benchmarks","Recommended default; free performance gain"],["LoRA+ (λ=4)","η","4·η","None","+0.5–1%","Conservative ratio; lower risk of B instability"],["muP LoRA","η/fan_in","η (last-layer scaled)","None","+1–2%","Full muP transfer: set LR via μP coord check"],["AdaLoRA","Adaptive (SVD)","Adaptive (SVD)","~20% overhead","+1–3%","Importance-aware rank allocation; more complex"]]},{"type":"text","content":"LoRA+ stacks naturally with DoRA (weight decomposition into magnitude and direction): the direction component maps to A\u0027s role and the magnitude component maps to B\u0027s role. Setting a higher LR for the magnitude vector (DoRA\u0027s equivalent of B) and a lower LR for the directional LoRA matrices is consistent with LoRA+ theory. This combined setup has been reported to outperform either method alone on several instruction-following benchmarks."},{"type":"callout","variant":"tip","title":"LoRA+ is a free performance upgrade","content":"LoRA+ with λ=16 (η_B = 16·η_A) provides 1–2% consistent improvement across tasks with zero additional compute — it\u0027s a free performance upgrade that should be the default over standard LoRA in most fine-tuning setups. Simply split your LoRA parameters into two optimizer groups and set the B group\u0027s LR 16× higher."},{"type":"list","ordered":false,"items":["λ=16 is the most robust default; sensitivity analysis shows little gain beyond λ=16 and risk of instability at λ=32.","A is initialized with Gaussian noise and adapts feature directions; B starts at zero and adapts output magnitudes.","muP theory predicts that output-proximal parameters should receive larger LR — LoRA+ is a practical approximation.","LoRA+ adds no trainable parameters, no forward-pass overhead, and no memory cost beyond two optimizer state partitions.","Compatible with quantization (QLoRA), DoRA, and gradient checkpointing — no architectural changes required.","When using peft library, filter named_parameters by \u0027lora_A\u0027 and \u0027lora_B\u0027 suffixes for group separation."]},{"type":"divider"}]"
---
# LoRA+ — Different Learning Rates for A and B Matrices

Standard LoRA decomposes a weight update as ΔW = B·A where A ∈ ℝ^{r×d_in} and B ∈ ℝ^{d_out×r}. By default, both matrices are trained with the same learning rate using a single optimizer parameter group. LoRA+ (Hayou et al., 2024) identifies this as a suboptimal choice: A and B play fundamentally different roles in the adapter and should evolve at different timescales. Setting η_B = λ·η_A with λ=16 yields consistent 1–2% benchmark gains at zero additional compute cost.

## The Problem with Standard LoRA Learning Rates

In LoRA, A is initialized with a Gaussian distribution (random projection, input-side) and B is initialized to zero (output-side, starts contributing nothing). During training, A functions as a feature extractor that adapts the direction in which inputs are projected, while B scales and combines those projected features into the output space. These two roles require different learning dynamics: B must move quickly from zero to useful values while A should update more carefully to preserve the learned projection structure.

## Feature Learning Theory and Maximal Update Parameterization

Maximal update parameterization (muP, Yang et al., 2022) provides a principled framework for setting per-layer learning rates in infinite-width networks. Under muP, 'last-layer' parameters — those closest to the output — should receive a larger learning rate to ensure feature learning (as opposed to lazy training). In LoRA's context, B is the output-proximal matrix and should have a larger LR. A is the input-proximal matrix and benefits from a smaller LR. LoRA+ formalizes this with the ratio η_B/η_A = λ, where λ=16 is the empirically validated default.

## LoRA+ Optimizer Setup

The key implementation detail is creating separate parameter groups for A and B matrices. PyTorch's AdamW optimizer accepts a list of parameter group dictionaries, each with its own learning rate. By iterating over named parameters and routing A-suffix parameters to one group and B-suffix parameters to another, LoRA+ requires only a small wrapper around standard optimizer construction.

```python
import torch
import torch.optim as optim
from peft import LoraConfig, get_peft_model
from transformers import AutoModelForCausalLM

def create_lora_plus_optimizer(
    model: torch.nn.Module,
    lr_A: float = 1e-4,
    lambda_ratio: float = 16.0,
    weight_decay: float = 0.01,
) -> optim.AdamW:
    """Create AdamW with separate LRs for LoRA A and B matrices."""
    lr_B = lr_A * lambda_ratio
    group_A, group_B, group_other = [], [], []
    for name, param in model.named_parameters():
        if not param.requires_grad:
            continue
        if 'lora_A' in name:
            group_A.append(param)
        elif 'lora_B' in name:
            group_B.append(param)
        else:
            group_other.append(param)
    param_groups = [
        {'params': group_A, 'lr': lr_A, 'weight_decay': weight_decay},
        {'params': group_B, 'lr': lr_B, 'weight_decay': weight_decay},
        {'params': group_other, 'lr': lr_A, 'weight_decay': weight_decay},
    ]
    print(f'LoRA+ optimizer: lr_A={lr_A:.2e}, lr_B={lr_B:.2e} (λ={lambda_ratio})')
    print(f'  A params: {len(group_A)}, B params: {len(group_B)}, other: {len(group_other)}')
    return optim.AdamW(param_groups)
```

## LoRA+ Layer Implementation

A self-contained LoRA+ module stores A and B as separate named attributes matching the peft library convention (lora_A, lora_B). The forward pass is identical to standard LoRA — the difference is entirely in the optimizer configuration. The scaling factor α/r is applied to the B·A product to normalize the initialization variance regardless of rank.

```python
import torch
import torch.nn as nn
import math

class LoRAPlusLinear(nn.Module):
    """Linear layer with LoRA+ adapter (separate LR groups for A and B)."""

    def __init__(self, in_features: int, out_features: int, rank: int = 16,
                 alpha: float = 16.0, dropout: float = 0.05):
        super().__init__()
        self.rank = rank
        self.scaling = alpha / rank
        # Base weight frozen
        self.weight = nn.Parameter(torch.randn(out_features, in_features), requires_grad=False)
        self.bias = nn.Parameter(torch.zeros(out_features), requires_grad=False)
        # LoRA adapters: A=Gaussian init, B=zero init
        self.lora_A = nn.Parameter(torch.empty(rank, in_features))
        self.lora_B = nn.Parameter(torch.zeros(out_features, rank))
        nn.init.kaiming_uniform_(self.lora_A, a=math.sqrt(5))
        self.dropout = nn.Dropout(dropout)

    def forward(self, x: torch.Tensor) -> torch.Tensor:
        base_out = nn.functional.linear(x, self.weight, self.bias)
        lora_out = nn.functional.linear(
            self.dropout(x), self.lora_A
        )  # (batch, rank)
        lora_out = nn.functional.linear(lora_out, self.lora_B)  # (batch, out)
        return base_out + lora_out * self.scaling

    def get_param_groups(self, lr_A: float, lambda_ratio: float = 16.0):
        return [
            {'params': [self.lora_A], 'lr': lr_A},
            {'params': [self.lora_B], 'lr': lr_A * lambda_ratio},
        ]

layer = LoRAPlusLinear(768, 768, rank=16)
x = torch.randn(4, 768)
print(f'Output shape: {layer(x).shape}')
print(f'lora_A shape: {layer.lora_A.shape}, lora_B shape: {layer.lora_B.shape}')
```

## Lambda Sensitivity Analysis

The choice of λ determines the ratio η_B/η_A. Hayou et al. perform a sweep across λ ∈ {1, 2, 4, 8, 16, 32} on commonsense reasoning and math benchmarks. λ=1 is equivalent to standard LoRA. The results show a clear optimum around λ=16 with diminishing returns beyond, and slight degradation at λ=32 due to B moving too fast and overshooting good solutions.

```python
import torch
import torch.nn as nn
import torch.optim as optim
from torch.utils.data import DataLoader, TensorDataset

def lr_ratio_sweep(lambdas=(1, 2, 4, 8, 16, 32), n_steps=200,
                   in_dim=128, out_dim=32, rank=8, seed=42):
    """Sweep LR ratio lambda and measure final validation loss."""
    torch.manual_seed(seed)
    X = torch.randn(512, in_dim)
    y = torch.randint(0, out_dim, (512,))
    loader = DataLoader(TensorDataset(X, y), batch_size=64, shuffle=True)
    results = {}
    for lam in lambdas:
        torch.manual_seed(seed)
        lora_A = nn.Parameter(torch.randn(rank, in_dim) * 0.02)
        lora_B = nn.Parameter(torch.zeros(out_dim, rank))
        base_W = torch.randn(out_dim, in_dim)
        opt = optim.AdamW([
            {'params': [lora_A], 'lr': 1e-3},
            {'params': [lora_B], 'lr': 1e-3 * lam},
        ], weight_decay=0.01)
        criterion = nn.CrossEntropyLoss()
        for step, (xb, yb) in zip(range(n_steps), loader):
            opt.zero_grad()
            out = (xb @ base_W.T) + (xb @ lora_A.T) @ lora_B.T
            loss = criterion(out, yb)
            loss.backward()
            opt.step()
        results[lam] = loss.item()
        print(f'  lambda={lam:>2}: final loss = {loss.item():.4f}')
    best = min(results, key=results.get)
    print(f'Best lambda: {best} (loss={results[best]:.4f})')
    return results

print('LR ratio sweep:')
lr_ratio_sweep()
```

## A vs B Gradient Analysis

To understand why different LRs help, we can track gradient norms and effective update magnitudes for A and B throughout training. With the same LR, B's gradient norm is typically much larger in early training (it starts at zero and needs to catch up), while A's gradient norm is more stable. LoRA+ explicitly compensates by scaling the B update upward, matching what the natural gradient would suggest.

```python
import torch
import torch.nn as nn
import torch.optim as optim

def track_ab_gradients(n_steps=100, rank=16, in_dim=256, out_dim=64, lambda_ratio=16):
    """Track gradient norms and update magnitudes for A and B matrices."""
    lora_A = nn.Parameter(torch.randn(rank, in_dim) * 0.02)
    lora_B = nn.Parameter(torch.zeros(out_dim, rank))
    opt = optim.AdamW([
        {'params': [lora_A], 'lr': 1e-4},
        {'params': [lora_B], 'lr': 1e-4 * lambda_ratio},
    ])
    history = {'grad_A': [], 'grad_B': [], 'norm_A': [], 'norm_B': []}
    for step in range(n_steps):
        x = torch.randn(32, in_dim)
        out = x @ lora_A.T @ lora_B.T
        loss = out.pow(2).mean()
        opt.zero_grad()
        loss.backward()
        if lora_A.grad is not None:
            history['grad_A'].append(lora_A.grad.norm().item())
            history['grad_B'].append(lora_B.grad.norm().item())
        history['norm_A'].append(lora_A.data.norm().item())
        history['norm_B'].append(lora_B.data.norm().item())
        opt.step()
    final = {k: round(v[-1], 5) for k, v in history.items()}
    print(f'Final grad norms  — A: {final["grad_A"]:.5f}, B: {final["grad_B"]:.5f}')
    print(f'Final param norms — A: {final["norm_A"]:.4f}, B: {final["norm_B"]:.4f}')
    return history

track_ab_gradients()
```

## LoRA Learning Rate Strategy Comparison

| Strategy | LR for A | LR for B | Extra Compute | Typical Improvement | Notes |
| --- | --- | --- | --- | --- | --- |
| Standard LoRA | η | η | None | Baseline | Same LR for both; simple but suboptimal |
| LoRA+ (λ=16) | η | 16·η | None | +1–2% on most benchmarks | Recommended default; free performance gain |
| LoRA+ (λ=4) | η | 4·η | None | +0.5–1% | Conservative ratio; lower risk of B instability |
| muP LoRA | η/fan_in | η (last-layer scaled) | None | +1–2% | Full muP transfer: set LR via μP coord check |
| AdaLoRA | Adaptive (SVD) | Adaptive (SVD) | ~20% overhead | +1–3% | Importance-aware rank allocation; more complex |

LoRA+ stacks naturally with DoRA (weight decomposition into magnitude and direction): the direction component maps to A's role and the magnitude component maps to B's role. Setting a higher LR for the magnitude vector (DoRA's equivalent of B) and a lower LR for the directional LoRA matrices is consistent with LoRA+ theory. This combined setup has been reported to outperform either method alone on several instruction-following benchmarks.

> **LoRA+ is a free performance upgrade**: LoRA+ with λ=16 (η_B = 16·η_A) provides 1–2% consistent improvement across tasks with zero additional compute — it's a free performance upgrade that should be the default over standard LoRA in most fine-tuning setups. Simply split your LoRA parameters into two optimizer groups and set the B group's LR 16× higher.

- λ=16 is the most robust default; sensitivity analysis shows little gain beyond λ=16 and risk of instability at λ=32.
- A is initialized with Gaussian noise and adapts feature directions; B starts at zero and adapts output magnitudes.
- muP theory predicts that output-proximal parameters should receive larger LR — LoRA+ is a practical approximation.
- LoRA+ adds no trainable parameters, no forward-pass overhead, and no memory cost beyond two optimizer state partitions.
- Compatible with quantization (QLoRA), DoRA, and gradient checkpointing — no architectural changes required.
- When using peft library, filter named_parameters by 'lora_A' and 'lora_B' suffixes for group separation.

---

