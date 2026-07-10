---
title: "Ring Attention — Sequence Parallelism for Long Contexts"
slug: "ring-attention"
description: "Simulate ring attention with Python lists, implement online softmax normalisation for distributed attention, combine ring attention with FlashAttention blocks, and analyse per-GPU memory scaling with sequence length and device count."
tags: ["deep-learning", "transformers", "attention-efficiency"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"Ring Attention (Liu et al. 2023) enables training on sequences far longer than a single GPU can hold by distributing the sequence across multiple GPUs. Each GPU holds a contiguous segment of Q, K, and V. The GPUs are arranged in a logical ring: at each step a GPU computes local attention between its Q segment and its current K,V segment, then passes its K,V to the next GPU in the ring. After N steps (N = number of GPUs), every Q has attended to every K and V. Crucially, the K,V communication overlaps with local FlashAttention computation, hiding most of the network latency."},{"type":"heading","level":2,"content":"Sequence Parallelism and the Ring Communication Pattern"},{"type":"text","content":"Tensor parallelism (Megatron-LM) splits model weights across GPUs. Data parallelism splits the batch. Sequence parallelism splits the sequence dimension L across GPUs. For N GPUs each holding L/N tokens, the local attention matrix is (L/N) × (L/N) instead of L × L — an N² reduction in per-GPU memory. Ring Attention implements sequence parallelism for attention: at step s, GPU i computes attention between its Q_i and the K,V block it currently holds (initially from GPU i, then cycled from GPU (i+s) mod N). After N steps, the partial attention outputs are combined using online softmax normalisation."},{"type":"heading","level":2,"content":"Ring Attention Forward Pass"},{"type":"text","content":"The ring attention algorithm: initialise output O_i = 0, running log-sum-exp lse_i = -∞ for each GPU i. For s = 0 to N-1: compute local attention scores A_{i,j} = Q_i K_jᵀ / √d where j = (i+s) mod N; update the running softmax using online normalisation (FlashAttention-style); send K_j, V_j to GPU (i+1) mod N while computing; receive K_{j-1}, V_{j-1} from GPU (i-1) mod N. After N steps each GPU holds O_i = softmax(Q_i [K_0; K_1; ...; K_{N-1}]ᵀ) V — the correct full-sequence attention output for its Q segment."},{"type":"code","language":"python","content":"import torch\nimport torch.nn.functional as F\nimport math\n\ndef ring_attention_simulate(Q_segs, K_segs, V_segs):\n    \"\"\"Simulate ring attention with Python lists (no actual multi-GPU comms).\n    Q_segs, K_segs, V_segs: lists of tensors, one per GPU, shape (B,h,Ls,d).\n    Returns: list of output segments, one per GPU.\n    \"\"\"\n    N = len(Q_segs)  # number of GPUs\n    B, h, Ls, d = Q_segs[0].shape\n    # Each GPU maintains running output O and log-sum-exp for online softmax\n    Os   = [torch.zeros(B, h, Ls, d) for _ in range(N)]\n    lses = [torch.full((B, h, Ls, 1), float(\u0027-inf\u0027)) for _ in range(N)]\n    kv_ring = list(zip(K_segs, V_segs))  # initial K,V assignment\n    for step in range(N):\n        for i in range(N):\n            j = (i + step) % N          # which K,V block GPU i holds\n            K_j, V_j = kv_ring[j]\n            scores = Q_segs[i] @ K_j.transpose(-2,-1) / math.sqrt(d)  # (B,h,Ls,Ls)\n            block_max = scores.max(dim=-1, keepdim=True).values\n            exp_scores = torch.exp(scores - block_max)\n            block_lse  = block_max + torch.log(exp_scores.sum(-1, keepdim=True))\n            # Merge with running lse (online softmax)\n            lse_new = torch.logaddexp(lses[i], block_lse)\n            alpha = torch.exp(lses[i] - lse_new)\n            beta  = torch.exp(block_lse - lse_new)\n            Os[i]   = alpha * Os[i] + beta * (exp_scores / exp_scores.sum(-1,keepdim=True) @ V_j)\n            lses[i] = lse_new\n        # Simulate ring rotation: each GPU sends K,V to next\n        kv_ring = [kv_ring[(i - 1) % N] for i in range(N)]\n    return Os\n\nN, B, h, Ls, d = 4, 1, 2, 8, 16  # 4 GPUs, 8 tokens each = 32 total\nQ_segs = [torch.randn(B,h,Ls,d) for _ in range(N)]\nK_segs = [torch.randn(B,h,Ls,d) for _ in range(N)]\nV_segs = [torch.randn(B,h,Ls,d) for _ in range(N)]\nOs = ring_attention_simulate(Q_segs, K_segs, V_segs)\nQ_full = torch.cat(Q_segs, dim=2)\nK_full = torch.cat(K_segs, dim=2)\nV_full = torch.cat(V_segs, dim=2)\nO_ref  = F.scaled_dot_product_attention(Q_full, K_full, V_full)\nO_ring = torch.cat(Os, dim=2)\nprint(f\u0027Ring output shape: {O_ring.shape}\u0027)\nprint(f\u0027Max diff vs full attention: {(O_ring - O_ref).abs().max().item():.6f}\u0027)"},{"type":"heading","level":2,"content":"Online Normalisation for Distributed Softmax"},{"type":"text","content":"The key algorithmic challenge in ring attention is combining partial softmax results computed on different K,V blocks. Standard softmax requires seeing all keys to compute the denominator Σ_j exp(q·kⱼ/√d). Online normalisation (from FlashAttention) maintains a running log-sum-exp (lse) that allows updating the output incrementally. For each new K block: compute block_lse, merge with running lse using logaddexp, rescale the previous output by exp(old_lse - new_lse), add the contribution from the new block scaled by exp(block_lse - new_lse). After all N ring steps, the output is numerically equivalent to full softmax attention."},{"type":"code","language":"python","content":"import torch\nimport math\n\ndef online_softmax_accumulate(q, k_blocks, v_blocks):\n    \"\"\"Accumulate attention over K,V blocks using online (log-sum-exp) normalisation.\n    q: (L_q, d)  k_blocks/v_blocks: list of (L_k, d) tensors.\n    Returns output (L_q, d) equivalent to full softmax attention.\n    \"\"\"\n    d = q.shape[-1]\n    L_q = q.shape[0]\n    O   = torch.zeros(L_q, d)\n    lse = torch.full((L_q, 1), float(\u0027-inf\u0027))\n    for K_b, V_b in zip(k_blocks, v_blocks):\n        scores    = q @ K_b.T / math.sqrt(d)              # (L_q, L_k)\n        block_max = scores.max(dim=-1, keepdim=True).values\n        e_scores  = torch.exp(scores - block_max)          # numerically stable\n        block_lse = block_max + torch.log(e_scores.sum(-1, keepdim=True))\n        lse_new   = torch.logaddexp(lse, block_lse)\n        alpha     = torch.exp(lse - lse_new)               # rescale old contribution\n        beta      = torch.exp(block_lse - lse_new)         # scale new contribution\n        O         = alpha * O + beta * (e_scores / e_scores.sum(-1,keepdim=True) @ V_b)\n        lse       = lse_new\n    return O\n\ntorch.manual_seed(1)\nL, d = 32, 16\nq = torch.randn(L, d)\nK = torch.randn(L, d)\nV = torch.randn(L, d)\n# Split K, V into 4 blocks as if distributed across 4 GPUs\nk_blocks = K.chunk(4, dim=0)\nv_blocks = V.chunk(4, dim=0)\nO_online = online_softmax_accumulate(q, k_blocks, v_blocks)\nimport torch.nn.functional as F\nO_full = F.scaled_dot_product_attention(q.unsqueeze(0).unsqueeze(0),\n             K.unsqueeze(0).unsqueeze(0), V.unsqueeze(0).unsqueeze(0)).squeeze()\nprint(f\u0027Online norm max diff: {(O_online - O_full).abs().max().item():.8f}\u0027)\nprint(\u0027Numerically identical to full softmax attention across 4 blocks.\u0027)"},{"type":"heading","level":2,"content":"Combining Ring Attention with FlashAttention"},{"type":"text","content":"In practice, ring attention does not compute naive local attention — it uses FlashAttention within each ring step for memory efficiency. FlashAttention tiles the local (L/N) × (L/N) attention matrix to avoid materialising it, keeping per-GPU memory O(L/N) rather than O((L/N)²). The combination: ring attention handles the sequence distribution across GPUs (inter-GPU level), FlashAttention handles the memory-efficient tiling within each GPU (intra-GPU level). Together they achieve O(L/N) memory per GPU in both sequence length and attention scores, enabling contexts of L = N × L_GPU where L_GPU is the per-GPU FlashAttention limit (~128K on an 80 GB A100)."},{"type":"code","language":"python","content":"import torch\nimport torch.nn.functional as F\nimport math\n\ndef flash_attention_block(Q, K, V, block_size=32):\n    \"\"\"Simplified FlashAttention: tiled computation to avoid O(L^2) memory.\n    Q: (B,h,Lq,d)  K,V: (B,h,Lk,d). Returns (B,h,Lq,d).\n    \"\"\"\n    B, h, Lq, d = Q.shape\n    Lk = K.shape[2]\n    O   = torch.zeros_like(Q)\n    lse = torch.full((B, h, Lq, 1), float(\u0027-inf\u0027))\n    for j in range(0, Lk, block_size):\n        Kj = K[:, :, j:j+block_size]\n        Vj = V[:, :, j:j+block_size]\n        s  = Q @ Kj.transpose(-2,-1) / math.sqrt(d)\n        bm = s.max(-1, keepdim=True).values\n        e  = torch.exp(s - bm)\n        bl = bm + torch.log(e.sum(-1, keepdim=True))\n        lse_new = torch.logaddexp(lse, bl)\n        O = torch.exp(lse - lse_new) * O + torch.exp(bl - lse_new) * (e / e.sum(-1,keepdim=True) @ Vj)\n        lse = lse_new\n    return O\n\ndef ring_flash_attention(Q_segs, K_segs, V_segs, block_size=16):\n    \"\"\"Ring attention with FlashAttention as the local compute kernel.\"\"\"\n    N = len(Q_segs)\n    Os   = [torch.zeros_like(q) for q in Q_segs]\n    lses = [torch.full((*q.shape[:3], 1), float(\u0027-inf\u0027)) for q in Q_segs]\n    kv   = list(zip(K_segs, V_segs))\n    for step in range(N):\n        for i in range(N):\n            j = (i + step) % N\n            Kj, Vj = kv[j]\n            block_out = flash_attention_block(Q_segs[i], Kj, Vj, block_size)\n            # Merge using online normalisation at segment level\n            bl = torch.log(torch.ones(*Q_segs[i].shape[:3], 1))  # simplified\n            lse_new = torch.logaddexp(lses[i], bl)\n            Os[i] = 0.5 * Os[i] + 0.5 * block_out  # simplified merge for demo\n            lses[i] = lse_new\n        kv = [kv[(i - 1) % N] for i in range(N)]\n    return Os\n\nN, B, h, Ls, d = 2, 1, 1, 16, 8\nQ_segs = [torch.randn(B,h,Ls,d) for _ in range(N)]\nK_segs = [torch.randn(B,h,Ls,d) for _ in range(N)]\nV_segs = [torch.randn(B,h,Ls,d) for _ in range(N)]\nOs = ring_flash_attention(Q_segs, K_segs, V_segs)\nprint(f\u0027Ring+Flash: {N} GPUs, {Ls} tokens/GPU = {N*Ls} total tokens\u0027)\nprint(f\u0027Output seg 0: {Os[0].shape}\u0027)\nprint(f\u0027Per-GPU attn memory: O((Ls/block)^2) = O({Ls}^2) vs O({N*Ls}^2) full\u0027)"},{"type":"heading","level":2,"content":"Scaling Analysis: Memory per GPU"},{"type":"text","content":"Ring attention\u0027s memory advantage is linear in N. With N GPUs, each holding L/N tokens, the local attention matrix is (L/N)² — N² smaller than the full L² matrix. Combined with FlashAttention (which avoids materialising even the local matrix), per-GPU memory for attention is O(L/N) in sequence length. Parameter memory remains the same across GPUs (model weights are replicated or tensor-partitioned separately). Communication cost per ring step is sending K and V of shape (B × h × L/N × d_head) to the neighbouring GPU — proportional to L/N, not L²."},{"type":"code","language":"python","content":"import math\n\ndef ring_attention_memory(L, N, h, d_head, dtype_bytes=2):\n    \"\"\"Estimate per-GPU memory for ring attention (attention tensors only).\"\"\"\n    Ls = L // N  # tokens per GPU\n    # Q, K, V segments: each (h, Ls, d_head)\n    qkv_mem = 3 * h * Ls * d_head * dtype_bytes\n    # Local attention score block (with FlashAttention, never fully materialised)\n    # FlashAttention tiles with block_size b: max block = h * Ls * b\n    b = min(128, Ls)\n    flash_tile = h * Ls * b * dtype_bytes\n    # Output buffer O: same shape as Q\n    out_mem = h * Ls * d_head * dtype_bytes\n    # Communication: one K,V send per step\n    comm_per_step = 2 * h * Ls * d_head * dtype_bytes\n    return qkv_mem + flash_tile + out_mem, comm_per_step\n\nh, d_head = 16, 64\nprint(f\"{\u0027L\u0027:\u003e8} {\u0027N GPUs\u0027:\u003e8} {\u0027Mem/GPU MB\u0027:\u003e12} {\u0027Comm/step MB\u0027:\u003e14} {\u0027Full-attn MB\u0027:\u003e14}\")\nfor L in [8192, 32768, 131072, 524288]:\n    for N in [1, 4, 8, 16]:\n        if L // N \u003c 64:\n            continue\n        mem, comm = ring_attention_memory(L, N, h, d_head)\n        full_attn = h * L * L * 2 / 1024**2  # full L^2 attention, float16\n        print(f\u0027{L:\u003e8} {N:\u003e8} {mem/1024**2:\u003e12.1f} {comm/1024**2:\u003e14.2f} {full_attn:\u003e14.1f}\u0027)"},{"type":"table","headers":["Strategy","Dimension parallelized","Communication pattern","Max sequence length","Use case"],"rows":[["Data parallelism","Batch (B)","AllReduce gradients","Single-GPU limit","Standard training with large batch"],["Tensor parallelism","Model weights (h or d_model)","AllReduce per layer forward","Single-GPU limit","Large models that don\u0027t fit on one GPU"],["Sequence parallelism (non-ring)","Sequence (L) — non-attention layers","AllGather / ReduceScatter","Modest improvement","Used in Megatron-LM for LayerNorm, Dropout"],["Ring attention","Sequence (L) — attention layer","P2P K,V ring rotation (N steps)","L × N (linear in GPU count)","Very long contexts: 128K–1M tokens"],["Combined (all four)","B, h, d_model, L simultaneously","All of the above","Product of all axes","Gemini/LLaMA 3 long-context training"]]},{"type":"heading","level":2,"content":"Communication Overhead and Overlap"},{"type":"text","content":"Ring attention requires N ring steps where N is the number of GPUs. At each step GPU i sends its current K,V block (L/N × h × d_head floats) to GPU (i+1) while simultaneously computing local attention with its current K,V block. If the NVLink or InfiniBand bandwidth is sufficient to send L/N × h × d_head floats in the time it takes to run FlashAttention on L/N × L/N tokens, communication is fully hidden. In practice, for NVLink at 600 GB/s and A100 at ~300 TFLOPS, communication is hidden for L/N ≥ 4096 with typical model dimensions. Blocking Ring Attention reduces communication rounds to ⌈N/2⌉ by bidirectional ring rotation."},{"type":"callout","variant":"info","title":"Ring Attention Enables Million-Token Contexts","content":"Ring attention scales sequence length linearly with GPU count: 8 × A100 GPUs each handling 128K tokens = 1M total context. This is how long-context LLaMA variants (LLaMA 3.1 with 128K context) and Gemini (1M context) are trained. The communication overhead is bounded by L/N (not L²), and overlaps with compute. For inference, ring attention is less common — KV cache compression (GQA, MLA) is preferred because inference is typically single-GPU or uses pipeline parallelism."},{"type":"heading","level":2,"content":"Long-Context Training in Practice"},{"type":"text","content":"Ring attention is primarily a training technique — it enables fitting long sequences into GPU memory during the forward and backward pass. At inference, the full sequence typically fits in a single GPU\u0027s memory if KV cache compression (GQA or MLA) is used, making ring attention unnecessary. Production long-context training pipelines combine ring attention (sequence parallelism) with tensor parallelism (split heads across GPUs) and data parallelism (split batch) — all three dimensions partitioned simultaneously. The code changes required to add ring attention to an existing transformer are isolated to the attention layer; the rest of the transformer operates on L/N token segments without modification."},{"type":"list","ordered":false,"items":["Ring attention paper (Liu et al. 2023): first paper to demonstrate O(L/N) per-GPU memory for attention across N GPUs.","LLaMA 3.1 (128K context): trained with ring attention across 8 GPUs per sequence for long-context variants.","Gemini (1M context): uses a combination of ring-style sequence parallelism and tensor parallelism.","BlockingRingAttention: reduces communication steps from N to ⌈N/2⌉ using bidirectional ring rotation.","EasyContext (open source): PyTorch implementation of ring attention with DeepSpeed and FSDP integration.","Ring attention is orthogonal to FlashAttention — each ring step uses FlashAttention internally for memory-efficient local compute."]},{"type":"divider"}]"
---
# Ring Attention — Sequence Parallelism for Long Contexts

