---
title: "VeRA — Vector-Based Random Matrix Adaptation for Extreme Parameter Efficiency"
slug: "vera-random-matrix"
description: "VeRA (Kopiczko et al. 2024) shares a single frozen random matrix pair across all adapter layers and learns only per-layer scaling vectors, achieving ~32× fewer trainable parameters than LoRA r=16 while remaining competitive on language tasks."
tags: ["deep-learning", "llm"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"LoRA reduces trainable parameters by using low-rank matrices per layer, but each layer still maintains its own private A and B matrices. For a 7B parameter model with LoRA rank=16 applied to all attention projections, trainable parameters reach ~84M. VeRA (Vector-based Random matrix Adaptation, Kopiczko et al., 2024) pushes parameter efficiency further: a single pair of random matrices is shared (frozen) across all layers, and only small per-layer scaling vectors are learned. This reduces trainable parameters to approximately 1.4M — a 60× reduction over LoRA r=16 — while achieving surprisingly competitive task performance."},{"type":"heading","level":2,"content":"VeRA Architecture — Shared Random Matrices"},{"type":"text","content":"In VeRA, a single random matrix A ∈ ℝ^{r×d_in} and a single random matrix B ∈ ℝ^{d_out×r} are generated once (using a fixed random seed) and kept frozen across all layers. For each layer l, VeRA introduces two learnable scaling vectors: b_d^l ∈ ℝ^{d_out} (scales rows of B) and d_r^l ∈ ℝ^r (scales rows of A). The forward pass for layer l is: h += B·diag(b_d^l)·A·diag(d_r^l)·x. The diagonal scaling vectors select which directions in the shared random basis matter for each specific layer."},{"type":"heading","level":2,"content":"VeRA Layer Implementation"},{"type":"text","content":"The implementation instantiates the shared random matrices as buffers (not parameters) at model initialization. Per-layer trainable vectors are registered as parameters. The forward pass computes the scaled random projection via element-wise multiplication — equivalent to row-scaling of the matrices — which avoids materializing full diagonal matrices."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport math\n\nclass VeRALinear(nn.Module):\n    \"\"\"VeRA adapter: shared frozen (A,B), learnable per-layer scaling vectors.\"\"\"\n\n    def __init__(self, in_features: int, out_features: int,\n                 rank: int, shared_A: torch.Tensor, shared_B: torch.Tensor,\n                 alpha: float = 1.0, dropout: float = 0.0):\n        super().__init__()\n        self.rank = rank\n        self.scaling = alpha / rank\n        # Base weight (frozen)\n        self.weight = nn.Parameter(torch.randn(out_features, in_features), requires_grad=False)\n        self.bias = nn.Parameter(torch.zeros(out_features), requires_grad=False)\n        # Shared random matrices (frozen buffers, NOT trainable)\n        self.register_buffer(\u0027shared_A\u0027, shared_A)  # (rank, in_features)\n        self.register_buffer(\u0027shared_B\u0027, shared_B)  # (out_features, rank)\n        # Per-layer trainable scaling vectors\n        self.vec_d = nn.Parameter(torch.ones(rank))       # scales A rows\n        self.vec_b = nn.Parameter(torch.zeros(out_features))  # scales B rows\n        self.dropout = nn.Dropout(dropout)\n\n    def forward(self, x: torch.Tensor) -\u003e torch.Tensor:\n        base = nn.functional.linear(x, self.weight, self.bias)\n        # diag(d_r) @ A: scale each row of A, shape (rank, in_features)\n        scaled_A = self.shared_A * self.vec_d.unsqueeze(1)\n        # B @ diag(b_d): scale each row of B, shape (out_features, rank)\n        scaled_B = self.shared_B * self.vec_b.unsqueeze(1)\n        lora_out = nn.functional.linear(\n            nn.functional.linear(self.dropout(x), scaled_A), scaled_B\n        )\n        return base + lora_out * self.scaling\n\nrank, d_in, d_out = 16, 768, 768\nshared_A = torch.randn(rank, d_in)\nshared_B = torch.randn(d_out, rank)\nlayer = VeRALinear(d_in, d_out, rank, shared_A, shared_B)\nx = torch.randn(4, d_in)\nprint(f\u0027Output: {layer(x).shape}\u0027)\nprint(f\u0027Trainable params: vec_d={layer.vec_d.numel()}, vec_b={layer.vec_b.numel()}\u0027)"},{"type":"heading","level":2,"content":"Parameter Count Comparison"},{"type":"text","content":"For a model with L adapter layers, d_in and d_out, and rank r: LoRA contributes 2×L×r×d params per layer pair. VeRA contributes L×(r+d_out) for the scaling vectors, plus one shared pair (r×d_in + d_out×r) that does not scale with L. For a 7B LLaMA-style model with L=32 attention layers, d=4096, r=16: LoRA has 32×2×16×4096 = 4.2M trainable params per projection. VeRA has 32×(16+4096) = 131K trainable params — a 32× reduction per projection."},{"type":"code","language":"python","content":"import torch\n\ndef compare_param_counts(model_dims: dict, ranks: list = (4, 8, 16, 32)):\n    \"\"\"Compare LoRA vs VeRA trainable params for a transformer model.\"\"\"\n    n_layers = model_dims[\u0027n_layers\u0027]     # e.g., 32\n    d_model = model_dims[\u0027d_model\u0027]       # e.g., 4096\n    n_proj = model_dims[\u0027n_projections\u0027]  # Q, K, V, O = 4\n    print(f\u0027Model: {n_layers} layers, d={d_model}, {n_proj} projections\u0027)\n    print(f\u0027{\"Rank\":\u003e6}  {\"LoRA params\":\u003e14}  {\"VeRA params\":\u003e14}  {\"Ratio\":\u003e8}\u0027)\n    print(\u0027-\u0027 * 50)\n    for r in ranks:\n        lora_params = n_layers * n_proj * 2 * r * d_model\n        # VeRA: per-layer vectors + one shared pair (counted once)\n        vera_per_layer = n_layers * n_proj * (r + d_model)\n        vera_shared = 2 * r * d_model  # shared A and B\n        vera_params = vera_per_layer + vera_shared\n        ratio = lora_params / vera_params\n        print(f\u0027{r:\u003e6}  {lora_params/1e6:\u003e12.2f}M  {vera_params/1e6:\u003e12.3f}M  {ratio:\u003e7.1f}x\u0027)\n\ncompare_param_counts({\u0027n_layers\u0027: 32, \u0027d_model\u0027: 4096, \u0027n_projections\u0027: 4})\nprint()\ncompare_param_counts({\u0027n_layers\u0027: 32, \u0027d_model\u0027: 4096, \u0027n_projections\u0027: 4},\n                     ranks=[64, 128])"},{"type":"heading","level":2,"content":"VeRA Training"},{"type":"text","content":"Training VeRA requires generating the shared random matrices once with a fixed seed and replicating them across all layers. Only the scaling vectors are passed to the optimizer. The shared matrices are registered as buffers so they move to the correct device automatically but do not consume optimizer state (no Adam m/v statistics for them)."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.optim as optim\nfrom typing import List\n\ndef build_vera_model(n_layers: int, d_model: int, rank: int = 16,\n                     seed: int = 42) -\u003e nn.ModuleList:\n    \"\"\"Build a stack of VeRA layers sharing a single random matrix pair.\"\"\"\n    torch.manual_seed(seed)\n    shared_A = torch.randn(rank, d_model) / (rank ** 0.5)  # normalized init\n    shared_B = torch.randn(d_model, rank) / (rank ** 0.5)\n    layers = nn.ModuleList([\n        VeRALinear(d_model, d_model, rank, shared_A.clone(), shared_B.clone())\n        for _ in range(n_layers)\n    ])\n    return layers\n\ndef get_vera_optimizer(model: nn.ModuleList, lr: float = 1e-3) -\u003e optim.AdamW:\n    \"\"\"Only optimize scaling vectors; ignore frozen weights and shared buffers.\"\"\"\n    trainable = [p for p in model.parameters() if p.requires_grad]\n    total = sum(p.numel() for p in trainable)\n    print(f\u0027VeRA trainable parameters: {total:,}\u0027)\n    return optim.AdamW(trainable, lr=lr, weight_decay=0.01)\n\n# Simulate training\nlayers = build_vera_model(n_layers=4, d_model=256, rank=16)\noptimizer = get_vera_optimizer(layers)\nx = torch.randn(8, 256)\nfor step in range(5):\n    h = x\n    for layer in layers:\n        h = layer(h) + h  # residual\n    loss = h.pow(2).mean()\n    optimizer.zero_grad()\n    loss.backward()\n    optimizer.step()\n    if step % 2 == 0:\n        print(f\u0027Step {step}: loss={loss.item():.4f}\u0027)"},{"type":"heading","level":2,"content":"Quality vs Parameter Efficiency"},{"type":"text","content":"Benchmarking VeRA against LoRA and full fine-tuning reveals that VeRA achieves surprisingly competitive accuracy on language understanding tasks. The gap widens on tasks that require very different representations across layers, where the shared random basis becomes a bottleneck. However, for standard instruction following and commonsense reasoning, VeRA within ~1–3% of LoRA r=16 despite 32× fewer parameters."},{"type":"code","language":"python","content":"import torch\nimport math\n\n# Approximate benchmark results from VeRA paper (Kopiczko et al. 2024)\n# Evaluated on LLaMA-7B with commonsense and GLUE benchmarks\nbenchmark_data = [\n    {\u0027method\u0027: \u0027Full Fine-Tuning\u0027, \u0027params_M\u0027: 7000.0, \u0027accuracy\u0027: 0.892},\n    {\u0027method\u0027: \u0027LoRA r=16\u0027,        \u0027params_M\u0027: 83.9,   \u0027accuracy\u0027: 0.871},\n    {\u0027method\u0027: \u0027LoRA r=4\u0027,         \u0027params_M\u0027: 20.9,   \u0027accuracy\u0027: 0.859},\n    {\u0027method\u0027: \u0027DoRA r=16\u0027,        \u0027params_M\u0027: 83.9,   \u0027accuracy\u0027: 0.878},\n    {\u0027method\u0027: \u0027VeRA r=256\u0027,       \u0027params_M\u0027: 1.4,    \u0027accuracy\u0027: 0.862},\n    {\u0027method\u0027: \u0027IA3\u0027,              \u0027params_M\u0027: 0.02,   \u0027accuracy\u0027: 0.828},\n]\n\nprint(f\u0027{\"Method\":\u003c20}  {\"Params (M)\":\u003e12}  {\"Accuracy\":\u003e10}  {\"Params/FullFT\":\u003e14}\u0027)\nprint(\u0027-\u0027 * 65)\nfor entry in benchmark_data:\n    frac = entry[\u0027params_M\u0027] / 7000.0\n    print(f\"{entry[\u0027method\u0027]:\u003c20}  {entry[\u0027params_M\u0027]:\u003e12.1f}  \"\n          f\"{entry[\u0027accuracy\u0027]:\u003e10.3f}  {frac:\u003e13.4%}\")\n\n# Efficiency score: accuracy / log10(params)\nprint(\u0027\\nEfficiency score (accuracy / log10(params)):\u0027)\nfor entry in benchmark_data:\n    score = entry[\u0027accuracy\u0027] / math.log10(entry[\u0027params_M\u0027] * 1e6 + 1)\n    print(f\"  {entry[\u0027method\u0027]:\u003c20}: {score:.4f}\")"},{"type":"heading","level":2,"content":"Why Random Matrices Work"},{"type":"text","content":"The theoretical justification for VeRA comes from random feature theory. A random matrix A with i.i.d. Gaussian entries spans the entire input space in expectation — any direction can be approximately reached by a suitable linear combination of the rows. The scaling vector d_r selects which random directions to amplify, effectively constructing a task-specific projection from the shared random basis. This is analogous to random kitchen sinks (Rahimi \u0026 Recht, 2007): random features approximate a rich kernel function, and the learned weights select the relevant features for the task."},{"type":"heading","level":2,"content":"PEFT Parameter Efficiency Comparison"},{"type":"table","headers":["Method","Trainable Params (7B)","% of Total","Quality vs Full FT","Inference Overhead","Memory Savings"],"rows":[["Full Fine-Tuning","7,000M","100%","Baseline","None","None"],["LoRA r=16","~84M","~1.2%","-1 to -2%","Merge: none; separate: minimal","High"],["LoRA r=4","~21M","~0.3%","-2 to -4%","Merge: none; separate: minimal","Very high"],["VeRA (r=256)","~1.4M","~0.02%","-2 to -3%","Shared buffers; minimal","Extreme"],["Prefix Tuning (P=100)","~5M","~0.07%","-3 to -5%","Extra KV cache per layer","High"],["IA3","~0.02M","~0.0003%","-6 to -10%","None","Extreme"]]},{"type":"callout","variant":"info","title":"Why shared random matrices work","content":"VeRA\u0027s shared random matrices work because random projection matrices span a rich function space — any direction can be approximately reached by scaling random vectors, similar to how random features approximate kernel methods. The per-layer scaling vectors learn which directions in this shared random basis are most useful for each layer\u0027s task."},{"type":"list","ordered":false,"items":["Shared random seed: use the same seed across processes and runs so shared_A and shared_B are reproducible.","Rank choice: VeRA uses much larger ranks (r=64–256) than LoRA because the matrices are not learned — more columns give richer basis coverage.","Limitation: shared matrices limit expressivity when tasks require highly diverse layer-wise adaptations (e.g., multimodal models).","Memory: VeRA\u0027s shared buffers are stored once and broadcast — saves memory on multi-GPU setups vs per-layer LoRA matrices.","Stacking: VeRA scaling vectors can be task-specific; load different vec_d and vec_b for different tasks with the same base + shared random matrices."]},{"type":"divider"}]"
---
# VeRA — Vector-Based Random Matrix Adaptation for Extreme Parameter Efficiency

