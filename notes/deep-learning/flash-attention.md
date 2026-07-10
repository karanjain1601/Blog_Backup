---
title: "Flash Attention 1/2/3 — IO-Aware Attention Algorithm"
slug: "flash-attention"
description: "How FlashAttention eliminates O(N²) memory by tiling attention in SRAM, online softmax normalization, backward pass recomputation, and benchmarks vs standard attention."
tags: ["deep-learning", "transformers", "attention-efficiency"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"Standard attention requires materializing the full N×N attention matrix in GPU HBM (high-bandwidth memory), consuming O(N²) memory. For a sequence of length 8192 with 32 heads in float16, this is 8192² × 32 × 2 bytes ≈ 32 GB — exceeding typical GPU memory budgets. FlashAttention (Dao et al. 2022) reformulates attention as an IO-aware algorithm: compute attention in tiles that fit entirely in SRAM (on-chip cache), avoiding the roundtrip to HBM. The result is identical to standard attention mathematically, but uses O(N) memory and runs 2–4× faster on A100 GPUs."},{"type":"heading","level":2,"content":"Standard Attention: O(N²) Memory Problem"},{"type":"text","content":"Standard scaled dot-product attention computes: S = QK^T/√d (N×N), P = softmax(S) (N×N), O = PV (N×d). The bottleneck is storing S and P in HBM. Each HBM read/write costs ~10–20 ns; SRAM access costs ~1 ns. A single attention computation for N=8192, d=64 requires writing 8192² float16 values = 128 MB to HBM. Across many layers and batch sizes this dominates training time — the GPU\u0027s tensor cores are idle waiting for memory transfers. The key insight of FlashAttention: the memory bottleneck, not FLOP count, limits attention speed."},{"type":"code","language":"python","content":"import torch\nimport torch.nn.functional as F\nimport math\n\ndef standard_attention(Q, K, V, causal=False):\n    \"\"\"Naive attention that materializes the full N x N matrix in memory.\"\"\"\n    scale = math.sqrt(Q.shape[-1])\n    S = torch.matmul(Q, K.transpose(-2, -1)) / scale  # (B, H, N, N) -- O(N^2) memory\n    if causal:\n        N = Q.shape[-2]\n        mask = torch.tril(torch.ones(N, N, device=Q.device)).bool()\n        S = S.masked_fill(~mask, float(\u0027-inf\u0027))\n    P = F.softmax(S, dim=-1)  # still O(N^2) in memory\n    return torch.matmul(P, V)  # (B, H, N, d_head)\n\ndef flash_attention_reference(Q, K, V, block_size=64):\n    \"\"\"\n    Simplified block-wise attention for clarity (not the real CUDA kernel).\n    Computes the same result as standard attention using tiled softmax.\n    \"\"\"\n    B, H, N, d = Q.shape\n    O = torch.zeros_like(Q)\n    L = torch.zeros(B, H, N, device=Q.device)   # log-sum-exp running state\n    m = torch.full((B, H, N), float(\u0027-inf\u0027), device=Q.device)  # running max\n    scale = d ** -0.5\n    for j in range(0, N, block_size):\n        Kj = K[:, :, j:j+block_size, :]\n        Vj = V[:, :, j:j+block_size, :]\n        S_block = (Q @ Kj.transpose(-2, -1)) * scale  # (B, H, N, block_size)\n        m_new = torch.maximum(m, S_block.max(dim=-1).values)\n        exp_block = torch.exp(S_block - m_new.unsqueeze(-1))\n        L = torch.exp(m - m_new) * L + exp_block.sum(dim=-1)\n        O = torch.exp(m - m_new).unsqueeze(-1) * O + exp_block @ Vj\n        m = m_new\n    return O / L.unsqueeze(-1)  # normalize\n\nB, H, N, d = 1, 1, 64, 32\nQ = torch.randn(B, H, N, d)\nK = torch.randn(B, H, N, d)\nV = torch.randn(B, H, N, d)\nout_std = standard_attention(Q, K, V)\nout_flash = flash_attention_reference(Q, K, V, block_size=16)\nprint(f\u0027Max diff: {(out_std - out_flash).abs().max().item():.2e}\u0027)  # near 0"},{"type":"heading","level":2,"content":"Online Softmax: Incremental Normalization"},{"type":"text","content":"Standard softmax over a row requires two passes: one to find the maximum (for numerical stability) and one to compute exp and sum. When processing attention in tiles, the full row is never available at once. Online softmax maintains a running maximum m and a running sum L: for each new tile of scores, update m_new = max(m, max(new_tile)), then rescale the running sum and accumulator: L_new = exp(m − m_new) × L + Σexp(s − m_new), O_new = exp(m − m_new) × O + exp(s − m_new) × V. This produces identical output to two-pass softmax while never materializing the full N×N matrix."},{"type":"code","language":"python","content":"import torch\n\ndef online_softmax_demo(scores_list):\n    \"\"\"\n    Demonstrate online softmax for a 1D sequence of score chunks.\n    Equivalent to softmax(torch.cat(scores_list)) but computed incrementally.\n    \"\"\"\n    m = float(\u0027-inf\u0027)  # running max\n    d = 0.0            # running denominator (sum of exp)\n    numerators = []    # store (chunk, correction_factor) pairs\n\n    for chunk in scores_list:\n        m_chunk = chunk.max().item()\n        if m_chunk \u003e m:\n            # Rescale previous denominator and numerators\n            correction = torch.exp(torch.tensor(m - m_chunk))\n            d = d * correction.item()\n            numerators = [(n * correction, c) for n, c in numerators]\n            m = m_chunk\n        exp_chunk = torch.exp(chunk - m)\n        d += exp_chunk.sum().item()\n        numerators.append((exp_chunk, 1.0))\n\n    # Normalize all chunks\n    result = torch.cat([n / d for n, _ in numerators])\n    return result\n\n# Verify against standard softmax\ntorch.manual_seed(0)\nfull_scores = torch.randn(32)\nchunks = full_scores.split(8)\nonline_result = online_softmax_demo(list(chunks))\nstandard_result = torch.softmax(full_scores, dim=0)\nprint(f\u0027Max error: {(online_result - standard_result).abs().max().item():.2e}\u0027)\nprint(f\u0027Sum: {online_result.sum().item():.6f} (should be 1.0)\u0027)"},{"type":"heading","level":2,"content":"Using Flash Attention in PyTorch"},{"type":"text","content":"PyTorch 2.0+ exposes FlashAttention through torch.nn.functional.scaled_dot_product_attention. When inputs are on CUDA in float16 or bfloat16 and no custom mask is required, PyTorch automatically dispatches to the FlashAttention kernel. For causal (autoregressive) attention, pass is_causal=True. The API is a drop-in replacement for the naive implementation. Transformers library uses this internally when use_flash_attention_2=True."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.nn.functional as F\nimport math\n\nclass FlashMHA(nn.Module):\n    \"\"\"Multi-Head Attention using PyTorch\u0027s built-in FlashAttention.\"\"\"\n    def __init__(self, d_model=512, n_heads=8, dropout=0.0):\n        super().__init__()\n        self.n_heads = n_heads\n        self.d_head = d_model // n_heads\n        self.qkv = nn.Linear(d_model, 3 * d_model, bias=False)\n        self.proj = nn.Linear(d_model, d_model, bias=False)\n        self.dropout = dropout\n\n    def forward(self, x, is_causal=False):\n        B, T, C = x.shape\n        q, k, v = self.qkv(x).split(C, dim=-1)\n        def reshape(t):\n            return t.view(B, T, self.n_heads, self.d_head).transpose(1, 2)\n        q, k, v = reshape(q), reshape(k), reshape(v)\n        # Dispatch to FlashAttention when on CUDA with float16/bfloat16\n        out = F.scaled_dot_product_attention(\n            q, k, v,\n            attn_mask=None,\n            dropout_p=self.dropout if self.training else 0.0,\n            is_causal=is_causal\n        )\n        return self.proj(out.transpose(1, 2).contiguous().view(B, T, C))\n\nmha = FlashMHA(d_model=512, n_heads=8)\nx = torch.randn(4, 128, 512)\nout = mha(x, is_causal=True)\nprint(f\u0027Output: {out.shape}\u0027)  # (4, 128, 512)\nprint(f\u0027Uses flash attention when on CUDA with float16\u0027)"},{"type":"heading","level":2,"content":"Benchmarking Standard vs Flash Attention"},{"type":"code","language":"python","content":"import torch\nimport torch.nn.functional as F\nimport time\nimport math\n\ndef time_attention(fn, Q, K, V, n_warmup=5, n_runs=20):\n    for _ in range(n_warmup):\n        fn(Q, K, V)\n    if Q.is_cuda: torch.cuda.synchronize()\n    t0 = time.perf_counter()\n    for _ in range(n_runs):\n        fn(Q, K, V)\n    if Q.is_cuda: torch.cuda.synchronize()\n    return (time.perf_counter() - t0) / n_runs * 1000  # ms\n\ndef naive_attn(Q, K, V):\n    scale = math.sqrt(Q.shape[-1])\n    return F.softmax(Q @ K.transpose(-2, -1) / scale, dim=-1) @ V\n\ndef flash_attn(Q, K, V):\n    return F.scaled_dot_product_attention(Q, K, V, is_causal=True)\n\ndevice = \u0027cuda\u0027 if torch.cuda.is_available() else \u0027cpu\u0027\nprint(f\u0027Device: {device}\u0027)\nseq_lens = [512, 1024, 2048, 4096]\nprint(f\u0027{\u0027SeqLen\u0027:\u003e8} {\u0027Naive (ms)\u0027:\u003e12} {\u0027Flash (ms)\u0027:\u003e12} {\u0027Naive MB\u0027:\u003e10} {\u0027Speedup\u0027:\u003e8}\u0027)\nfor N in seq_lens:\n    B, H, d = 1, 16, 64\n    Q = torch.randn(B, H, N, d, device=device, dtype=torch.float16)\n    K = torch.randn(B, H, N, d, device=device, dtype=torch.float16)\n    V = torch.randn(B, H, N, d, device=device, dtype=torch.float16)\n    naive_mb = B * H * N * N * 2 / 1e6  # float16 bytes\n    try:\n        t_naive = time_attention(naive_attn, Q, K, V)\n        t_flash = time_attention(flash_attn, Q, K, V)\n        speedup = t_naive / t_flash\n        print(f\u0027{N:\u003e8} {t_naive:\u003e12.2f} {t_flash:\u003e12.2f} {naive_mb:\u003e10.1f} {speedup:\u003e8.2f}x\u0027)\n    except RuntimeError as e:\n        print(f\u0027{N:\u003e8} OOM for naive; flash still works\u0027)"},{"type":"heading","level":2,"content":"FlashAttention Versions and Hardware"},{"type":"text","content":"FlashAttention-1 (Dao et al. 2022) achieved 2–4× speedup on A100 by reducing HBM reads/writes. The backward pass recomputes attention weights from Q,K,V instead of storing the O(N²) attention matrix — trading compute for memory. FlashAttention-2 (Dao 2023) reduced non-matmul FLOPs and improved thread block partitioning, reaching ~72% of A100 peak utilization (up from ~25% for v1). FlashAttention-3 (Shah et al. 2024) targets H100: uses asynchronous Tensor Core pipelines and the H100 TMA instruction to overlap data movement with computation, reaching ~75% of H100\u0027s 989 TFLOPS."},{"type":"callout","variant":"tip","title":"When FlashAttention Cannot Be Used","content":"PyTorch\u0027s SDPA dispatches to FlashAttention only when: (1) input is on CUDA, (2) dtype is float16 or bfloat16, (3) no custom attention mask is provided (only is_causal=True is supported natively). For arbitrary sparse masks, custom position biases (ALiBi, T5 relative bias), or cross-attention with different Q and K/V lengths, standard attention may be required unless you use the xformers or flash-attn package directly."},{"type":"heading","level":2,"content":"Summary: Standard vs FlashAttention Versions"},{"type":"table","headers":["Attribute","Standard","FlashAttention-1","FlashAttention-2","FlashAttention-3"],"rows":[["Memory complexity","O(N²)","O(N)","O(N)","O(N)"],["HBM reads/writes","O(N²)","O(N × d)","O(N × d)","O(N × d)"],["Peak TFLOPS (A100)","~10–15","~60–70","~72","N/A (H100 target)"],["Peak TFLOPS (H100)","~25","~130","~200","~740 (75% utilization)"],["Causal masking","Full mask in HBM","Skip lower-tri blocks","Fewer non-matmul ops","Same + async pipeline"],["Max seq length","~4K (memory bound)","~64K (compute bound)","~128K","~256K+"],["Backend","cuBLAS + custom","Custom CUDA kernel","Custom CUDA kernel","H100 async WGMMA"]]},{"type":"list","ordered":false,"items":["Backward pass: FlashAttention recomputes attention from Q,K,V rather than storing the N×N attention matrix — O(N) memory for backward.","Causal masking: FlashAttention skips lower-triangular blocks entirely (they contribute zero after −inf masking), halving computation for causal models.","PyTorch integration: torch.nn.functional.scaled_dot_product_attention auto-selects FlashAttention kernel when conditions are met.","xformers and flash-attn packages expose lower-level APIs for custom masks and variable-length sequences.","All modern LLMs (LLaMA, Mistral, GPT-4, Gemini) use FlashAttention as a training and inference requirement."]},{"type":"heading","level":2,"content":"Backward Pass: Activation Recomputation"},{"type":"text","content":"Standard attention stores the N×N attention weight matrix P during the forward pass so the backward pass can compute gradients dL/dQ = dO · P^T and dL/dK = Q^T · dP without recomputing attention. FlashAttention-1 avoids storing P by recomputing it during the backward pass from the saved Q, K, V tensors. This trades an extra forward-pass compute (~33% overhead) for an N²→O(N) reduction in memory. The backward pass visits each tile of Q,K,V twice (once forward, once recomputed for gradients), so the total backward pass cost is ~2× the forward pass, same as standard backprop."},{"type":"text","content":"FlashAttention is now a prerequisite for training any serious long-context model. Without it, a 4096-token sequence with 32 heads in float16 requires 4096² × 32 × 2 bytes = 1 GB just for attention matrices per layer — infeasible for multi-layer models. With FlashAttention the memory is O(N × d) ≈ 4096 × 128 × 2 bytes = 1 MB per layer. This 1000× reduction in attention memory is what made training LLaMA-2 (4096 context), Mistral (8192), and Llama-3 (131072) feasible on standard GPU clusters."},{"type":"divider"}]"
---
# Flash Attention 1/2/3 — IO-Aware Attention Algorithm