Ring Attention (Liu et al. 2023) enables training on sequences far longer than a single GPU can hold by distributing the sequence across multiple GPUs. Each GPU holds a contiguous segment of Q, K, and V. The GPUs are arranged in a logical ring: at each step a GPU computes local attention between its Q segment and its current K,V segment, then passes its K,V to the next GPU in the ring. After N steps (N = number of GPUs), every Q has attended to every K and V. Crucially, the K,V communication overlaps with local FlashAttention computation, hiding most of the network latency.

## Sequence Parallelism and the Ring Communication Pattern

Tensor parallelism (Megatron-LM) splits model weights across GPUs. Data parallelism splits the batch. Sequence parallelism splits the sequence dimension L across GPUs. For N GPUs each holding L/N tokens, the local attention matrix is (L/N) × (L/N) instead of L × L — an N² reduction in per-GPU memory. Ring Attention implements sequence parallelism for attention: at step s, GPU i computes attention between its Q_i and the K,V block it currently holds (initially from GPU i, then cycled from GPU (i+s) mod N). After N steps, the partial attention outputs are combined using online softmax normalisation.

## Ring Attention Forward Pass

The ring attention algorithm: initialise output O_i = 0, running log-sum-exp lse_i = -∞ for each GPU i. For s = 0 to N-1: compute local attention scores A_{i,j} = Q_i K_jᵀ / √d where j = (i+s) mod N; update the running softmax using online normalisation (FlashAttention-style); send K_j, V_j to GPU (i+1) mod N while computing; receive K_{j-1}, V_{j-1} from GPU (i-1) mod N. After N steps each GPU holds O_i = softmax(Q_i [K_0; K_1; ...; K_{N-1}]ᵀ) V — the correct full-sequence attention output for its Q segment.

