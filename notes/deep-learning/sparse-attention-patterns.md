---
title: "Sparse Attention — Local, Strided, and Longformer Patterns"
slug: "sparse-attention-patterns"
description: "Implement sliding window, global+local, and BigBird sparse attention patterns from scratch, benchmark sparse vs dense attention memory at L=4096, and understand when sparse attention is the right tool."
tags: ["deep-learning", "transformers", "attention-efficiency"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"Full self-attention computes O(L²) attention weights — for L=16K tokens that is 256 million pairs per head per layer. At 16 heads and 32 layers, a forward pass requires roughly 130 billion attention scores before softmax; storing them in float16 uses 260 GB. Sparse attention addresses this by computing attention only for a structured subset of (query, key) pairs, reducing complexity from O(L²) to O(L·k) where k ≪ L is the sparsity pattern width. The challenge is that irregular sparsity patterns cannot be implemented as a single dense matrix multiply and require custom GPU kernels or masked attention tricks."},{"type":"heading","level":2,"content":"Full Attention: O(L²) Complexity"},{"type":"text","content":"Standard scaled dot-product attention computes scores S = QKᵀ/√d of shape (B, h, L, L). Memory for S is B × h × L² × 2 bytes (float16). For B=1, h=1, L=4096: 33 MB just for scores; for L=16384: 537 MB. Across 16 heads: ~8 GB per layer. FlashAttention avoids materialising the full matrix but still requires O(L²) compute. For tasks with L \u003e 4096 — long documents, genomics, audio, code repositories — the quadratic cost becomes the binding constraint, motivating sparse patterns that preserve essential attention paths while skipping irrelevant pairs."},{"type":"heading","level":2,"content":"Sliding Window Attention (Longformer)"},{"type":"text","content":"The simplest sparse pattern: each token attends only to the w/2 tokens to its left and right (window size w). Complexity drops to O(L × w). Longformer (Beltagy et al. 2020) uses w=512 on sequences up to L=4096. The sliding window captures local context that dominates most NLP tasks — adjacent tokens, nearby sentences. The effective receptive field grows with depth: a token at layer l can indirectly attend to positions up to l × w/2 tokens away. For w=512 and 12 layers, the receptive field covers the full L=4096 document."},{"type":"code","language":"python","content":"import torch\nimport torch.nn.functional as F\nimport math\n\ndef sliding_window_attention(Q, K, V, window):\n    \"\"\"Naive sliding window attention (Longformer-style local attention).\n    Q, K, V: (B, h, L, d). Each token attends to window//2 tokens on each side.\n    Returns: (B, h, L, d). O(L * window) attention pairs computed.\n    \"\"\"\n    B, h, L, d = Q.shape\n    half = window // 2\n    out = torch.zeros_like(Q)\n    for i in range(L):\n        lo = max(0, i - half)\n        hi = min(L, i + half + 1)\n        q_i = Q[:, :, i:i+1, :]          # (B, h, 1, d)\n        k_w = K[:, :, lo:hi, :]          # (B, h, win, d)\n        v_w = V[:, :, lo:hi, :]          # (B, h, win, d)\n        scores = q_i @ k_w.transpose(-2,-1) / math.sqrt(d)\n        out[:, :, i, :] = (F.softmax(scores, dim=-1) @ v_w).squeeze(2)\n    return out\n\ntorch.manual_seed(0)\nB, h, L, d, W = 1, 2, 64, 16, 8\nQ = torch.randn(B, h, L, d)\nK = torch.randn(B, h, L, d)\nV = torch.randn(B, h, L, d)\nout = sliding_window_attention(Q, K, V, W)\nprint(f\u0027Sliding window attention: L={L}, window={W}\u0027)\nprint(f\u0027Output shape: {out.shape}\u0027)\nattended_pairs = sum(min(L, i+W//2+1) - max(0, i-W//2) for i in range(L))\nfull_pairs = L * L\nprint(f\u0027Pairs computed: {attended_pairs} / {full_pairs} ({attended_pairs/full_pairs:.1%} of full)\u0027)\nprint(f\u0027Theoretical complexity: O(L*w)={L*W} vs O(L^2)={L*L}\u0027)"},{"type":"heading","level":2,"content":"Global + Local Attention (Longformer)"},{"type":"text","content":"Pure local window attention cannot capture global context — a [CLS] token or a question token needs to attend to all positions. Longformer solves this with global tokens: a small set of positions (typically [CLS] for classification, or question tokens for QA) attend to all L positions and all positions attend back to global tokens. This adds O(L × g) pairs where g is the number of global tokens (typically g ≪ L). The pattern has three components: local window pairs, global-to-all pairs, and all-to-global pairs — keeping total complexity O(L × (w + g))."},{"type":"code","language":"python","content":"import torch\nimport torch.nn.functional as F\nimport math\n\ndef global_local_attention(Q, K, V, window, global_indices):\n    \"\"\"Global+local attention (Longformer pattern).\n    global_indices: list of token positions with global attention.\n    \"\"\"\n    B, h, L, d = Q.shape\n    scale = math.sqrt(d)\n    half = window // 2\n    # Start with local window attention for all tokens\n    out = torch.zeros_like(Q)\n    for i in range(L):\n        lo, hi = max(0, i - half), min(L, i + half + 1)\n        attend_to = list(range(lo, hi))\n        # All tokens also attend to global tokens\n        for g in global_indices:\n            if g not in attend_to:\n                attend_to.append(g)\n        attend_to = sorted(set(attend_to))\n        kw = K[:, :, attend_to, :]\n        vw = V[:, :, attend_to, :]\n        scores = Q[:, :, i:i+1, :] @ kw.transpose(-2,-1) / scale\n        out[:, :, i, :] = (F.softmax(scores, dim=-1) @ vw).squeeze(2)\n    # Global tokens also attend to ALL positions\n    for g in global_indices:\n        scores = Q[:, :, g:g+1, :] @ K.transpose(-2,-1) / scale\n        out[:, :, g, :] = (F.softmax(scores, dim=-1) @ V).squeeze(2)\n    return out\n\nB, h, L, d, W = 1, 1, 32, 8, 6\nglobals_idx = [0, 1]  # e.g., [CLS] and [SEP] are global\nQ = torch.randn(B, h, L, d)\nK, V = torch.randn(B,h,L,d), torch.randn(B,h,L,d)\nout = global_local_attention(Q, K, V, W, globals_idx)\nprint(f\u0027Global+local attention: L={L}, window={W}, global_tokens={globals_idx}\u0027)\nprint(f\u0027Output: {out.shape}\u0027)\nprint(f\u0027Complexity: O(L*(w+g)) = O({L}*({W}+{len(globals_idx)})) = O({L*(W+len(globals_idx))})\u0027)"},{"type":"heading","level":2,"content":"BigBird: Local, Global, and Random Attention"},{"type":"text","content":"BigBird (Zaheer et al. 2020) combines three attention components to prove that O(L) attention is a universal approximator of full attention: (1) local window of size w (same as Longformer), (2) g global tokens that attend to all positions, (3) r random keys per query — each query additionally attends to r randomly selected positions. The random component ensures that no two tokens are too many hops apart in the attention graph, enabling gradient flow and long-range information mixing. BigBird achieves O(L × (w + g + r)) complexity with strong empirical results on genomics (DNA sequences up to L=4096) and long-document tasks."},{"type":"code","language":"python","content":"import torch\nimport torch.nn.functional as F\nimport math\n\ndef bigbird_attention(Q, K, V, window, global_indices, num_random):\n    \"\"\"BigBird attention: local + global + random attention pattern.\"\"\"\n    B, h, L, d = Q.shape\n    scale = math.sqrt(d)\n    half = window // 2\n    out = torch.zeros_like(Q)\n    torch.manual_seed(42)  # reproducible random pattern\n    # Precompute random attention pattern (same for all positions for simplicity)\n    random_keys = [torch.randperm(L)[:num_random].tolist() for _ in range(L)]\n    for i in range(L):\n        lo, hi = max(0, i-half), min(L, i+half+1)\n        local_idx = list(range(lo, hi))\n        all_idx = sorted(set(local_idx + list(global_indices) + random_keys[i]))\n        kw = K[:, :, all_idx, :]\n        vw = V[:, :, all_idx, :]\n        scores = Q[:, :, i:i+1, :] @ kw.transpose(-2,-1) / scale\n        out[:, :, i, :] = (F.softmax(scores, dim=-1) @ vw).squeeze(2)\n    for g in global_indices:\n        scores = Q[:, :, g:g+1, :] @ K.transpose(-2,-1) / scale\n        out[:, :, g, :] = (F.softmax(scores, dim=-1) @ V).squeeze(2)\n    return out\n\nB, h, L, d = 1, 1, 48, 8\nW, g_idx, r = 8, [0, 1], 4\nQ = torch.randn(B, h, L, d)\nK, V = torch.randn(B,h,L,d), torch.randn(B,h,L,d)\nout = bigbird_attention(Q, K, V, W, g_idx, r)\nprint(f\u0027BigBird: L={L}, window={W}, global={g_idx}, random={r}\u0027)\nprint(f\u0027Output: {out.shape}\u0027)\neff_k = W + len(g_idx) + r\nprint(f\u0027Effective keys per query: ~{eff_k}, complexity: O({L}*{eff_k})={L*eff_k} vs O(L^2)={L*L}\u0027)"},{"type":"heading","level":2,"content":"Benchmarking Sparse vs Dense Attention"},{"type":"text","content":"The quadratic memory of full attention becomes the bottleneck above L=2048 on a 16 GB GPU. Sparse attention allows L=16K or even L=128K within the same memory budget. However, naive Python implementations of sparse patterns are slower than dense attention for small L because they lack the highly optimised CUDA kernels that power F.scaled_dot_product_attention. Production sparse attention requires custom kernels (Longformer uses a dilated convolution trick; BigBird uses block-sparse CUDA operations). The benchmarks below measure the naive implementations to verify correctness and complexity scaling."},{"type":"code","language":"python","content":"import torch\nimport torch.nn.functional as F\nimport math\nimport time\n\ndef dense_attention(Q, K, V):\n    d = Q.shape[-1]\n    return F.softmax(Q @ K.transpose(-2,-1) / math.sqrt(d), dim=-1) @ V\n\ndef measure_attn(fn, *args, n=10):\n    t0 = time.perf_counter()\n    for _ in range(n):\n        _ = fn(*args)\n    return (time.perf_counter() - t0) / n * 1000\n\nB, h, d = 1, 1, 32\nW, r = 16, 4\nprint(f\"{\u0027Method\u0027:\u003e20} {\u0027L=256\u0027:\u003e10} {\u0027L=512\u0027:\u003e10} {\u0027L=1024\u0027:\u003e10} {\u0027Complexity\u0027:\u003e14}\")\nfor L in [256, 512, 1024]:\n    Q = torch.randn(B, h, L, d)\n    K, V = torch.randn(B,h,L,d), torch.randn(B,h,L,d)\n    t_dense = measure_attn(dense_attention, Q, K, V)\n    row = f\u0027{\u0027Dense\u0027:\u003e20} {t_dense:\u003e9.1f}\u0027\n    print(f\"Dense L={L}: {t_dense:.2f}ms | mem~{L*L*2/1024:.0f}KB\")\nprint(\u0027\\nKey takeaway: sparse patterns reduce memory O(L^2)-\u003eO(L*w);\u0027)\nprint(\u0027custom CUDA kernels needed for actual speed gains over dense at small L.\u0027)\nprint(f\u0027Dense at L=4096: mem~{4096*4096*2//1024//1024}MB | Sparse(w={W}): ~{4096*W*2//1024}KB\u0027)"},{"type":"table","headers":["Method","Complexity","Memory at L=4K","Quality vs Full","Implementation","Best Use Case"],"rows":[["Full (dense)","O(L²)","~32 MB/head","Baseline","Single matmul — trivial","L \u003c 2K, any task"],["Sliding window","O(L·w)","~2 MB (w=256)","Good for local tasks","Loop or block-sparse kernel","Long NLP, audio (L 2K–32K)"],["Global+local","O(L·(w+g))","~2 MB (w=256, g=2)","Strong — global tokens preserve semantics","Longformer kernel","Long-doc QA, classification"],["BigBird","O(L·(w+g+r))","~3 MB (w=64,g=2,r=8)","Near full attention quality","Block-sparse CUDA","Genomics, very long docs"],["Linear attention","O(L·d²)","O(L) — no L² term","Quality gap for long sequences","Kernel trick — pure matmuls","L \u003e 64K, approximate tasks"]]},{"type":"heading","level":2,"content":"Practical Considerations"},{"type":"text","content":"Choosing a sparse pattern requires understanding where attention is informative in your data. For text classification a few global tokens ([CLS]) are sufficient; for long-form generation a sliding window preserves fluency. Sparse attention patterns implemented naively in PyTorch are slower than dense attention for L \u003c 4096 because loop overhead dominates. For production use, specialised kernels are required: Longformer\u0027s Hugging Face implementation uses a carefully optimised chunk-based approach; BigBird and Sparse Transformer rely on block-sparse CUDA operations from libraries like triton or apex."},{"type":"callout","variant":"warning","title":"Sparse Attention Needs Custom Kernels","content":"Never implement sparse attention with Python loops or masked dense attention (setting masked entries to -inf) in production — both are O(L²) in memory. Masked dense attention computes the full L×L matrix and zeroes entries after the fact; it gives the correct output but defeats the purpose. Real O(L·w) sparse attention requires custom CUDA kernels or block-sparse libraries. For quick prototyping, use the Longformer implementation in HuggingFace transformers."},{"type":"heading","level":2,"content":"When to Use Sparse Attention"},{"type":"text","content":"Use sparse attention when sequence length exceeds ~2K tokens and the task structure justifies the pattern. Sliding window is appropriate when local context is sufficient (most token-level NLP tasks). Global+local (Longformer) suits document-level tasks where a few anchor tokens need full context. BigBird is best when you need near-full-attention quality at O(L) cost and can afford block-sparse kernel complexity. For sequences above L=64K where even O(L·w) is expensive, linear attention or state-space models (Mamba, S4) may be more appropriate."},{"type":"list","ordered":false,"items":["Sliding window (w=512): Longformer uses this for token classification on L=4096 documents.","Global+local: add [CLS] as a global token for classification, question tokens for QA.","BigBird: used for genomic sequence modelling (DNA, RNA) with L up to 4096.","Sparse Transformer (OpenAI 2019): alternating local and strided patterns for autoregressive generation.","Longformer-Encoder-Decoder (LED): applies sparse attention to encoder, full attention to cross-attention.","All sparse patterns require causal masking for autoregressive generation — future positions must be excluded."]},{"type":"divider"}]"
---
# Sparse Attention — Local, Strided, and Longformer Patterns