LoRA reduces trainable parameters by using low-rank matrices per layer, but each layer still maintains its own private A and B matrices. For a 7B parameter model with LoRA rank=16 applied to all attention projections, trainable parameters reach ~84M. VeRA (Vector-based Random matrix Adaptation, Kopiczko et al., 2024) pushes parameter efficiency further: a single pair of random matrices is shared (frozen) across all layers, and only small per-layer scaling vectors are learned. This reduces trainable parameters to approximately 1.4M — a 60× reduction over LoRA r=16 — while achieving surprisingly competitive task performance.

## VeRA Architecture — Shared Random Matrices

In VeRA, a single random matrix A ∈ ℝ^{r×d_in} and a single random matrix B ∈ ℝ^{d_out×r} are generated once (using a fixed random seed) and kept frozen across all layers. For each layer l, VeRA introduces two learnable scaling vectors: b_d^l ∈ ℝ^{d_out} (scales rows of B) and d_r^l ∈ ℝ^r (scales rows of A). The forward pass for layer l is: h += B·diag(b_d^l)·A·diag(d_r^l)·x. The diagonal scaling vectors select which directions in the shared random basis matter for each specific layer.

## VeRA Layer Implementation

The implementation instantiates the shared random matrices as buffers (not parameters) at model initialization. Per-layer trainable vectors are registered as parameters. The forward pass computes the scaled random projection via element-wise multiplication — equivalent to row-scaling of the matrices — which avoids materializing full diagonal matrices.