```python
import torch
import torch.nn.functional as F
import math

def ring_attention_simulate(Q_segs, K_segs, V_segs):
    """Simulate ring attention with Python lists (no actual multi-GPU comms).
    Q_segs, K_segs, V_segs: lists of tensors, one per GPU, shape (B,h,Ls,d).
    Returns: list of output segments, one per GPU.
    """
    N = len(Q_segs)  # number of GPUs
    B, h, Ls, d = Q_segs[0].shape
    # Each GPU maintains running output O and log-sum-exp for online softmax
    Os   = [torch.zeros(B, h, Ls, d) for _ in range(N)]
    lses = [torch.full((B, h, Ls, 1), float('-inf')) for _ in range(N)]
    kv_ring = list(zip(K_segs, V_segs))  # initial K,V assignment
    for step in range(N):
        for i in range(N):
            j = (i + step) % N          # which K,V block GPU i holds
            K_j, V_j = kv_ring[j]
            scores = Q_segs[i] @ K_j.transpose(-2,-1) / math.sqrt(d)  # (B,h,Ls,Ls)
            block_max = scores.max(dim=-1, keepdim=True).values
            exp_scores = torch.exp(scores - block_max)
            block_lse  = block_max + torch.log(exp_scores.sum(-1, keepdim=True))
            # Merge with running lse (online softmax)
            lse_new = torch.logaddexp(lses[i], block_lse)
            alpha = torch.exp(lses[i] - lse_new)
            beta  = torch.exp(block_lse - lse_new)
            Os[i]   = alpha * Os[i] + beta * (exp_scores / exp_scores.sum(-1,keepdim=True) @ V_j)
            lses[i] = lse_new
        # Simulate ring rotation: each GPU sends K,V to next
        kv_ring = [kv_ring[(i - 1) % N] for i in range(N)]
    return Os

N, B, h, Ls, d = 4, 1, 2, 8, 16  # 4 GPUs, 8 tokens each = 32 total
Q_segs = [torch.randn(B,h,Ls,d) for _ in range(N)]
K_segs = [torch.randn(B,h,Ls,d) for _ in range(N)]
V_segs = [torch.randn(B,h,Ls,d) for _ in range(N)]
Os = ring_attention_simulate(Q_segs, K_segs, V_segs)
Q_full = torch.cat(Q_segs, dim=2)
K_full = torch.cat(K_segs, dim=2)
V_full = torch.cat(V_segs, dim=2)
O_ref  = F.scaled_dot_product_attention(Q_full, K_full, V_full)
O_ring = torch.cat(Os, dim=2)
print(f'Ring output shape: {O_ring.shape}')
print(f'Max diff vs full attention: {(O_ring - O_ref).abs().max().item():.6f}')
```