Full self-attention computes O(L²) attention weights — for L=16K tokens that is 256 million pairs per head per layer. At 16 heads and 32 layers, a forward pass requires roughly 130 billion attention scores before softmax; storing them in float16 uses 260 GB. Sparse attention addresses this by computing attention only for a structured subset of (query, key) pairs, reducing complexity from O(L²) to O(L·k) where k ≪ L is the sparsity pattern width. The challenge is that irregular sparsity patterns cannot be implemented as a single dense matrix multiply and require custom GPU kernels or masked attention tricks.

## Full Attention: O(L²) Complexity

Standard scaled dot-product attention computes scores S = QKᵀ/√d of shape (B, h, L, L). Memory for S is B × h × L² × 2 bytes (float16). For B=1, h=1, L=4096: 33 MB just for scores; for L=16384: 537 MB. Across 16 heads: ~8 GB per layer. FlashAttention avoids materialising the full matrix but still requires O(L²) compute. For tasks with L > 4096 — long documents, genomics, audio, code repositories — the quadratic cost becomes the binding constraint, motivating sparse patterns that preserve essential attention paths while skipping irrelevant pairs.

## Sliding Window Attention (Longformer)

The simplest sparse pattern: each token attends only to the w/2 tokens to its left and right (window size w). Complexity drops to O(L × w). Longformer (Beltagy et al. 2020) uses w=512 on sequences up to L=4096. The sliding window captures local context that dominates most NLP tasks — adjacent tokens, nearby sentences. The effective receptive field grows with depth: a token at layer l can indirectly attend to positions up to l × w/2 tokens away. For w=512 and 12 layers, the receptive field covers the full L=4096 document.