```python
import torch
import torch.nn as nn
import math

class VeRALinear(nn.Module):
    """VeRA adapter: shared frozen (A,B), learnable per-layer scaling vectors."""

    def __init__(self, in_features: int, out_features: int,
                 rank: int, shared_A: torch.Tensor, shared_B: torch.Tensor,
                 alpha: float = 1.0, dropout: float = 0.0):
        super().__init__()
        self.rank = rank
        self.scaling = alpha / rank
        # Base weight (frozen)
        self.weight = nn.Parameter(torch.randn(out_features, in_features), requires_grad=False)
        self.bias = nn.Parameter(torch.zeros(out_features), requires_grad=False)
        # Shared random matrices (frozen buffers, NOT trainable)
        self.register_buffer('shared_A', shared_A)  # (rank, in_features)
        self.register_buffer('shared_B', shared_B)  # (out_features, rank)
        # Per-layer trainable scaling vectors
        self.vec_d = nn.Parameter(torch.ones(rank))       # scales A rows
        self.vec_b = nn.Parameter(torch.zeros(out_features))  # scales B rows
        self.dropout = nn.Dropout(dropout)

    def forward(self, x: torch.Tensor) -> torch.Tensor:
        base = nn.functional.linear(x, self.weight, self.bias)
        # diag(d_r) @ A: scale each row of A, shape (rank, in_features)
        scaled_A = self.shared_A * self.vec_d.unsqueeze(1)
        # B @ diag(b_d): scale each row of B, shape (out_features, rank)
        scaled_B = self.shared_B * self.vec_b.unsqueeze(1)
        lora_out = nn.functional.linear(
            nn.functional.linear(self.dropout(x), scaled_A), scaled_B
        )
        return base + lora_out * self.scaling

rank, d_in, d_out = 16, 768, 768
shared_A = torch.randn(rank, d_in)
shared_B = torch.randn(d_out, rank)
layer = VeRALinear(d_in, d_out, rank, shared_A, shared_B)
x = torch.randn(4, d_in)
print(f'Output: {layer(x).shape}')
print(f'Trainable params: vec_d={layer.vec_d.numel()}, vec_b={layer.vec_b.numel()}')
```

