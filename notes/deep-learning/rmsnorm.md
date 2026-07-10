---
title: "RMSNorm — Simplified Layer Norm in LLaMA and Gemma"
slug: "rmsnorm"
description: "Derive RMSNorm by removing mean subtraction from LN, benchmark its speed advantage, implement LLaMA-style pre-norm transformer blocks, and verify when RMSNorm equals LN."
tags: ["deep-learning", "neural-networks"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"RMSNorm (Zhang \u0026 Sennrich 2019) simplifies Layer Normalization by removing the mean subtraction step, keeping only the root-mean-square scaling. The intuition — called the re-centering hypothesis — is that mean subtraction adds compute without meaningful benefit in practice, since the scale and shift parameters γ and β can absorb any centering. RMSNorm achieves 10–15% faster forward and backward passes than LayerNorm and has become the default normalization in virtually all modern large language models."},{"type":"heading","level":2,"content":"RMSNorm Formula"},{"type":"text","content":"RMSNorm computes: RMS(x) = √((1/n) Σᵢ xᵢ²) — the root mean square of the input (no mean subtraction). x̂ᵢ = xᵢ / RMS(x) — divide each element by the RMS. yᵢ = γᵢ · x̂ᵢ — apply a learned scale γ (no bias β). The key difference from LayerNorm: no mean computation, no subtraction, no β parameter. This removes the re-centering operation entirely, keeping only re-scaling. The gradient is also simpler: ∂L/∂xᵢ = (1/RMS) · [∂L/∂ŷᵢ · γᵢ − x̂ᵢ · (1/n) Σⱼ ∂L/∂ŷⱼ · γⱼ · x̂ⱼ]."},{"type":"code","language":"python","content":"import numpy as np\nimport torch\nimport torch.nn as nn\n\ndef rmsnorm_numpy(x, gamma, eps=1e-6):\n    # RMS over the last dimension (feature dim)\n    rms = np.sqrt(np.mean(x ** 2, axis=-1, keepdims=True) + eps)\n    return gamma * (x / rms)\n\nclass RMSNorm(nn.Module):\n    def __init__(self, dim, eps=1e-6):\n        super().__init__()\n        self.eps = eps\n        self.weight = nn.Parameter(torch.ones(dim))\n    def forward(self, x):\n        rms = x.pow(2).mean(dim=-1, keepdim=True).add(self.eps).sqrt()\n        return self.weight * (x / rms)\n\nnp.random.seed(42)\nB, T, C = 2, 10, 64\nx_np = np.random.randn(B, T, C).astype(np.float32)\ngamma_np = np.ones(C, dtype=np.float32)\nout_np = rmsnorm_numpy(x_np, gamma_np)\n\nx_torch = torch.tensor(x_np)\nrms_torch = RMSNorm(C)\nout_torch = rms_torch(x_torch).detach().numpy()\n\nprint(f\u0027Max diff numpy vs PyTorch: {np.abs(out_np - out_torch).max():.2e}\u0027)\nprint(f\u0027RMS of output (should ~1): {np.sqrt(np.mean(out_np**2, axis=-1)).mean():.4f}\u0027)\nprint(f\u0027Mean of output (not forced to 0): {out_np.mean(axis=-1).mean():.4f}\u0027)"},{"type":"heading","level":2,"content":"Motivation — Why Remove Mean Subtraction?"},{"type":"text","content":"The re-centering hypothesis states that the learned bias β in LayerNorm can absorb any constant shift, making explicit mean subtraction redundant. Empirically, removing mean computation saves memory bandwidth and arithmetic: for a feature vector of dimension d, LayerNorm requires two passes (one for mean, one for variance); RMSNorm requires one pass (variance around zero). This translates to approximately 10–15% wall-clock speedup on large tensors, which compounds significantly across thousands of transformer blocks in LLM training."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport time\n\ndevice = \u0027cuda\u0027 if torch.cuda.is_available() else \u0027cpu\u0027\n\nclass RMSNorm(nn.Module):\n    def __init__(self, dim, eps=1e-6):\n        super().__init__()\n        self.eps = eps\n        self.weight = nn.Parameter(torch.ones(dim))\n    def forward(self, x):\n        rms = x.pow(2).mean(-1, keepdim=True).add(self.eps).sqrt()\n        return self.weight * (x / rms)\n\nB, T, C = 32, 2048, 4096\nx = torch.randn(B, T, C, device=device)\nln = nn.LayerNorm(C).to(device)\nrms = RMSNorm(C).to(device)\n\ndef benchmark(fn, x, n=50):\n    for _ in range(5):  # warmup\n        fn(x)\n    if device == \u0027cuda\u0027:\n        torch.cuda.synchronize()\n    t0 = time.perf_counter()\n    for _ in range(n):\n        fn(x)\n    if device == \u0027cuda\u0027:\n        torch.cuda.synchronize()\n    return (time.perf_counter() - t0) / n * 1000\n\nln_ms = benchmark(ln, x)\nrms_ms = benchmark(rms, x)\nprint(f\u0027LayerNorm : {ln_ms:.3f} ms\u0027)\nprint(f\u0027RMSNorm   : {rms_ms:.3f} ms\u0027)\nprint(f\u0027Speedup   : {ln_ms/rms_ms:.2f}x\u0027)"},{"type":"heading","level":2,"content":"RMSNorm in Modern LLMs"},{"type":"text","content":"RMSNorm has become the default normalization for nearly all open-weight LLMs: LLaMA 1/2/3, Gemma 1/2, Mistral, Mixtral, Falcon, Qwen, and Phi all use RMSNorm with Pre-Norm placement. The standard placement is before the attention sublayer and before the feed-forward sublayer — two RMSNorm operations per transformer block. The final hidden state before the language model head receives one additional RMSNorm. LLaMA uses ε=1e-5; Gemma uses ε=1e-6. The weight γ is initialized to 1.0."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.nn.functional as F\n\nclass RMSNorm(nn.Module):\n    def __init__(self, dim, eps=1e-5):\n        super().__init__()\n        self.eps = eps\n        self.weight = nn.Parameter(torch.ones(dim))\n    def forward(self, x):\n        rms = x.pow(2).mean(-1, keepdim=True).add(self.eps).sqrt()\n        return self.weight * (x / rms)\n\nclass LLaMABlock(nn.Module):\n    def __init__(self, d_model, nhead, dim_ff):\n        super().__init__()\n        self.attn = nn.MultiheadAttention(d_model, nhead, batch_first=True)\n        self.ff = nn.Sequential(\n            nn.Linear(d_model, dim_ff, bias=False),\n            nn.SiLU(),\n            nn.Linear(dim_ff, d_model, bias=False)\n        )\n        self.rms1 = RMSNorm(d_model)  # before attention\n        self.rms2 = RMSNorm(d_model)  # before feed-forward\n    def forward(self, x):\n        n1 = self.rms1(x)\n        x = x + self.attn(n1, n1, n1)[0]\n        x = x + self.ff(self.rms2(x))\n        return x\n\nd_model, nhead, dim_ff = 128, 4, 512\nblock = LLaMABlock(d_model, nhead, dim_ff)\nx = torch.randn(2, 32, d_model)\nout = block(x)\nprint(f\u0027Input  norm: {x.norm(dim=-1).mean():.4f}\u0027)\nprint(f\u0027Output norm: {out.norm(dim=-1).mean():.4f}\u0027)\nprint(f\u0027Params: {sum(p.numel() for p in block.parameters()):,}\u0027)"},{"type":"callout","variant":"info","title":"Pre-Norm Placement in LLaMA","content":"In LLaMA-style models, RMSNorm is applied before attention (input_layernorm) and before the feed-forward network (post_attention_layernorm). A final RMSNorm is applied to the last hidden state before the unembedding layer. No normalization is applied to the embedding table output itself in LLaMA (unlike BERT)."},{"type":"heading","level":2,"content":"When Does Mean Subtraction Matter?"},{"type":"text","content":"If the input to a normalization layer has a significant non-zero mean shift (e.g., from a biased residual accumulation), LN\u0027s mean subtraction corrects it while RMSNorm leaves the shift for γ and β to handle. In practice, pre-norm placement means the residual stream is re-normalized frequently, and the mean shift accumulates very slowly. Empirical results across LLaMA, Gemma, and Mistral training show that RMSNorm matches LN perplexity to within 0.1–0.5% on standard benchmarks."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\n\nclass RMSNorm(nn.Module):\n    def __init__(self, dim, eps=1e-6):\n        super().__init__()\n        self.weight = nn.Parameter(torch.ones(dim))\n        self.eps = eps\n    def forward(self, x):\n        return self.weight * x / x.pow(2).mean(-1, keepdim=True).add(self.eps).sqrt()\n\ntorch.manual_seed(0)\ndim = 256\n\n# Case 1: zero-mean input — RMSNorm and LN should agree\nx_zeromean = torch.randn(16, dim)  # standard normal is zero-mean\nln = nn.LayerNorm(dim)\nrms = RMSNorm(dim)\nout_ln  = ln(x_zeromean)\nout_rms = rms(x_zeromean)\ndiff_zeromean = (out_ln - out_rms).abs().mean().item()\n\n# Case 2: shifted input — LN corrects shift, RMSNorm does not\nx_shifted = x_zeromean + 5.0  # add constant shift\nout_ln2  = ln(x_shifted)\nout_rms2 = rms(x_shifted)\ndiff_shifted = (out_ln2 - out_rms2).abs().mean().item()\n\nprint(f\u0027Zero-mean input  — LN vs RMSNorm mean abs diff: {diff_zeromean:.4f}\u0027)\nprint(f\u0027Shifted input (+5) — LN vs RMSNorm mean abs diff: {diff_shifted:.4f}\u0027)\nprint(\u0027RMSNorm matches LN closely for zero-mean inputs (typical after normalization).\u0027)"},{"type":"heading","level":2,"content":"Gradient and Numerical Properties"},{"type":"text","content":"The RMSNorm backward pass is simpler than LayerNorm: there is no centering term in the gradient. The gradient ∂L/∂x has the form (γᵢ/RMS) · [∂L/∂ŷᵢ − x̂ᵢ · mean(∂L/∂ŷⱼ · x̂ⱼ)] — a single dot-product correction instead of LayerNorm\u0027s two correction terms. The ε value matters: LLaMA uses 1e-5, Gemma uses 1e-6. Too small an ε causes NaN when inputs have near-zero magnitude; too large biases the normalization. In bfloat16 training, ε is sometimes increased to 1e-5 or higher for numerical safety."},{"type":"heading","level":2,"content":"Implementation Details"},{"type":"text","content":"Fused RMSNorm kernels (available in FlashAttention and Apex) compute the normalization in a single GPU kernel pass, eliminating the memory bandwidth bottleneck of reading x twice. The weight γ is typically stored in fp32 even when the activations are in bf16, to maintain precision in the scale parameters. Hugging Face Transformers implements LlamaRMSNorm with an upcast to fp32 for the normalization computation, downcast back to the activation dtype for output."},{"type":"list","ordered":false,"items":["No β parameter: RMSNorm has only γ (scale), not β (shift) — this saves parameters and slightly simplifies the computation graph.","Fused kernels: use apex.normalization.FusedRMSNorm or flash_attn.ops.rms_norm for maximum throughput.","Upcast to fp32: the pow/mean/sqrt sequence is numerically safer in fp32 even when activations are bf16.","ε tuning: increase ε to 1e-5 if you see NaN losses in the first few steps of training with bf16 precision.","Initialization: γ initialized to 1.0 (ones), which means the layer is an identity map at initialization."]},{"type":"heading","level":2,"content":"LN vs RMSNorm vs BN Comparison"},{"type":"table","headers":["Property","LayerNorm","RMSNorm","BatchNorm"],"rows":[["Formula","x̂=(x−μ)/σ, y=γx̂+β","x̂=x/RMS(x), y=γx̂","x̂=(x−μ_B)/σ_B, y=γx̂+β"],["Mean subtraction","Yes","No","Yes (over batch)"],["Learnable params","γ and β per feature","γ per feature only","γ and β per feature"],["Compute cost (relative)","1.0×","~0.85–0.90×","1.0× (+ running stats)"],["Batch dependence","None","None","Yes — train/eval gap"],["Used in","BERT, T5, GPT-2 (early)","LLaMA, Gemma, Mistral, Falcon","ResNet, EfficientNet, VGG"]]},{"type":"text","content":"For new Transformer-based models, RMSNorm is the recommended default. It delivers the same empirical performance as LayerNorm with lower compute cost. LayerNorm remains appropriate when loading pretrained checkpoints that used it (BERT, T5, early GPT-2). BatchNorm is inappropriate for autoregressive language models and sequence models with variable lengths."},{"type":"divider"}]"
---
# RMSNorm — Simplified Layer Norm in LLaMA and Gemma

RMSNorm (Zhang & Sennrich 2019) simplifies Layer Normalization by removing the mean subtraction step, keeping only the root-mean-square scaling. The intuition — called the re-centering hypothesis — is that mean subtraction adds compute without meaningful benefit in practice, since the scale and shift parameters γ and β can absorb any centering. RMSNorm achieves 10–15% faster forward and backward passes than LayerNorm and has become the default normalization in virtually all modern large language models.

## RMSNorm Formula

RMSNorm computes: RMS(x) = √((1/n) Σᵢ xᵢ²) — the root mean square of the input (no mean subtraction). x̂ᵢ = xᵢ / RMS(x) — divide each element by the RMS. yᵢ = γᵢ · x̂ᵢ — apply a learned scale γ (no bias β). The key difference from LayerNorm: no mean computation, no subtraction, no β parameter. This removes the re-centering operation entirely, keeping only re-scaling. The gradient is also simpler: ∂L/∂xᵢ = (1/RMS) · [∂L/∂ŷᵢ · γᵢ − x̂ᵢ · (1/n) Σⱼ ∂L/∂ŷⱼ · γⱼ · x̂ⱼ].

```python
import numpy as np
import torch
import torch.nn as nn

def rmsnorm_numpy(x, gamma, eps=1e-6):
    # RMS over the last dimension (feature dim)
    rms = np.sqrt(np.mean(x ** 2, axis=-1, keepdims=True) + eps)
    return gamma * (x / rms)

class RMSNorm(nn.Module):
    def __init__(self, dim, eps=1e-6):
        super().__init__()
        self.eps = eps
        self.weight = nn.Parameter(torch.ones(dim))
    def forward(self, x):
        rms = x.pow(2).mean(dim=-1, keepdim=True).add(self.eps).sqrt()
        return self.weight * (x / rms)

np.random.seed(42)
B, T, C = 2, 10, 64
x_np = np.random.randn(B, T, C).astype(np.float32)
gamma_np = np.ones(C, dtype=np.float32)
out_np = rmsnorm_numpy(x_np, gamma_np)

x_torch = torch.tensor(x_np)
rms_torch = RMSNorm(C)
out_torch = rms_torch(x_torch).detach().numpy()

print(f'Max diff numpy vs PyTorch: {np.abs(out_np - out_torch).max():.2e}')
print(f'RMS of output (should ~1): {np.sqrt(np.mean(out_np**2, axis=-1)).mean():.4f}')
print(f'Mean of output (not forced to 0): {out_np.mean(axis=-1).mean():.4f}')
```

## Motivation — Why Remove Mean Subtraction?

The re-centering hypothesis states that the learned bias β in LayerNorm can absorb any constant shift, making explicit mean subtraction redundant. Empirically, removing mean computation saves memory bandwidth and arithmetic: for a feature vector of dimension d, LayerNorm requires two passes (one for mean, one for variance); RMSNorm requires one pass (variance around zero). This translates to approximately 10–15% wall-clock speedup on large tensors, which compounds significantly across thousands of transformer blocks in LLM training.

```python
import torch
import torch.nn as nn
import time

device = 'cuda' if torch.cuda.is_available() else 'cpu'

class RMSNorm(nn.Module):
    def __init__(self, dim, eps=1e-6):
        super().__init__()
        self.eps = eps
        self.weight = nn.Parameter(torch.ones(dim))
    def forward(self, x):
        rms = x.pow(2).mean(-1, keepdim=True).add(self.eps).sqrt()
        return self.weight * (x / rms)

B, T, C = 32, 2048, 4096
x = torch.randn(B, T, C, device=device)
ln = nn.LayerNorm(C).to(device)
rms = RMSNorm(C).to(device)

def benchmark(fn, x, n=50):
    for _ in range(5):  # warmup
        fn(x)
    if device == 'cuda':
        torch.cuda.synchronize()
    t0 = time.perf_counter()
    for _ in range(n):
        fn(x)
    if device == 'cuda':
        torch.cuda.synchronize()
    return (time.perf_counter() - t0) / n * 1000

ln_ms = benchmark(ln, x)
rms_ms = benchmark(rms, x)
print(f'LayerNorm : {ln_ms:.3f} ms')
print(f'RMSNorm   : {rms_ms:.3f} ms')
print(f'Speedup   : {ln_ms/rms_ms:.2f}x')
```

## RMSNorm in Modern LLMs

RMSNorm has become the default normalization for nearly all open-weight LLMs: LLaMA 1/2/3, Gemma 1/2, Mistral, Mixtral, Falcon, Qwen, and Phi all use RMSNorm with Pre-Norm placement. The standard placement is before the attention sublayer and before the feed-forward sublayer — two RMSNorm operations per transformer block. The final hidden state before the language model head receives one additional RMSNorm. LLaMA uses ε=1e-5; Gemma uses ε=1e-6. The weight γ is initialized to 1.0.

```python
import torch
import torch.nn as nn
import torch.nn.functional as F

class RMSNorm(nn.Module):
    def __init__(self, dim, eps=1e-5):
        super().__init__()
        self.eps = eps
        self.weight = nn.Parameter(torch.ones(dim))
    def forward(self, x):
        rms = x.pow(2).mean(-1, keepdim=True).add(self.eps).sqrt()
        return self.weight * (x / rms)

class LLaMABlock(nn.Module):
    def __init__(self, d_model, nhead, dim_ff):
        super().__init__()
        self.attn = nn.MultiheadAttention(d_model, nhead, batch_first=True)
        self.ff = nn.Sequential(
            nn.Linear(d_model, dim_ff, bias=False),
            nn.SiLU(),
            nn.Linear(dim_ff, d_model, bias=False)
        )
        self.rms1 = RMSNorm(d_model)  # before attention
        self.rms2 = RMSNorm(d_model)  # before feed-forward
    def forward(self, x):
        n1 = self.rms1(x)
        x = x + self.attn(n1, n1, n1)[0]
        x = x + self.ff(self.rms2(x))
        return x

d_model, nhead, dim_ff = 128, 4, 512
block = LLaMABlock(d_model, nhead, dim_ff)
x = torch.randn(2, 32, d_model)
out = block(x)
print(f'Input  norm: {x.norm(dim=-1).mean():.4f}')
print(f'Output norm: {out.norm(dim=-1).mean():.4f}')
print(f'Params: {sum(p.numel() for p in block.parameters()):,}')
```

> **Pre-Norm Placement in LLaMA**: In LLaMA-style models, RMSNorm is applied before attention (input_layernorm) and before the feed-forward network (post_attention_layernorm). A final RMSNorm is applied to the last hidden state before the unembedding layer. No normalization is applied to the embedding table output itself in LLaMA (unlike BERT).

## When Does Mean Subtraction Matter?

If the input to a normalization layer has a significant non-zero mean shift (e.g., from a biased residual accumulation), LN's mean subtraction corrects it while RMSNorm leaves the shift for γ and β to handle. In practice, pre-norm placement means the residual stream is re-normalized frequently, and the mean shift accumulates very slowly. Empirical results across LLaMA, Gemma, and Mistral training show that RMSNorm matches LN perplexity to within 0.1–0.5% on standard benchmarks.

```python
import torch
import torch.nn as nn

class RMSNorm(nn.Module):
    def __init__(self, dim, eps=1e-6):
        super().__init__()
        self.weight = nn.Parameter(torch.ones(dim))
        self.eps = eps
    def forward(self, x):
        return self.weight * x / x.pow(2).mean(-1, keepdim=True).add(self.eps).sqrt()

torch.manual_seed(0)
dim = 256

# Case 1: zero-mean input — RMSNorm and LN should agree
x_zeromean = torch.randn(16, dim)  # standard normal is zero-mean
ln = nn.LayerNorm(dim)
rms = RMSNorm(dim)
out_ln  = ln(x_zeromean)
out_rms = rms(x_zeromean)
diff_zeromean = (out_ln - out_rms).abs().mean().item()

# Case 2: shifted input — LN corrects shift, RMSNorm does not
x_shifted = x_zeromean + 5.0  # add constant shift
out_ln2  = ln(x_shifted)
out_rms2 = rms(x_shifted)
diff_shifted = (out_ln2 - out_rms2).abs().mean().item()

print(f'Zero-mean input  — LN vs RMSNorm mean abs diff: {diff_zeromean:.4f}')
print(f'Shifted input (+5) — LN vs RMSNorm mean abs diff: {diff_shifted:.4f}')
print('RMSNorm matches LN closely for zero-mean inputs (typical after normalization).')
```

## Gradient and Numerical Properties

The RMSNorm backward pass is simpler than LayerNorm: there is no centering term in the gradient. The gradient ∂L/∂x has the form (γᵢ/RMS) · [∂L/∂ŷᵢ − x̂ᵢ · mean(∂L/∂ŷⱼ · x̂ⱼ)] — a single dot-product correction instead of LayerNorm's two correction terms. The ε value matters: LLaMA uses 1e-5, Gemma uses 1e-6. Too small an ε causes NaN when inputs have near-zero magnitude; too large biases the normalization. In bfloat16 training, ε is sometimes increased to 1e-5 or higher for numerical safety.

## Implementation Details

Fused RMSNorm kernels (available in FlashAttention and Apex) compute the normalization in a single GPU kernel pass, eliminating the memory bandwidth bottleneck of reading x twice. The weight γ is typically stored in fp32 even when the activations are in bf16, to maintain precision in the scale parameters. Hugging Face Transformers implements LlamaRMSNorm with an upcast to fp32 for the normalization computation, downcast back to the activation dtype for output.

- No β parameter: RMSNorm has only γ (scale), not β (shift) — this saves parameters and slightly simplifies the computation graph.
- Fused kernels: use apex.normalization.FusedRMSNorm or flash_attn.ops.rms_norm for maximum throughput.
- Upcast to fp32: the pow/mean/sqrt sequence is numerically safer in fp32 even when activations are bf16.
- ε tuning: increase ε to 1e-5 if you see NaN losses in the first few steps of training with bf16 precision.
- Initialization: γ initialized to 1.0 (ones), which means the layer is an identity map at initialization.

## LN vs RMSNorm vs BN Comparison

| Property | LayerNorm | RMSNorm | BatchNorm |
| --- | --- | --- | --- |
| Formula | x̂=(x−μ)/σ, y=γx̂+β | x̂=x/RMS(x), y=γx̂ | x̂=(x−μ_B)/σ_B, y=γx̂+β |
| Mean subtraction | Yes | No | Yes (over batch) |
| Learnable params | γ and β per feature | γ per feature only | γ and β per feature |
| Compute cost (relative) | 1.0× | ~0.85–0.90× | 1.0× (+ running stats) |
| Batch dependence | None | None | Yes — train/eval gap |
| Used in | BERT, T5, GPT-2 (early) | LLaMA, Gemma, Mistral, Falcon | ResNet, EfficientNet, VGG |

For new Transformer-based models, RMSNorm is the recommended default. It delivers the same empirical performance as LayerNorm with lower compute cost. LayerNorm remains appropriate when loading pretrained checkpoints that used it (BERT, T5, early GPT-2). BatchNorm is inappropriate for autoregressive language models and sequence models with variable lengths.

---