```python
import torch
import torch.nn.functional as F
import math

def sliding_window_attention(Q, K, V, window):
    """Naive sliding window attention (Longformer-style local attention).
    Q, K, V: (B, h, L, d). Each token attends to window//2 tokens on each side.
    Returns: (B, h, L, d). O(L * window) attention pairs computed.
    """
    B, h, L, d = Q.shape
    half = window // 2
    out = torch.zeros_like(Q)
    for i in range(L):
        lo = max(0, i - half)
        hi = min(L, i + half + 1)
        q_i = Q[:, :, i:i+1, :]          # (B, h, 1, d)
        k_w = K[:, :, lo:hi, :]          # (B, h, win, d)
        v_w = V[:, :, lo:hi, :]          # (B, h, win, d)
        scores = q_i @ k_w.transpose(-2,-1) / math.sqrt(d)
        out[:, :, i, :] = (F.softmax(scores, dim=-1) @ v_w).squeeze(2)
    return out

torch.manual_seed(0)
B, h, L, d, W = 1, 2, 64, 16, 8
Q = torch.randn(B, h, L, d)
K = torch.randn(B, h, L, d)
V = torch.randn(B, h, L, d)
out = sliding_window_attention(Q, K, V, W)
print(f'Sliding window attention: L={L}, window={W}')
print(f'Output shape: {out.shape}')
attended_pairs = sum(min(L, i+W//2+1) - max(0, i-W//2) for i in range(L))
full_pairs = L * L
print(f'Pairs computed: {attended_pairs} / {full_pairs} ({attended_pairs/full_pairs:.1%} of full)')
print(f'Theoretical complexity: O(L*w)={L*W} vs O(L^2)={L*L}')
```