Standard attention requires materializing the full N×N attention matrix in GPU HBM (high-bandwidth memory), consuming O(N²) memory. For a sequence of length 8192 with 32 heads in float16, this is 8192² × 32 × 2 bytes ≈ 32 GB — exceeding typical GPU memory budgets. FlashAttention (Dao et al. 2022) reformulates attention as an IO-aware algorithm: compute attention in tiles that fit entirely in SRAM (on-chip cache), avoiding the roundtrip to HBM. The result is identical to standard attention mathematically, but uses O(N) memory and runs 2–4× faster on A100 GPUs.

## Standard Attention: O(N²) Memory Problem

Standard scaled dot-product attention computes: S = QK^T/√d (N×N), P = softmax(S) (N×N), O = PV (N×d). The bottleneck is storing S and P in HBM. Each HBM read/write costs ~10–20 ns; SRAM access costs ~1 ns. A single attention computation for N=8192, d=64 requires writing 8192² float16 values = 128 MB to HBM. Across many layers and batch sizes this dominates training time — the GPU's tensor cores are idle waiting for memory transfers. The key insight of FlashAttention: the memory bottleneck, not FLOP count, limits attention speed.

```python
import torch
import torch.nn.functional as F
import math

def standard_attention(Q, K, V, causal=False):
    """Naive attention that materializes the full N x N matrix in memory."""
    scale = math.sqrt(Q.shape[-1])
    S = torch.matmul(Q, K.transpose(-2, -1)) / scale  # (B, H, N, N) -- O(N^2) memory
    if causal:
        N = Q.shape[-2]
        mask = torch.tril(torch.ones(N, N, device=Q.device)).bool()
        S = S.masked_fill(~mask, float('-inf'))
    P = F.softmax(S, dim=-1)  # still O(N^2) in memory
    return torch.matmul(P, V)  # (B, H, N, d_head)

def flash_attention_reference(Q, K, V, block_size=64):
    """
    Simplified block-wise attention for clarity (not the real CUDA kernel).
    Computes the same result as standard attention using tiled softmax.
    """
    B, H, N, d = Q.shape
    O = torch.zeros_like(Q)
    L = torch.zeros(B, H, N, device=Q.device)   # log-sum-exp running state
    m = torch.full((B, H, N), float('-inf'), device=Q.device)  # running max
    scale = d ** -0.5
    for j in range(0, N, block_size):
        Kj = K[:, :, j:j+block_size, :]
        Vj = V[:, :, j:j+block_size, :]
        S_block = (Q @ Kj.transpose(-2, -1)) * scale  # (B, H, N, block_size)
        m_new = torch.maximum(m, S_block.max(dim=-1).values)
        exp_block = torch.exp(S_block - m_new.unsqueeze(-1))
        L = torch.exp(m - m_new) * L + exp_block.sum(dim=-1)
        O = torch.exp(m - m_new).unsqueeze(-1) * O + exp_block @ Vj
        m = m_new
    return O / L.unsqueeze(-1)  # normalize

B, H, N, d = 1, 1, 64, 32
Q = torch.randn(B, H, N, d)
K = torch.randn(B, H, N, d)
V = torch.randn(B, H, N, d)
out_std = standard_attention(Q, K, V)
out_flash = flash_attention_reference(Q, K, V, block_size=16)
print(f'Max diff: {(out_std - out_flash).abs().max().item():.2e}')  # near 0
```