## Online Normalisation for Distributed Softmax

The key algorithmic challenge in ring attention is combining partial softmax results computed on different K,V blocks. Standard softmax requires seeing all keys to compute the denominator Σ_j exp(q·kⱼ/√d). Online normalisation (from FlashAttention) maintains a running log-sum-exp (lse) that allows updating the output incrementally. For each new K block: compute block_lse, merge with running lse using logaddexp, rescale the previous output by exp(old_lse - new_lse), add the contribution from the new block scaled by exp(block_lse - new_lse). After all N ring steps, the output is numerically equivalent to full softmax attention.

```python
import torch
import math

def online_softmax_accumulate(q, k_blocks, v_blocks):
    """Accumulate attention over K,V blocks using online (log-sum-exp) normalisation.
    q: (L_q, d)  k_blocks/v_blocks: list of (L_k, d) tensors.
    Returns output (L_q, d) equivalent to full softmax attention.
    """
    d = q.shape[-1]
    L_q = q.shape[0]
    O   = torch.zeros(L_q, d)
    lse = torch.full((L_q, 1), float('-inf'))
    for K_b, V_b in zip(k_blocks, v_blocks):
        scores    = q @ K_b.T / math.sqrt(d)              # (L_q, L_k)
        block_max = scores.max(dim=-1, keepdim=True).values
        e_scores  = torch.exp(scores - block_max)          # numerically stable
        block_lse = block_max + torch.log(e_scores.sum(-1, keepdim=True))
        lse_new   = torch.logaddexp(lse, block_lse)
        alpha     = torch.exp(lse - lse_new)               # rescale old contribution
        beta      = torch.exp(block_lse - lse_new)         # scale new contribution
        O         = alpha * O + beta * (e_scores / e_scores.sum(-1,keepdim=True) @ V_b)
        lse       = lse_new
    return O

torch.manual_seed(1)
L, d = 32, 16
q = torch.randn(L, d)
K = torch.randn(L, d)
V = torch.randn(L, d)
# Split K, V into 4 blocks as if distributed across 4 GPUs
k_blocks = K.chunk(4, dim=0)
v_blocks = V.chunk(4, dim=0)
O_online = online_softmax_accumulate(q, k_blocks, v_blocks)
import torch.nn.functional as F
O_full = F.scaled_dot_product_attention(q.unsqueeze(0).unsqueeze(0),
             K.unsqueeze(0).unsqueeze(0), V.unsqueeze(0).unsqueeze(0)).squeeze()
print(f'Online norm max diff: {(O_online - O_full).abs().max().item():.8f}')
print('Numerically identical to full softmax attention across 4 blocks.')
```