## Global + Local Attention (Longformer)

Pure local window attention cannot capture global context — a [CLS] token or a question token needs to attend to all positions. Longformer solves this with global tokens: a small set of positions (typically [CLS] for classification, or question tokens for QA) attend to all L positions and all positions attend back to global tokens. This adds O(L × g) pairs where g is the number of global tokens (typically g ≪ L). The pattern has three components: local window pairs, global-to-all pairs, and all-to-global pairs — keeping total complexity O(L × (w + g)).

```python
import torch
import torch.nn.functional as F
import math

def global_local_attention(Q, K, V, window, global_indices):
    """Global+local attention (Longformer pattern).
    global_indices: list of token positions with global attention.
    """
    B, h, L, d = Q.shape
    scale = math.sqrt(d)
    half = window // 2
    # Start with local window attention for all tokens
    out = torch.zeros_like(Q)
    for i in range(L):
        lo, hi = max(0, i - half), min(L, i + half + 1)
        attend_to = list(range(lo, hi))
        # All tokens also attend to global tokens
        for g in global_indices:
            if g not in attend_to:
                attend_to.append(g)
        attend_to = sorted(set(attend_to))
        kw = K[:, :, attend_to, :]
        vw = V[:, :, attend_to, :]
        scores = Q[:, :, i:i+1, :] @ kw.transpose(-2,-1) / scale
        out[:, :, i, :] = (F.softmax(scores, dim=-1) @ vw).squeeze(2)
    # Global tokens also attend to ALL positions
    for g in global_indices:
        scores = Q[:, :, g:g+1, :] @ K.transpose(-2,-1) / scale
        out[:, :, g, :] = (F.softmax(scores, dim=-1) @ V).squeeze(2)
    return out

B, h, L, d, W = 1, 1, 32, 8, 6
globals_idx = [0, 1]  # e.g., [CLS] and [SEP] are global
Q = torch.randn(B, h, L, d)
K, V = torch.randn(B,h,L,d), torch.randn(B,h,L,d)
out = global_local_attention(Q, K, V, W, globals_idx)
print(f'Global+local attention: L={L}, window={W}, global_tokens={globals_idx}')
print(f'Output: {out.shape}')
print(f'Complexity: O(L*(w+g)) = O({L}*({W}+{len(globals_idx)})) = O({L*(W+len(globals_idx))})')
```

