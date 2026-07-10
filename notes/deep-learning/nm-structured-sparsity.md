---
title: "N:M Sparsity — Hardware-Accelerated Structured Sparsity"
slug: "nm-structured-sparsity"
description: "N:M sparsity (e.g., 2:4) requires exactly N nonzeros per M consecutive weights, enabling 2× throughput via NVIDIA Sparse Tensor Cores. Covers mask generation, training-time enforcement, compression format, and accuracy vs hardware trade-offs."
tags: ["deep-learning", "model-compression", "pruning", "quantization"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"N:M sparsity is a structured sparsity pattern where, within every consecutive group of M weights, exactly N are nonzero. The 2:4 pattern (2 nonzeros per 4 weights, 50% sparsity) is natively supported by NVIDIA A100 and later GPUs via Sparse Tensor Cores, delivering up to 2× throughput for linear layers with minimal accuracy loss. Unlike unstructured sparsity, 2:4 requires no specialized sparse solver — the hardware handles it transparently."},{"type":"heading","level":2,"content":"How Sparse Tensor Cores Work"},{"type":"text","content":"In the compressed 2:4 representation, each group of 4 consecutive weights stores only 2 values plus a 2-bit index pair indicating their positions (00, 01, 10, or 11). The weight matrix is compressed to 50% storage. During matrix multiplication, the hardware unpacks the indices and multiplies only the nonzero values with the corresponding activations — effectively computing a sparse GEMM with no wasted multiplications. This is only available for linear (dense matmul) layers; batch norm, embeddings, and depthwise convolutions see no benefit."},{"type":"heading","level":2,"content":"2:4 Mask Generation"},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\n\ndef generate_2_4_mask(weight: torch.Tensor) -\u003e torch.Tensor:\n    \"\"\"\n    Generate a 2:4 sparsity mask: keep 2 largest-magnitude weights per group of 4.\n    weight: any shape; last dim is grouped into blocks of 4.\n    Returns a boolean mask of same shape.\n    \"\"\"\n    original_shape = weight.shape\n    # Flatten to 2D: (rows, cols) where cols must be divisible by 4\n    w2d = weight.view(-1, weight.shape[-1])  # (..., C) -\u003e (N, C)\n    N, C = w2d.shape\n    assert C % 4 == 0, f\u0027Last dim {C} must be divisible by 4 for 2:4 sparsity\u0027\n\n    # Group into blocks of 4\n    w_grouped = w2d.view(N, C // 4, 4)  # (N, C//4, 4)\n    # Find top-2 magnitudes within each group\n    _, top_idx = w_grouped.abs().topk(2, dim=-1)  # (N, C//4, 2)\n    # Build mask\n    mask = torch.zeros_like(w_grouped, dtype=torch.bool)\n    mask.scatter_(-1, top_idx, True)\n    return mask.view(original_shape)\n\n# Demonstrate\ntorch.manual_seed(42)\nW = torch.randn(4, 8)  # 4 output neurons, 8 inputs\nmask = generate_2_4_mask(W)\nprint(\u0027Weight matrix:\u0027)\nprint(W.round(decimals=2))\nprint(\u0027\\n2:4 Mask (1=keep, 0=prune):\u0027)\nprint(mask.int())\nprint(\u0027\\nSparse weight:\u0027)\nprint((W * mask).round(decimals=2))\nprint(f\u0027\\nSparsity: {(~mask).float().mean().item():.1%}\u0027)"},{"type":"heading","level":2,"content":"Training with 2:4 Constraint"},{"type":"text","content":"The 2:4 constraint can be applied post-training (prune + short fine-tune) or enforced during training by re-applying the mask every N gradient steps. During training, the mask is recomputed periodically from the current weight magnitudes, and weights outside the mask are zeroed. Gradients still flow through all positions, but the zeroed weights are re-zeroed before each forward pass. This allows the network to re-allocate the 2 kept positions within each group as training progresses."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.optim as optim\n\nclass SparseLinear24(nn.Module):\n    \"\"\"Linear layer that enforces 2:4 sparsity on its weight matrix.\"\"\"\n\n    def __init__(self, in_features: int, out_features: int):\n        super().__init__()\n        assert in_features % 4 == 0, \u0027in_features must be divisible by 4\u0027\n        self.linear = nn.Linear(in_features, out_features)\n        self.mask = self._compute_mask()\n\n    def _compute_mask(self) -\u003e torch.Tensor:\n        W = self.linear.weight.data  # (out, in)\n        w_grouped = W.view(W.shape[0], W.shape[1] // 4, 4)\n        _, idx = w_grouped.abs().topk(2, dim=-1)\n        mask = torch.zeros_like(w_grouped, dtype=torch.bool)\n        mask.scatter_(-1, idx, True)\n        return mask.view(W.shape)\n\n    def apply_mask(self):\n        \"\"\"Re-prune and re-zero weights outside the current mask.\"\"\"\n        self.mask = self._compute_mask()\n        with torch.no_grad():\n            self.linear.weight.data *= self.mask.float()\n\n    def forward(self, x: torch.Tensor) -\u003e torch.Tensor:\n        return self.linear(x)\n\n# Simulate 2:4 training loop\nmodel = SparseLinear24(64, 32)\noptimizer = optim.SGD(model.parameters(), lr=0.01)\nremask_every = 10  # re-apply 2:4 mask every 10 steps\n\nfor step in range(30):\n    x = torch.randn(16, 64)\n    loss = model(x).pow(2).mean()\n    optimizer.zero_grad()\n    loss.backward()\n    optimizer.step()\n    if (step + 1) % remask_every == 0:\n        model.apply_mask()\n        density = model.mask.float().mean().item()\n        print(f\u0027Step {step+1}: loss={loss.item():.4f}  density={density:.2f}\u0027)"},{"type":"heading","level":2,"content":"Compressed Storage Format"},{"type":"text","content":"In the 2:4 compressed format, a weight matrix of shape (M, K) is stored as: (1) a value tensor of shape (M, K/2) containing the 2 nonzero values per group and (2) a metadata tensor of shape (M, K/8) containing 2-bit indices (4 bits per group of 4). Total storage: K/2 values × element_size + K/8 metadata bytes. For FP16 weights, this is (K/2 × 2) + (K/8) = 5K/8 bytes vs K × 2 = 2K bytes uncompressed — a 3.2× reduction in storage per row."},{"type":"code","language":"python","content":"import torch\nimport numpy as np\n\ndef compress_2_4(weight: torch.Tensor):\n    \"\"\"\n    Simulate 2:4 compression: returns (values, metadata) tensors.\n    values: nonzero elements, shape (rows, cols//2)\n    metadata: 4-bit indices packed as uint8, shape (rows, cols//8)\n    \"\"\"\n    W = weight.view(-1, weight.shape[-1])  # (N, C)\n    N, C = W.shape\n    assert C % 4 == 0\n    w_grouped = W.view(N, C // 4, 4)  # (N, G, 4) where G = C//4\n    scores, indices = w_grouped.abs().topk(2, dim=-1)  # (N, G, 2)\n    # Gather nonzero values\n    values = w_grouped.gather(-1, indices)  # (N, G, 2)\n    values_flat = values.reshape(N, C // 2)  # (N, C//2)\n    # Pack indices as 4 bits per group (2 positions in {0,1,2,3})\n    # Each index fits in 2 bits; 4 bits per group of 4\n    idx_sorted = indices.sort(dim=-1).values  # ensure ascending order\n    meta = (idx_sorted[..., 0] * 4 + idx_sorted[..., 1]).to(torch.uint8)  # (N, G)\n    return values_flat, meta\n\nW = torch.randn(8, 16)\nvals, meta = compress_2_4(W)\n\nuncompressed_bytes = W.numel() * 4  # float32\ncompressed_bytes = vals.numel() * 4 + meta.numel()  # float32 vals + uint8 meta\nprint(f\u0027Original: {W.shape}  -\u003e  {uncompressed_bytes} bytes\u0027)\nprint(f\u0027Values:   {vals.shape},  Metadata: {meta.shape}\u0027)\nprint(f\u0027Compressed: {compressed_bytes} bytes  (ratio {uncompressed_bytes/compressed_bytes:.2f}x)\u0027)\nprint(f\u0027Density check: {vals.numel()}/{W.numel()} = {vals.numel()/W.numel():.0%}\u0027)"},{"type":"callout","variant":"warning","title":"2:4 Only Helps on A100+ for Linear Layers","content":"Sparse Tensor Core acceleration is only available on NVIDIA Ampere (A100) and later GPUs. On earlier GPUs (V100, T4) or on CPU, 2:4 sparsity provides no speedup — the sparse zeros still participate in computation. Additionally, only linear (matmul) layers benefit; depthwise convolutions, batch norm, and embeddings remain dense. For CPU deployment, unstructured sparsity with SpMM or full structured pruning are better choices."},{"type":"heading","level":2,"content":"Accuracy vs Dense Baseline"},{"type":"text","content":"NVIDIA\u0027s experiments on ResNet-50 and BERT show that 2:4 sparsity with 10–20 epochs of fine-tuning recovers to within 0.1–0.5% of the dense baseline. The key insight is that within each group of 4, the 2 surviving weights can be any pair — this gives the network enough flexibility to represent the same functions as the dense model. Larger models (GPT-3 scale) show even smaller accuracy gaps, as the redundancy in large models makes it easier to prune half the weights without losing function."},{"type":"heading","level":2,"content":"Comparison of Sparsity Formats"},{"type":"table","headers":["Format","Sparsity","A100 Speedup","Accuracy vs Dense","Hardware Support","Implementation Difficulty"],"rows":[["Dense (baseline)","0%","1×","Baseline","All hardware","Trivial"],["2:4 (N=2, M=4)","50%","~2×","-0.1 to -0.5%","A100+ only (Ampere)","Low — torch.nn.utils.prune or apex"],["1:4 (N=1, M=4)","75%","~2× (same HW path)","-2 to -5%","A100+ only","Low — same tooling"],["Unstructured 50%","50%","~1× (no HW support)","-0.5 to -2%","None (standard GPU)","Low — threshold mask"],["Structured filter 50%","50% of filters","~1.5–2× (any GPU)","-1 to -3%","All hardware","High — reshape dependent layers"]]},{"type":"heading","level":2,"content":"Applying 2:4 Sparsity with PyTorch Semi-Structured Pruning"},{"type":"text","content":"PyTorch 2.1+ includes torch.sparse.SparseSemiStructuredTensor which wraps the 2:4 compressed format. Calling to_sparse_semi_structured(weight) returns a tensor that participates transparently in nn.Linear forward and backward passes, using cuSPARSELt under the hood on A100 GPUs. No changes to the model\u0027s forward method are required — simply convert the weight tensor after pruning."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\n# Requires PyTorch \u003e= 2.1 and CUDA A100+\n# from torch.sparse import to_sparse_semi_structured, SparseSemiStructuredTensor\n\ndef apply_2_4_to_model(model: nn.Module, verbose: bool = True):\n    \"\"\"\n    Apply 2:4 structured sparsity to all Linear layers.\n    Prune in-place using magnitude criterion, then convert to semi-structured format.\n    \"\"\"\n    n_converted = 0\n    for name, module in model.named_modules():\n        if not isinstance(module, nn.Linear):\n            continue\n        W = module.weight.data\n        if W.shape[1] % 4 != 0:\n            if verbose:\n                print(f\u0027  Skip {name}: in_features={W.shape[1]} not divisible by 4\u0027)\n            continue\n        # Generate 2:4 mask and apply\n        w_grouped = W.view(W.shape[0], W.shape[1] // 4, 4)\n        _, idx = w_grouped.abs().topk(2, dim=-1)\n        mask = torch.zeros_like(w_grouped, dtype=torch.bool)\n        mask.scatter_(-1, idx, True)\n        module.weight.data = W * mask.view(W.shape).float()\n        n_converted += 1\n        if verbose:\n            density = mask.float().mean().item()\n            print(f\u0027  {name}: {W.shape} pruned, density={density:.2f}\u0027)\n    print(f\u0027Applied 2:4 sparsity to {n_converted} Linear layers.\u0027)\n\nmodel = nn.Sequential(nn.Linear(64, 128), nn.ReLU(), nn.Linear(128, 32))\napply_2_4_to_model(model)"},{"type":"text","content":"After applying 2:4 sparsity, re-training (fine-tuning) for 10–20 epochs with a small learning rate (10% of original) is sufficient to recover baseline accuracy on most tasks. Training-time 2:4 (enforcing the constraint throughout training) gives slightly better accuracy than post-training pruning but requires modifying the training loop to re-mask every few steps."},{"type":"list","ordered":false,"items":["2:4 is the sweet spot: 50% sparsity with 2× hardware speedup at near-zero accuracy cost.","Metadata overhead: 2-bit index per position adds 6.25% storage overhead over the dense values-only storage.","Only matmul layers benefit: skip 2:4 for depthwise conv, batch norm, and embedding layers.","Re-masking frequency during training: every 100–1000 steps; too frequent slows training, too rare wastes capacity.","For INT8 + 2:4: A100 supports INT8 Sparse Tensor Cores giving up to 4× throughput vs FP16 dense."]},{"type":"divider"}]"
---
# N:M Sparsity — Hardware-Accelerated Structured Sparsity

N:M sparsity is a structured sparsity pattern where, within every consecutive group of M weights, exactly N are nonzero. The 2:4 pattern (2 nonzeros per 4 weights, 50% sparsity) is natively supported by NVIDIA A100 and later GPUs via Sparse Tensor Cores, delivering up to 2× throughput for linear layers with minimal accuracy loss. Unlike unstructured sparsity, 2:4 requires no specialized sparse solver — the hardware handles it transparently.

## How Sparse Tensor Cores Work

In the compressed 2:4 representation, each group of 4 consecutive weights stores only 2 values plus a 2-bit index pair indicating their positions (00, 01, 10, or 11). The weight matrix is compressed to 50% storage. During matrix multiplication, the hardware unpacks the indices and multiplies only the nonzero values with the corresponding activations — effectively computing a sparse GEMM with no wasted multiplications. This is only available for linear (dense matmul) layers; batch norm, embeddings, and depthwise convolutions see no benefit.

## 2:4 Mask Generation

```python
import torch
import torch.nn as nn

def generate_2_4_mask(weight: torch.Tensor) -> torch.Tensor:
    """
    Generate a 2:4 sparsity mask: keep 2 largest-magnitude weights per group of 4.
    weight: any shape; last dim is grouped into blocks of 4.
    Returns a boolean mask of same shape.
    """
    original_shape = weight.shape
    # Flatten to 2D: (rows, cols) where cols must be divisible by 4
    w2d = weight.view(-1, weight.shape[-1])  # (..., C) -> (N, C)
    N, C = w2d.shape
    assert C % 4 == 0, f'Last dim {C} must be divisible by 4 for 2:4 sparsity'

    # Group into blocks of 4
    w_grouped = w2d.view(N, C // 4, 4)  # (N, C//4, 4)
    # Find top-2 magnitudes within each group
    _, top_idx = w_grouped.abs().topk(2, dim=-1)  # (N, C//4, 2)
    # Build mask
    mask = torch.zeros_like(w_grouped, dtype=torch.bool)
    mask.scatter_(-1, top_idx, True)
    return mask.view(original_shape)

# Demonstrate
torch.manual_seed(42)
W = torch.randn(4, 8)  # 4 output neurons, 8 inputs
mask = generate_2_4_mask(W)
print('Weight matrix:')
print(W.round(decimals=2))
print('\n2:4 Mask (1=keep, 0=prune):')
print(mask.int())
print('\nSparse weight:')
print((W * mask).round(decimals=2))
print(f'\nSparsity: {(~mask).float().mean().item():.1%}')
```

## Training with 2:4 Constraint

The 2:4 constraint can be applied post-training (prune + short fine-tune) or enforced during training by re-applying the mask every N gradient steps. During training, the mask is recomputed periodically from the current weight magnitudes, and weights outside the mask are zeroed. Gradients still flow through all positions, but the zeroed weights are re-zeroed before each forward pass. This allows the network to re-allocate the 2 kept positions within each group as training progresses.

```python
import torch
import torch.nn as nn
import torch.optim as optim

class SparseLinear24(nn.Module):
    """Linear layer that enforces 2:4 sparsity on its weight matrix."""

    def __init__(self, in_features: int, out_features: int):
        super().__init__()
        assert in_features % 4 == 0, 'in_features must be divisible by 4'
        self.linear = nn.Linear(in_features, out_features)
        self.mask = self._compute_mask()

    def _compute_mask(self) -> torch.Tensor:
        W = self.linear.weight.data  # (out, in)
        w_grouped = W.view(W.shape[0], W.shape[1] // 4, 4)
        _, idx = w_grouped.abs().topk(2, dim=-1)
        mask = torch.zeros_like(w_grouped, dtype=torch.bool)
        mask.scatter_(-1, idx, True)
        return mask.view(W.shape)

    def apply_mask(self):
        """Re-prune and re-zero weights outside the current mask."""
        self.mask = self._compute_mask()
        with torch.no_grad():
            self.linear.weight.data *= self.mask.float()

    def forward(self, x: torch.Tensor) -> torch.Tensor:
        return self.linear(x)

# Simulate 2:4 training loop
model = SparseLinear24(64, 32)
optimizer = optim.SGD(model.parameters(), lr=0.01)
remask_every = 10  # re-apply 2:4 mask every 10 steps

for step in range(30):
    x = torch.randn(16, 64)
    loss = model(x).pow(2).mean()
    optimizer.zero_grad()
    loss.backward()
    optimizer.step()
    if (step + 1) % remask_every == 0:
        model.apply_mask()
        density = model.mask.float().mean().item()
        print(f'Step {step+1}: loss={loss.item():.4f}  density={density:.2f}')
```

## Compressed Storage Format

In the 2:4 compressed format, a weight matrix of shape (M, K) is stored as: (1) a value tensor of shape (M, K/2) containing the 2 nonzero values per group and (2) a metadata tensor of shape (M, K/8) containing 2-bit indices (4 bits per group of 4). Total storage: K/2 values × element_size + K/8 metadata bytes. For FP16 weights, this is (K/2 × 2) + (K/8) = 5K/8 bytes vs K × 2 = 2K bytes uncompressed — a 3.2× reduction in storage per row.

```python
import torch
import numpy as np

def compress_2_4(weight: torch.Tensor):
    """
    Simulate 2:4 compression: returns (values, metadata) tensors.
    values: nonzero elements, shape (rows, cols//2)
    metadata: 4-bit indices packed as uint8, shape (rows, cols//8)
    """
    W = weight.view(-1, weight.shape[-1])  # (N, C)
    N, C = W.shape
    assert C % 4 == 0
    w_grouped = W.view(N, C // 4, 4)  # (N, G, 4) where G = C//4
    scores, indices = w_grouped.abs().topk(2, dim=-1)  # (N, G, 2)
    # Gather nonzero values
    values = w_grouped.gather(-1, indices)  # (N, G, 2)
    values_flat = values.reshape(N, C // 2)  # (N, C//2)
    # Pack indices as 4 bits per group (2 positions in {0,1,2,3})
    # Each index fits in 2 bits; 4 bits per group of 4
    idx_sorted = indices.sort(dim=-1).values  # ensure ascending order
    meta = (idx_sorted[..., 0] * 4 + idx_sorted[..., 1]).to(torch.uint8)  # (N, G)
    return values_flat, meta

W = torch.randn(8, 16)
vals, meta = compress_2_4(W)

uncompressed_bytes = W.numel() * 4  # float32
compressed_bytes = vals.numel() * 4 + meta.numel()  # float32 vals + uint8 meta
print(f'Original: {W.shape}  ->  {uncompressed_bytes} bytes')
print(f'Values:   {vals.shape},  Metadata: {meta.shape}')
print(f'Compressed: {compressed_bytes} bytes  (ratio {uncompressed_bytes/compressed_bytes:.2f}x)')
print(f'Density check: {vals.numel()}/{W.numel()} = {vals.numel()/W.numel():.0%}')
```

> **2:4 Only Helps on A100+ for Linear Layers**: Sparse Tensor Core acceleration is only available on NVIDIA Ampere (A100) and later GPUs. On earlier GPUs (V100, T4) or on CPU, 2:4 sparsity provides no speedup — the sparse zeros still participate in computation. Additionally, only linear (matmul) layers benefit; depthwise convolutions, batch norm, and embeddings remain dense. For CPU deployment, unstructured sparsity with SpMM or full structured pruning are better choices.

## Accuracy vs Dense Baseline

NVIDIA's experiments on ResNet-50 and BERT show that 2:4 sparsity with 10–20 epochs of fine-tuning recovers to within 0.1–0.5% of the dense baseline. The key insight is that within each group of 4, the 2 surviving weights can be any pair — this gives the network enough flexibility to represent the same functions as the dense model. Larger models (GPT-3 scale) show even smaller accuracy gaps, as the redundancy in large models makes it easier to prune half the weights without losing function.

## Comparison of Sparsity Formats

| Format | Sparsity | A100 Speedup | Accuracy vs Dense | Hardware Support | Implementation Difficulty |
| --- | --- | --- | --- | --- | --- |
| Dense (baseline) | 0% | 1× | Baseline | All hardware | Trivial |
| 2:4 (N=2, M=4) | 50% | ~2× | -0.1 to -0.5% | A100+ only (Ampere) | Low — torch.nn.utils.prune or apex |
| 1:4 (N=1, M=4) | 75% | ~2× (same HW path) | -2 to -5% | A100+ only | Low — same tooling |
| Unstructured 50% | 50% | ~1× (no HW support) | -0.5 to -2% | None (standard GPU) | Low — threshold mask |
| Structured filter 50% | 50% of filters | ~1.5–2× (any GPU) | -1 to -3% | All hardware | High — reshape dependent layers |

## Applying 2:4 Sparsity with PyTorch Semi-Structured Pruning

PyTorch 2.1+ includes torch.sparse.SparseSemiStructuredTensor which wraps the 2:4 compressed format. Calling to_sparse_semi_structured(weight) returns a tensor that participates transparently in nn.Linear forward and backward passes, using cuSPARSELt under the hood on A100 GPUs. No changes to the model's forward method are required — simply convert the weight tensor after pruning.

```python
import torch
import torch.nn as nn
# Requires PyTorch >= 2.1 and CUDA A100+
# from torch.sparse import to_sparse_semi_structured, SparseSemiStructuredTensor

def apply_2_4_to_model(model: nn.Module, verbose: bool = True):
    """
    Apply 2:4 structured sparsity to all Linear layers.
    Prune in-place using magnitude criterion, then convert to semi-structured format.
    """
    n_converted = 0
    for name, module in model.named_modules():
        if not isinstance(module, nn.Linear):
            continue
        W = module.weight.data
        if W.shape[1] % 4 != 0:
            if verbose:
                print(f'  Skip {name}: in_features={W.shape[1]} not divisible by 4')
            continue
        # Generate 2:4 mask and apply
        w_grouped = W.view(W.shape[0], W.shape[1] // 4, 4)
        _, idx = w_grouped.abs().topk(2, dim=-1)
        mask = torch.zeros_like(w_grouped, dtype=torch.bool)
        mask.scatter_(-1, idx, True)
        module.weight.data = W * mask.view(W.shape).float()
        n_converted += 1
        if verbose:
            density = mask.float().mean().item()
            print(f'  {name}: {W.shape} pruned, density={density:.2f}')
    print(f'Applied 2:4 sparsity to {n_converted} Linear layers.')

model = nn.Sequential(nn.Linear(64, 128), nn.ReLU(), nn.Linear(128, 32))
apply_2_4_to_model(model)
```

After applying 2:4 sparsity, re-training (fine-tuning) for 10–20 epochs with a small learning rate (10% of original) is sufficient to recover baseline accuracy on most tasks. Training-time 2:4 (enforcing the constraint throughout training) gives slightly better accuracy than post-training pruning but requires modifying the training loop to re-mask every few steps.

- 2:4 is the sweet spot: 50% sparsity with 2× hardware speedup at near-zero accuracy cost.
- Metadata overhead: 2-bit index per position adds 6.25% storage overhead over the dense values-only storage.
- Only matmul layers benefit: skip 2:4 for depthwise conv, batch norm, and embedding layers.
- Re-masking frequency during training: every 100–1000 steps; too frequent slows training, too rare wastes capacity.
- For INT8 + 2:4: A100 supports INT8 Sparse Tensor Cores giving up to 4× throughput vs FP16 dense.

---