## Parameter Count Comparison

For a model with L adapter layers, d_in and d_out, and rank r: LoRA contributes 2×L×r×d params per layer pair. VeRA contributes L×(r+d_out) for the scaling vectors, plus one shared pair (r×d_in + d_out×r) that does not scale with L. For a 7B LLaMA-style model with L=32 attention layers, d=4096, r=16: LoRA has 32×2×16×4096 = 4.2M trainable params per projection. VeRA has 32×(16+4096) = 131K trainable params — a 32× reduction per projection.

```python
import torch

def compare_param_counts(model_dims: dict, ranks: list = (4, 8, 16, 32)):
    """Compare LoRA vs VeRA trainable params for a transformer model."""
    n_layers = model_dims['n_layers']     # e.g., 32
    d_model = model_dims['d_model']       # e.g., 4096
    n_proj = model_dims['n_projections']  # Q, K, V, O = 4
    print(f'Model: {n_layers} layers, d={d_model}, {n_proj} projections')
    print(f'{"Rank":>6}  {"LoRA params":>14}  {"VeRA params":>14}  {"Ratio":>8}')
    print('-' * 50)
    for r in ranks:
        lora_params = n_layers * n_proj * 2 * r * d_model
        # VeRA: per-layer vectors + one shared pair (counted once)
        vera_per_layer = n_layers * n_proj * (r + d_model)
        vera_shared = 2 * r * d_model  # shared A and B
        vera_params = vera_per_layer + vera_shared
        ratio = lora_params / vera_params
        print(f'{r:>6}  {lora_params/1e6:>12.2f}M  {vera_params/1e6:>12.3f}M  {ratio:>7.1f}x')

compare_param_counts({'n_layers': 32, 'd_model': 4096, 'n_projections': 4})
print()
compare_param_counts({'n_layers': 32, 'd_model': 4096, 'n_projections': 4},
                     ranks=[64, 128])
```