## Online Softmax: Incremental Normalization

Standard softmax over a row requires two passes: one to find the maximum (for numerical stability) and one to compute exp and sum. When processing attention in tiles, the full row is never available at once. Online softmax maintains a running maximum m and a running sum L: for each new tile of scores, update m_new = max(m, max(new_tile)), then rescale the running sum and accumulator: L_new = exp(m − m_new) × L + Σexp(s − m_new), O_new = exp(m − m_new) × O + exp(s − m_new) × V. This produces identical output to two-pass softmax while never materializing the full N×N matrix.

```python
import torch

def online_softmax_demo(scores_list):
    """
    Demonstrate online softmax for a 1D sequence of score chunks.
    Equivalent to softmax(torch.cat(scores_list)) but computed incrementally.
    """
    m = float('-inf')  # running max
    d = 0.0            # running denominator (sum of exp)
    numerators = []    # store (chunk, correction_factor) pairs

    for chunk in scores_list:
        m_chunk = chunk.max().item()
        if m_chunk > m:
            # Rescale previous denominator and numerators
            correction = torch.exp(torch.tensor(m - m_chunk))
            d = d * correction.item()
            numerators = [(n * correction, c) for n, c in numerators]
            m = m_chunk
        exp_chunk = torch.exp(chunk - m)
        d += exp_chunk.sum().item()
        numerators.append((exp_chunk, 1.0))

    # Normalize all chunks
    result = torch.cat([n / d for n, _ in numerators])
    return result

# Verify against standard softmax
torch.manual_seed(0)
full_scores = torch.randn(32)
chunks = full_scores.split(8)
online_result = online_softmax_demo(list(chunks))
standard_result = torch.softmax(full_scores, dim=0)
print(f'Max error: {(online_result - standard_result).abs().max().item():.2e}')
print(f'Sum: {online_result.sum().item():.6f} (should be 1.0)')
```