## BigBird: Local, Global, and Random Attention

BigBird (Zaheer et al. 2020) combines three attention components to prove that O(L) attention is a universal approximator of full attention: (1) local window of size w (same as Longformer), (2) g global tokens that attend to all positions, (3) r random keys per query — each query additionally attends to r randomly selected positions. The random component ensures that no two tokens are too many hops apart in the attention graph, enabling gradient flow and long-range information mixing. BigBird achieves O(L × (w + g + r)) complexity with strong empirical results on genomics (DNA sequences up to L=4096) and long-document tasks.

```python
import torch
import torch.nn.functional as F
import math

def bigbird_attention(Q, K, V, window, global_indices, num_random):
    """BigBird attention: local + global + random attention pattern."""
    B, h, L, d = Q.shape
    scale = math.sqrt(d)
    half = window // 2
    out = torch.zeros_like(Q)
    torch.manual_seed(42)  # reproducible random pattern
    # Precompute random attention pattern (same for all positions for simplicity)
    random_keys = [torch.randperm(L)[:num_random].tolist() for _ in range(L)]
    for i in range(L):
        lo, hi = max(0, i-half), min(L, i+half+1)
        local_idx = list(range(lo, hi))
        all_idx = sorted(set(local_idx + list(global_indices) + random_keys[i]))
        kw = K[:, :, all_idx, :]
        vw = V[:, :, all_idx, :]
        scores = Q[:, :, i:i+1, :] @ kw.transpose(-2,-1) / scale
        out[:, :, i, :] = (F.softmax(scores, dim=-1) @ vw).squeeze(2)
    for g in global_indices:
        scores = Q[:, :, g:g+1, :] @ K.transpose(-2,-1) / scale
        out[:, :, g, :] = (F.softmax(scores, dim=-1) @ V).squeeze(2)
    return out

B, h, L, d = 1, 1, 48, 8
W, g_idx, r = 8, [0, 1], 4
Q = torch.randn(B, h, L, d)
K, V = torch.randn(B,h,L,d), torch.randn(B,h,L,d)
out = bigbird_attention(Q, K, V, W, g_idx, r)
print(f'BigBird: L={L}, window={W}, global={g_idx}, random={r}')
print(f'Output: {out.shape}')
eff_k = W + len(g_idx) + r
print(f'Effective keys per query: ~{eff_k}, complexity: O({L}*{eff_k})={L*eff_k} vs O(L^2)={L*L}')
```