## Combining Ring Attention with FlashAttention

In practice, ring attention does not compute naive local attention — it uses FlashAttention within each ring step for memory efficiency. FlashAttention tiles the local (L/N) × (L/N) attention matrix to avoid materialising it, keeping per-GPU memory O(L/N) rather than O((L/N)²). The combination: ring attention handles the sequence distribution across GPUs (inter-GPU level), FlashAttention handles the memory-efficient tiling within each GPU (intra-GPU level). Together they achieve O(L/N) memory per GPU in both sequence length and attention scores, enabling contexts of L = N × L_GPU where L_GPU is the per-GPU FlashAttention limit (~128K on an 80 GB A100).

```python
import torch
import torch.nn.functional as F
import math

def flash_attention_block(Q, K, V, block_size=32):
    """Simplified FlashAttention: tiled computation to avoid O(L^2) memory.
    Q: (B,h,Lq,d)  K,V: (B,h,Lk,d). Returns (B,h,Lq,d).
    """
    B, h, Lq, d = Q.shape
    Lk = K.shape[2]
    O   = torch.zeros_like(Q)
    lse = torch.full((B, h, Lq, 1), float('-inf'))
    for j in range(0, Lk, block_size):
        Kj = K[:, :, j:j+block_size]
        Vj = V[:, :, j:j+block_size]
        s  = Q @ Kj.transpose(-2,-1) / math.sqrt(d)
        bm = s.max(-1, keepdim=True).values
        e  = torch.exp(s - bm)
        bl = bm + torch.log(e.sum(-1, keepdim=True))
        lse_new = torch.logaddexp(lse, bl)
        O = torch.exp(lse - lse_new) * O + torch.exp(bl - lse_new) * (e / e.sum(-1,keepdim=True) @ Vj)
        lse = lse_new
    return O

def ring_flash_attention(Q_segs, K_segs, V_segs, block_size=16):
    """Ring attention with FlashAttention as the local compute kernel."""
    N = len(Q_segs)
    Os   = [torch.zeros_like(q) for q in Q_segs]
    lses = [torch.full((*q.shape[:3], 1), float('-inf')) for q in Q_segs]
    kv   = list(zip(K_segs, V_segs))
    for step in range(N):
        for i in range(N):
            j = (i + step) % N
            Kj, Vj = kv[j]
            block_out = flash_attention_block(Q_segs[i], Kj, Vj, block_size)
            # Merge using online normalisation at segment level
            bl = torch.log(torch.ones(*Q_segs[i].shape[:3], 1))  # simplified
            lse_new = torch.logaddexp(lses[i], bl)
            Os[i] = 0.5 * Os[i] + 0.5 * block_out  # simplified merge for demo
            lses[i] = lse_new
        kv = [kv[(i - 1) % N] for i in range(N)]
    return Os

N, B, h, Ls, d = 2, 1, 1, 16, 8
Q_segs = [torch.randn(B,h,Ls,d) for _ in range(N)]
K_segs = [torch.randn(B,h,Ls,d) for _ in range(N)]
V_segs = [torch.randn(B,h,Ls,d) for _ in range(N)]
Os = ring_flash_attention(Q_segs, K_segs, V_segs)
print(f'Ring+Flash: {N} GPUs, {Ls} tokens/GPU = {N*Ls} total tokens')
print(f'Output seg 0: {Os[0].shape}')
print(f'Per-GPU attn memory: O((Ls/block)^2) = O({Ls}^2) vs O({N*Ls}^2) full')
```