## Using Flash Attention in PyTorch

PyTorch 2.0+ exposes FlashAttention through torch.nn.functional.scaled_dot_product_attention. When inputs are on CUDA in float16 or bfloat16 and no custom mask is required, PyTorch automatically dispatches to the FlashAttention kernel. For causal (autoregressive) attention, pass is_causal=True. The API is a drop-in replacement for the naive implementation. Transformers library uses this internally when use_flash_attention_2=True.

```python
import torch
import torch.nn as nn
import torch.nn.functional as F
import math

class FlashMHA(nn.Module):
    """Multi-Head Attention using PyTorch's built-in FlashAttention."""
    def __init__(self, d_model=512, n_heads=8, dropout=0.0):
        super().__init__()
        self.n_heads = n_heads
        self.d_head = d_model // n_heads
        self.qkv = nn.Linear(d_model, 3 * d_model, bias=False)
        self.proj = nn.Linear(d_model, d_model, bias=False)
        self.dropout = dropout

    def forward(self, x, is_causal=False):
        B, T, C = x.shape
        q, k, v = self.qkv(x).split(C, dim=-1)
        def reshape(t):
            return t.view(B, T, self.n_heads, self.d_head).transpose(1, 2)
        q, k, v = reshape(q), reshape(k), reshape(v)
        # Dispatch to FlashAttention when on CUDA with float16/bfloat16
        out = F.scaled_dot_product_attention(
            q, k, v,
            attn_mask=None,
            dropout_p=self.dropout if self.training else 0.0,
            is_causal=is_causal
        )
        return self.proj(out.transpose(1, 2).contiguous().view(B, T, C))

mha = FlashMHA(d_model=512, n_heads=8)
x = torch.randn(4, 128, 512)
out = mha(x, is_causal=True)
print(f'Output: {out.shape}')  # (4, 128, 512)
print(f'Uses flash attention when on CUDA with float16')
```