## VeRA Training

Training VeRA requires generating the shared random matrices once with a fixed seed and replicating them across all layers. Only the scaling vectors are passed to the optimizer. The shared matrices are registered as buffers so they move to the correct device automatically but do not consume optimizer state (no Adam m/v statistics for them).

```python
import torch
import torch.nn as nn
import torch.optim as optim
from typing import List

def build_vera_model(n_layers: int, d_model: int, rank: int = 16,
                     seed: int = 42) -> nn.ModuleList:
    """Build a stack of VeRA layers sharing a single random matrix pair."""
    torch.manual_seed(seed)
    shared_A = torch.randn(rank, d_model) / (rank ** 0.5)  # normalized init
    shared_B = torch.randn(d_model, rank) / (rank ** 0.5)
    layers = nn.ModuleList([
        VeRALinear(d_model, d_model, rank, shared_A.clone(), shared_B.clone())
        for _ in range(n_layers)
    ])
    return layers

def get_vera_optimizer(model: nn.ModuleList, lr: float = 1e-3) -> optim.AdamW:
    """Only optimize scaling vectors; ignore frozen weights and shared buffers."""
    trainable = [p for p in model.parameters() if p.requires_grad]
    total = sum(p.numel() for p in trainable)
    print(f'VeRA trainable parameters: {total:,}')
    return optim.AdamW(trainable, lr=lr, weight_decay=0.01)

# Simulate training
layers = build_vera_model(n_layers=4, d_model=256, rank=16)
optimizer = get_vera_optimizer(layers)
x = torch.randn(8, 256)
for step in range(5):
    h = x
    for layer in layers:
        h = layer(h) + h  # residual
    loss = h.pow(2).mean()
    optimizer.zero_grad()
    loss.backward()
    optimizer.step()
    if step % 2 == 0:
        print(f'Step {step}: loss={loss.item():.4f}')
```