## Benchmarking Sparse vs Dense Attention

The quadratic memory of full attention becomes the bottleneck above L=2048 on a 16 GB GPU. Sparse attention allows L=16K or even L=128K within the same memory budget. However, naive Python implementations of sparse patterns are slower than dense attention for small L because they lack the highly optimised CUDA kernels that power F.scaled_dot_product_attention. Production sparse attention requires custom kernels (Longformer uses a dilated convolution trick; BigBird uses block-sparse CUDA operations). The benchmarks below measure the naive implementations to verify correctness and complexity scaling.

```python
import torch
import torch.nn.functional as F
import math
import time

def dense_attention(Q, K, V):
    d = Q.shape[-1]
    return F.softmax(Q @ K.transpose(-2,-1) / math.sqrt(d), dim=-1) @ V

def measure_attn(fn, *args, n=10):
    t0 = time.perf_counter()
    for _ in range(n):
        _ = fn(*args)
    return (time.perf_counter() - t0) / n * 1000

B, h, d = 1, 1, 32
W, r = 16, 4
print(f"{'Method':>20} {'L=256':>10} {'L=512':>10} {'L=1024':>10} {'Complexity':>14}")
for L in [256, 512, 1024]:
    Q = torch.randn(B, h, L, d)
    K, V = torch.randn(B,h,L,d), torch.randn(B,h,L,d)
    t_dense = measure_attn(dense_attention, Q, K, V)
    row = f'{'Dense':>20} {t_dense:>9.1f}'
    print(f"Dense L={L}: {t_dense:.2f}ms | mem~{L*L*2/1024:.0f}KB")
print('\nKey takeaway: sparse patterns reduce memory O(L^2)->O(L*w);')
print('custom CUDA kernels needed for actual speed gains over dense at small L.')
print(f'Dense at L=4096: mem~{4096*4096*2//1024//1024}MB | Sparse(w={W}): ~{4096*W*2//1024}KB')
```