## Benchmarking Standard vs Flash Attention

```python
import torch
import torch.nn.functional as F
import time
import math

def time_attention(fn, Q, K, V, n_warmup=5, n_runs=20):
    for _ in range(n_warmup):
        fn(Q, K, V)
    if Q.is_cuda: torch.cuda.synchronize()
    t0 = time.perf_counter()
    for _ in range(n_runs):
        fn(Q, K, V)
    if Q.is_cuda: torch.cuda.synchronize()
    return (time.perf_counter() - t0) / n_runs * 1000  # ms

def naive_attn(Q, K, V):
    scale = math.sqrt(Q.shape[-1])
    return F.softmax(Q @ K.transpose(-2, -1) / scale, dim=-1) @ V

def flash_attn(Q, K, V):
    return F.scaled_dot_product_attention(Q, K, V, is_causal=True)

device = 'cuda' if torch.cuda.is_available() else 'cpu'
print(f'Device: {device}')
seq_lens = [512, 1024, 2048, 4096]
print(f'{'SeqLen':>8} {'Naive (ms)':>12} {'Flash (ms)':>12} {'Naive MB':>10} {'Speedup':>8}')
for N in seq_lens:
    B, H, d = 1, 16, 64
    Q = torch.randn(B, H, N, d, device=device, dtype=torch.float16)
    K = torch.randn(B, H, N, d, device=device, dtype=torch.float16)
    V = torch.randn(B, H, N, d, device=device, dtype=torch.float16)
    naive_mb = B * H * N * N * 2 / 1e6  # float16 bytes
    try:
        t_naive = time_attention(naive_attn, Q, K, V)
        t_flash = time_attention(flash_attn, Q, K, V)
        speedup = t_naive / t_flash
        print(f'{N:>8} {t_naive:>12.2f} {t_flash:>12.2f} {naive_mb:>10.1f} {speedup:>8.2f}x')
    except RuntimeError as e:
        print(f'{N:>8} OOM for naive; flash still works')
```