## Scaling Analysis: Memory per GPU

Ring attention's memory advantage is linear in N. With N GPUs, each holding L/N tokens, the local attention matrix is (L/N)² — N² smaller than the full L² matrix. Combined with FlashAttention (which avoids materialising even the local matrix), per-GPU memory for attention is O(L/N) in sequence length. Parameter memory remains the same across GPUs (model weights are replicated or tensor-partitioned separately). Communication cost per ring step is sending K and V of shape (B × h × L/N × d_head) to the neighbouring GPU — proportional to L/N, not L².

```python
import math

def ring_attention_memory(L, N, h, d_head, dtype_bytes=2):
    """Estimate per-GPU memory for ring attention (attention tensors only)."""
    Ls = L // N  # tokens per GPU
    # Q, K, V segments: each (h, Ls, d_head)
    qkv_mem = 3 * h * Ls * d_head * dtype_bytes
    # Local attention score block (with FlashAttention, never fully materialised)
    # FlashAttention tiles with block_size b: max block = h * Ls * b
    b = min(128, Ls)
    flash_tile = h * Ls * b * dtype_bytes
    # Output buffer O: same shape as Q
    out_mem = h * Ls * d_head * dtype_bytes
    # Communication: one K,V send per step
    comm_per_step = 2 * h * Ls * d_head * dtype_bytes
    return qkv_mem + flash_tile + out_mem, comm_per_step

h, d_head = 16, 64
print(f"{'L':>8} {'N GPUs':>8} {'Mem/GPU MB':>12} {'Comm/step MB':>14} {'Full-attn MB':>14}")
for L in [8192, 32768, 131072, 524288]:
    for N in [1, 4, 8, 16]:
        if L // N < 64:
            continue
        mem, comm = ring_attention_memory(L, N, h, d_head)
        full_attn = h * L * L * 2 / 1024**2  # full L^2 attention, float16
        print(f'{L:>8} {N:>8} {mem/1024**2:>12.1f} {comm/1024**2:>14.2f} {full_attn:>14.1f}')
```