## Quality vs Parameter Efficiency

Benchmarking VeRA against LoRA and full fine-tuning reveals that VeRA achieves surprisingly competitive accuracy on language understanding tasks. The gap widens on tasks that require very different representations across layers, where the shared random basis becomes a bottleneck. However, for standard instruction following and commonsense reasoning, VeRA within ~1–3% of LoRA r=16 despite 32× fewer parameters.

```python
import torch
import math

# Approximate benchmark results from VeRA paper (Kopiczko et al. 2024)
# Evaluated on LLaMA-7B with commonsense and GLUE benchmarks
benchmark_data = [
    {'method': 'Full Fine-Tuning', 'params_M': 7000.0, 'accuracy': 0.892},
    {'method': 'LoRA r=16',        'params_M': 83.9,   'accuracy': 0.871},
    {'method': 'LoRA r=4',         'params_M': 20.9,   'accuracy': 0.859},
    {'method': 'DoRA r=16',        'params_M': 83.9,   'accuracy': 0.878},
    {'method': 'VeRA r=256',       'params_M': 1.4,    'accuracy': 0.862},
    {'method': 'IA3',              'params_M': 0.02,   'accuracy': 0.828},
]

print(f'{"Method":<20}  {"Params (M)":>12}  {"Accuracy":>10}  {"Params/FullFT":>14}')
print('-' * 65)
for entry in benchmark_data:
    frac = entry['params_M'] / 7000.0
    print(f"{entry['method']:<20}  {entry['params_M']:>12.1f}  "
          f"{entry['accuracy']:>10.3f}  {frac:>13.4%}")

# Efficiency score: accuracy / log10(params)
print('\nEfficiency score (accuracy / log10(params)):')
for entry in benchmark_data:
    score = entry['accuracy'] / math.log10(entry['params_M'] * 1e6 + 1)
    print(f"  {entry['method']:<20}: {score:.4f}")
```

## Why Random Matrices Work

The theoretical justification for VeRA comes from random feature theory. A random matrix A with i.i.d. Gaussian entries spans the entire input space in expectation — any direction can be approximately reached by a suitable linear combination of the rows. The scaling vector d_r selects which random directions to amplify, effectively constructing a task-specific projection from the shared random basis. This is analogous to random kitchen sinks (Rahimi & Recht, 2007): random features approximate a rich kernel function, and the learned weights select the relevant features for the task.

## PEFT Parameter Efficiency Comparison

| Method | Trainable Params (7B) | % of Total | Quality vs Full FT | Inference Overhead | Memory Savings |
| --- | --- | --- | --- | --- | --- |
| Full Fine-Tuning | 7,000M | 100% | Baseline | None | None |
| LoRA r=16 | ~84M | ~1.2% | -1 to -2% | Merge: none; separate: minimal | High |
| LoRA r=4 | ~21M | ~0.3% | -2 to -4% | Merge: none; separate: minimal | Very high |
| VeRA (r=256) | ~1.4M | ~0.02% | -2 to -3% | Shared buffers; minimal | Extreme |
| Prefix Tuning (P=100) | ~5M | ~0.07% | -3 to -5% | Extra KV cache per layer | High |
| IA3 | ~0.02M | ~0.0003% | -6 to -10% | None | Extreme |

> **Why shared random matrices work**: VeRA's shared random matrices work because random projection matrices span a rich function space — any direction can be approximately reached by scaling random vectors, similar to how random features approximate kernel methods. The per-layer scaling vectors learn which directions in this shared random basis are most useful for each layer's task.

- Shared random seed: use the same seed across processes and runs so shared_A and shared_B are reproducible.
- Rank choice: VeRA uses much larger ranks (r=64–256) than LoRA because the matrices are not learned — more columns give richer basis coverage.
- Limitation: shared matrices limit expressivity when tasks require highly diverse layer-wise adaptations (e.g., multimodal models).
- Memory: VeRA's shared buffers are stored once and broadcast — saves memory on multi-GPU setups vs per-layer LoRA matrices.
- Stacking: VeRA scaling vectors can be task-specific; load different vec_d and vec_b for different tasks with the same base + shared random matrices.

---