## FlashAttention Versions and Hardware

FlashAttention-1 (Dao et al. 2022) achieved 2–4× speedup on A100 by reducing HBM reads/writes. The backward pass recomputes attention weights from Q,K,V instead of storing the O(N²) attention matrix — trading compute for memory. FlashAttention-2 (Dao 2023) reduced non-matmul FLOPs and improved thread block partitioning, reaching ~72% of A100 peak utilization (up from ~25% for v1). FlashAttention-3 (Shah et al. 2024) targets H100: uses asynchronous Tensor Core pipelines and the H100 TMA instruction to overlap data movement with computation, reaching ~75% of H100's 989 TFLOPS.

> **When FlashAttention Cannot Be Used**: PyTorch's SDPA dispatches to FlashAttention only when: (1) input is on CUDA, (2) dtype is float16 or bfloat16, (3) no custom attention mask is provided (only is_causal=True is supported natively). For arbitrary sparse masks, custom position biases (ALiBi, T5 relative bias), or cross-attention with different Q and K/V lengths, standard attention may be required unless you use the xformers or flash-attn package directly.

## Summary: Standard vs FlashAttention Versions

| Attribute | Standard | FlashAttention-1 | FlashAttention-2 | FlashAttention-3 |
| --- | --- | --- | --- | --- |
| Memory complexity | O(N²) | O(N) | O(N) | O(N) |
| HBM reads/writes | O(N²) | O(N × d) | O(N × d) | O(N × d) |
| Peak TFLOPS (A100) | ~10–15 | ~60–70 | ~72 | N/A (H100 target) |
| Peak TFLOPS (H100) | ~25 | ~130 | ~200 | ~740 (75% utilization) |
| Causal masking | Full mask in HBM | Skip lower-tri blocks | Fewer non-matmul ops | Same + async pipeline |
| Max seq length | ~4K (memory bound) | ~64K (compute bound) | ~128K | ~256K+ |
| Backend | cuBLAS + custom | Custom CUDA kernel | Custom CUDA kernel | H100 async WGMMA |