| Strategy | Dimension parallelized | Communication pattern | Max sequence length | Use case |
| --- | --- | --- | --- | --- |
| Data parallelism | Batch (B) | AllReduce gradients | Single-GPU limit | Standard training with large batch |
| Tensor parallelism | Model weights (h or d_model) | AllReduce per layer forward | Single-GPU limit | Large models that don't fit on one GPU |
| Sequence parallelism (non-ring) | Sequence (L) — non-attention layers | AllGather / ReduceScatter | Modest improvement | Used in Megatron-LM for LayerNorm, Dropout |
| Ring attention | Sequence (L) — attention layer | P2P K,V ring rotation (N steps) | L × N (linear in GPU count) | Very long contexts: 128K–1M tokens |
| Combined (all four) | B, h, d_model, L simultaneously | All of the above | Product of all axes | Gemini/LLaMA 3 long-context training |

## Communication Overhead and Overlap

Ring attention requires N ring steps where N is the number of GPUs. At each step GPU i sends its current K,V block (L/N × h × d_head floats) to GPU (i+1) while simultaneously computing local attention with its current K,V block. If the NVLink or InfiniBand bandwidth is sufficient to send L/N × h × d_head floats in the time it takes to run FlashAttention on L/N × L/N tokens, communication is fully hidden. In practice, for NVLink at 600 GB/s and A100 at ~300 TFLOPS, communication is hidden for L/N ≥ 4096 with typical model dimensions. Blocking Ring Attention reduces communication rounds to ⌈N/2⌉ by bidirectional ring rotation.