| Method | Complexity | Memory at L=4K | Quality vs Full | Implementation | Best Use Case |
| --- | --- | --- | --- | --- | --- |
| Full (dense) | O(L²) | ~32 MB/head | Baseline | Single matmul — trivial | L < 2K, any task |
| Sliding window | O(L·w) | ~2 MB (w=256) | Good for local tasks | Loop or block-sparse kernel | Long NLP, audio (L 2K–32K) |
| Global+local | O(L·(w+g)) | ~2 MB (w=256, g=2) | Strong — global tokens preserve semantics | Longformer kernel | Long-doc QA, classification |
| BigBird | O(L·(w+g+r)) | ~3 MB (w=64,g=2,r=8) | Near full attention quality | Block-sparse CUDA | Genomics, very long docs |
| Linear attention | O(L·d²) | O(L) — no L² term | Quality gap for long sequences | Kernel trick — pure matmuls | L > 64K, approximate tasks |

## Practical Considerations

Choosing a sparse pattern requires understanding where attention is informative in your data. For text classification a few global tokens ([CLS]) are sufficient; for long-form generation a sliding window preserves fluency. Sparse attention patterns implemented naively in PyTorch are slower than dense attention for L < 4096 because loop overhead dominates. For production use, specialised kernels are required: Longformer's Hugging Face implementation uses a carefully optimised chunk-based approach; BigBird and Sparse Transformer rely on block-sparse CUDA operations from libraries like triton or apex.

> **Sparse Attention Needs Custom Kernels**: Never implement sparse attention with Python loops or masked dense attention (setting masked entries to -inf) in production — both are O(L²) in memory. Masked dense attention computes the full L×L matrix and zeroes entries after the fact; it gives the correct output but defeats the purpose. Real O(L·w) sparse attention requires custom CUDA kernels or block-sparse libraries. For quick prototyping, use the Longformer implementation in HuggingFace transformers.

## When to Use Sparse Attention

Use sparse attention when sequence length exceeds ~2K tokens and the task structure justifies the pattern. Sliding window is appropriate when local context is sufficient (most token-level NLP tasks). Global+local (Longformer) suits document-level tasks where a few anchor tokens need full context. BigBird is best when you need near-full-attention quality at O(L) cost and can afford block-sparse kernel complexity. For sequences above L=64K where even O(L·w) is expensive, linear attention or state-space models (Mamba, S4) may be more appropriate.

- Sliding window (w=512): Longformer uses this for token classification on L=4096 documents.
- Global+local: add [CLS] as a global token for classification, question tokens for QA.
- BigBird: used for genomic sequence modelling (DNA, RNA) with L up to 4096.
- Sparse Transformer (OpenAI 2019): alternating local and strided patterns for autoregressive generation.
- Longformer-Encoder-Decoder (LED): applies sparse attention to encoder, full attention to cross-attention.
- All sparse patterns require causal masking for autoregressive generation — future positions must be excluded.

---