- Backward pass: FlashAttention recomputes attention from Q,K,V rather than storing the N×N attention matrix — O(N) memory for backward.
- Causal masking: FlashAttention skips lower-triangular blocks entirely (they contribute zero after −inf masking), halving computation for causal models.
- PyTorch integration: torch.nn.functional.scaled_dot_product_attention auto-selects FlashAttention kernel when conditions are met.
- xformers and flash-attn packages expose lower-level APIs for custom masks and variable-length sequences.
- All modern LLMs (LLaMA, Mistral, GPT-4, Gemini) use FlashAttention as a training and inference requirement.

## Backward Pass: Activation Recomputation

Standard attention stores the N×N attention weight matrix P during the forward pass so the backward pass can compute gradients dL/dQ = dO · P^T and dL/dK = Q^T · dP without recomputing attention. FlashAttention-1 avoids storing P by recomputing it during the backward pass from the saved Q, K, V tensors. This trades an extra forward-pass compute (~33% overhead) for an N²→O(N) reduction in memory. The backward pass visits each tile of Q,K,V twice (once forward, once recomputed for gradients), so the total backward pass cost is ~2× the forward pass, same as standard backprop.

FlashAttention is now a prerequisite for training any serious long-context model. Without it, a 4096-token sequence with 32 heads in float16 requires 4096² × 32 × 2 bytes = 1 GB just for attention matrices per layer — infeasible for multi-layer models. With FlashAttention the memory is O(N × d) ≈ 4096 × 128 × 2 bytes = 1 MB per layer. This 1000× reduction in attention memory is what made training LLaMA-2 (4096 context), Mistral (8192), and Llama-3 (131072) feasible on standard GPU clusters.

---