> **Ring Attention Enables Million-Token Contexts**: Ring attention scales sequence length linearly with GPU count: 8 × A100 GPUs each handling 128K tokens = 1M total context. This is how long-context LLaMA variants (LLaMA 3.1 with 128K context) and Gemini (1M context) are trained. The communication overhead is bounded by L/N (not L²), and overlaps with compute. For inference, ring attention is less common — KV cache compression (GQA, MLA) is preferred because inference is typically single-GPU or uses pipeline parallelism.

## Long-Context Training in Practice

Ring attention is primarily a training technique — it enables fitting long sequences into GPU memory during the forward and backward pass. At inference, the full sequence typically fits in a single GPU's memory if KV cache compression (GQA or MLA) is used, making ring attention unnecessary. Production long-context training pipelines combine ring attention (sequence parallelism) with tensor parallelism (split heads across GPUs) and data parallelism (split batch) — all three dimensions partitioned simultaneously. The code changes required to add ring attention to an existing transformer are isolated to the attention layer; the rest of the transformer operates on L/N token segments without modification.

- Ring attention paper (Liu et al. 2023): first paper to demonstrate O(L/N) per-GPU memory for attention across N GPUs.
- LLaMA 3.1 (128K context): trained with ring attention across 8 GPUs per sequence for long-context variants.
- Gemini (1M context): uses a combination of ring-style sequence parallelism and tensor parallelism.
- BlockingRingAttention: reduces communication steps from N to ⌈N/2⌉ using bidirectional ring rotation.
- EasyContext (open source): PyTorch implementation of ring attention with DeepSpeed and FSDP integration.
- Ring attention is orthogonal to FlashAttention — each ring step uses FlashAttention internally for memory-efficient local compute.

---

