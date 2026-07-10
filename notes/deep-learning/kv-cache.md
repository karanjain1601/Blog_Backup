---
title: "KV Cache in Transformer Inference"
slug: "kv-cache"
description: "Caching key and value projections from previous tokens to avoid recomputation during autoregressive decoding, reducing complexity from O(n^2) per step to O(n)."
tags: ["deep-learning", "llm"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"The KV cache is the primary optimization that makes autoregressive transformer inference practical at scale. During the prefill phase, the model computes key (K) and value (V) projections for every input token in one parallel forward pass. Without caching, each subsequent decode step would recompute these projections for all previous tokens — an O(n) operation per step repeated n times, giving O(n^2) total work over an n-token generation. By storing the K and V tensors after prefill and reusing them in all subsequent decode steps, the model reduces each decode step to computing only one new pair of K, V projections for the newly generated token, then concatenating them with the cache. This drops per-step attention from O(n^2) to O(n) in sequence length."},{"type":"heading","level":2,"content":"Overview"},{"type":"text","content":"Transformer attention computes Attention(Q, K, V) = softmax(QK^T / sqrt(d_k)) V. In autoregressive decoding, each generated token t must attend to all t-1 previous tokens plus itself. Without caching, generating token t requires computing K_i and V_i for every prior token i, which is wasteful since K_i and V_i are deterministic functions of fixed previous input tokens and never change. The KV cache stores K_i and V_i after their first computation and reuses them indefinitely. At each decode step, only the new token\u0027s Q, K, V are computed from the new token embedding; the new K and V are appended to the cache, and attention runs against the full cached sequence. This is a pure algorithmic optimization — correctness is identical to the uncached version, with no approximation."},{"type":"heading","level":2,"content":"Prefill vs Decode Phase"},{"type":"text","content":"LLM inference has two computationally distinct phases. The prefill phase processes the entire prompt in a single parallel forward pass. All token positions are known, so attention can be computed as a dense matrix multiplication across all positions simultaneously. Prefill is compute-bound: arithmetic intensity (FLOPs per byte of memory bandwidth) is high, and modern GPUs achieve close to peak FLOP utilization. The decode phase generates tokens one at a time autoregressively. Each step is memory-bandwidth-bound: the GPU must read the full model weights and the full KV cache from HBM (High-Bandwidth Memory) to compute a single output token. On an A100 80GB GPU with 2 TB/s memory bandwidth, reading a 70B parameter model in bfloat16 (~140 GB) plus a 32 GB KV cache takes ~86ms per step — setting a hard floor on token generation latency. This fundamental asymmetry motivates separate optimization strategies: maximize batch size during prefill (higher arithmetic intensity), minimize KV cache size and maximize batch size during decode (higher bandwidth utilization)."},{"type":"heading","level":2,"content":"KV Cache Mechanics"},{"type":"text","content":"At each transformer layer, the KV cache maintains two tensors: K_cache and V_cache, each of shape (batch_size, n_kv_heads, seq_len, head_dim). At decode step t, the new token embedding passes through the Q, K, V projection matrices to produce q_t, k_t, v_t, each of shape (bsz, n_kv_heads, 1, head_dim). k_t and v_t are appended to the cache: K_full = cat([K_cache, k_t], dim=2). Attention then runs against K_full and V_full with the query q_t, producing output of shape (bsz, n_heads, 1, head_dim). This output is projected and added to the residual stream. The updated cache, now containing seq_len + 1 entries, is passed to the next decode step. Across all L layers, this means the model maintains 2 * L KV cache tensors simultaneously. The total memory is proportional to L * n_kv_heads * head_dim * batch_size * seq_len * 2 * dtype_bytes."},{"type":"code","language":"python","content":"import torch\nimport torch.nn.functional as F\nimport math\nimport time\n\ndef decode_step_with_cache(q_new, k_new, v_new, kv_cache=None):\n    \"\"\"\n    Single autoregressive decode step using a KV cache dict.\n    q_new, k_new, v_new: (bsz, 1, head_dim) tensors for the new token.\n    kv_cache: dict {\u0027k\u0027: (bsz, past_len, d), \u0027v\u0027: (bsz, past_len, d)} or None.\n    Returns (output, updated_kv_cache). Cache grows by 1 position each step.\n    Complexity: O(n) per step with cache vs O(n^2) total without.\n    \"\"\"\n    if kv_cache is not None:\n        k = torch.cat([kv_cache[\u0027k\u0027], k_new], dim=1)  # (bsz, past+1, head_dim)\n        v = torch.cat([kv_cache[\u0027v\u0027], v_new], dim=1)\n    else:\n        k, v = k_new, v_new\n    new_cache = {\u0027k\u0027: k, \u0027v\u0027: v}\n    scale = math.sqrt(q_new.shape[-1])\n    scores = torch.bmm(q_new, k.transpose(1, 2)) / scale  # (bsz, 1, seq_len)\n    attn = F.softmax(scores, dim=-1)\n    output = torch.bmm(attn, v)                            # (bsz, 1, head_dim)\n    return output, new_cache\n\n# Benchmark 200-step decode with KV cache\nbsz, head_dim, n_steps = 1, 64, 200\ncache = None\nt0 = time.perf_counter()\nfor step in range(n_steps):\n    q = torch.randn(bsz, 1, head_dim)\n    out, cache = decode_step_with_cache(q, q.clone(), q.clone(), cache)\nelapsed = (time.perf_counter() - t0) * 1000\nprint(f\"Decoded {n_steps} tokens with cache in {elapsed:.1f}ms\")\nprint(f\"Final KV cache shape: {cache[\u0027k\u0027].shape}\")  # (1, 200, 64)\nprint(\"KV cache: O(n) per step -- eliminates redundant K,V recomputation.\")"},{"type":"heading","level":2,"content":"Memory Footprint"},{"type":"text","content":"KV cache memory is the product of six factors: 2 (K and V) × layers × KV_heads × head_dim × batch_size × seq_len × dtype_bytes. For LLaMA-3-8B (32 layers, 8 GQA heads, head_dim=128) in bfloat16 at batch=1, seq=4096: 2 × 32 × 8 × 128 × 1 × 4096 × 2 = 536 MB. At batch=32, seq=8192: 2 × 32 × 8 × 128 × 32 × 8192 × 2 = 34.4 GB. For LLaMA-3-70B (80 layers, 8 GQA heads, head_dim=128) at batch=32, seq=8192: 86 GB — more than the model weights on a single A100. KV cache allocation must be planned as part of GPU memory budgeting: a typical deployment allocates model weights first, then reserves remaining GPU memory for KV cache. The KV cache size determines the maximum achievable batch size and sequence length simultaneously — engineers must choose carefully based on expected workload."},{"type":"code","language":"python","content":"import torch\nfrom typing import Dict, Tuple\n\ndef compute_kv_cache_bytes(\n    n_layers: int,\n    n_kv_heads: int,\n    head_dim: int,\n    batch_size: int,\n    seq_len: int,\n    dtype_bytes: int = 2,  # 2 = bfloat16/float16, 4 = float32\n) -\u003e int:\n    \"\"\"\n    Total KV cache memory in bytes.\n    Formula: 2 (K+V) * layers * kv_heads * head_dim * batch * seq * dtype_bytes.\n    \"\"\"\n    return 2 * n_layers * n_kv_heads * head_dim * batch_size * seq_len * dtype_bytes\n\n# Model configs (GQA reduces n_kv_heads far below n_query_heads)\nconfigs = {\n    \"LLaMA-3-8B  (GQA-8)\":  dict(n_layers=32, n_kv_heads=8,  head_dim=128),\n    \"LLaMA-3-70B (GQA-8)\":  dict(n_layers=80, n_kv_heads=8,  head_dim=128),\n    \"Mistral-7B  (GQA-8)\":  dict(n_layers=32, n_kv_heads=8,  head_dim=128),\n    \"GPT-2 Large (MHA-16)\": dict(n_layers=36, n_kv_heads=16, head_dim=64),\n}\nweight_bytes = {\"LLaMA-3-8B  (GQA-8)\": 8e9*2, \"LLaMA-3-70B (GQA-8)\": 70e9*2,\n                \"Mistral-7B  (GQA-8)\": 7e9*2, \"GPT-2 Large (MHA-16)\": 0.77e9*4}\n\nprint(f\"{\u0027Model\u0027:\u003c26} {\u0027bsz\u0027:\u003e4} {\u0027seq\u0027:\u003e6} {\u0027KV GB\u0027:\u003e8} {\u0027% of weights\u0027:\u003e14}\")\nprint(\"-\" * 64)\nfor name, cfg in configs.items():\n    for bsz, seq in [(1, 4096), (8, 4096), (32, 8192)]:\n        kv = compute_kv_cache_bytes(**cfg, batch_size=bsz, seq_len=seq)\n        pct = kv / weight_bytes[name] * 100\n        print(f\"{name:\u003c26} {bsz:\u003e4} {seq:\u003e6} {kv/1e9:\u003e7.2f}G {pct:\u003e13.1f}%\")"},{"type":"callout","variant":"warning","title":"KV Cache Memory Warning","content":"The KV cache grows linearly with sequence length and batch size — a batch of 32 requests at 8K context can easily require 50+ GB of KV cache alone for a 70B model, before even storing the weights. On a single A100 80GB, storing 70B weights in bfloat16 consumes ~140 GB across multiple GPUs; KV cache must be budgeted per-GPU across the tensor-parallel split. Always profile KV cache size before deploying at batch sizes larger than 4."},{"type":"table","headers":["Attention Type","KV Heads (32L)","Cache Size (seq=4096, bsz=1, dim=128)","vs MHA","Notes"],"rows":[["MHA  (H=32)","32","~2.15 GB","1.0x","Full per-head K,V; GPT-2 / LLaMA-1"],["MQA  (H=1)","1","~0.067 GB","32x smaller","Shared single K,V; PaLM, Falcon-7B"],["GQA-8 (H=8)","8","~0.536 GB","4x smaller","LLaMA-3 all sizes, Mistral-7B"],["GQA-4 (H=4)","4","~0.268 GB","8x smaller","Aggressive; viable at 13B+ scale"],["GQA-2 (H=2)","2","~0.134 GB","16x smaller","Extreme compression; quality tradeoff"]]},{"type":"heading","level":2,"content":"Multi-Query and Grouped-Query Attention"},{"type":"text","content":"Standard Multi-Head Attention (MHA) assigns each query head its own K, V projection matrices, giving n_heads KV heads. Multi-Query Attention (MQA, Shazeer 2019) uses a single shared K, V head across all query heads, reducing KV cache by a factor of n_heads. For a 32-head model, MQA cuts KV cache 32x but can degrade quality, particularly on tasks requiring diverse attention patterns per head. Grouped-Query Attention (GQA, Ainslie et al. 2023) generalizes between MHA and MQA: G groups of query heads share one K,V head each, where 1 \u003c= G \u003c n_heads. LLaMA-3 (8B, 70B), LLaMA-3.1, Mistral-7B, Mixtral, Gemma, and most modern open-source LLMs use GQA with G=8 KV heads. GQA with G=8 achieves 4x KV cache reduction vs MHA while maintaining near-MHA quality at 7B+ parameter scale. The quality degradation from GQA is negligible compared to the memory and throughput benefits, making GQA the default for new large LLM architectures."},{"type":"code","language":"python","content":"import torch\nimport math\n\ndef kv_cache_gb(\n    n_layers: int, n_kv_heads: int, head_dim: int,\n    batch_size: int, seq_len: int, dtype_bytes: int = 2,\n) -\u003e float:\n    \"\"\"KV cache memory in GB (float16/bfloat16 by default).\"\"\"\n    return (2 * n_layers * n_kv_heads * head_dim\n            * batch_size * seq_len * dtype_bytes) / 1e9\n\n# Compare MHA, GQA variants, and MQA for 32-layer model, seq=4096, bsz=1\nbase = dict(n_layers=32, head_dim=128, batch_size=1, seq_len=4096)\nattention_types = [\n    (\"MHA  (32 KV heads)\",  32,  \"GPT-2 / Llama-1 style\"),\n    (\"GQA-8 (8 KV heads)\",   8,  \"LLaMA-3 / Mistral-7B\"),\n    (\"GQA-4 (4 KV heads)\",   4,  \"Custom GQA-4 config\"),\n    (\"GQA-2 (2 KV heads)\",   2,  \"Aggressive compression\"),\n    (\"MQA   (1 KV head)\",    1,  \"PaLM / Falcon-7B style\"),\n]\nmha_gb = kv_cache_gb(**base, n_kv_heads=32)\nprint(f\"{\u0027Attention Type\u0027:\u003c24} {\u0027KV Heads\u0027:\u003e10} {\u0027GB\u0027:\u003e8} {\u0027vs MHA\u0027:\u003e10}  Notes\")\nprint(\"-\" * 75)\nfor label, n_kv, notes in attention_types:\n    gb = kv_cache_gb(**base, n_kv_heads=n_kv)\n    reduction = mha_gb / gb\n    print(f\"{label:\u003c24} {n_kv:\u003e10} {gb:\u003e7.3f}G {reduction:\u003e9.1f}x  {notes}\")\nprint(f\"\\nBase (MHA): {mha_gb:.3f} GB at seq=4096, bsz=1, 32L, dim=128, bf16\")\nprint(\"GQA-8 reduces KV cache 4x vs MHA with minimal quality loss at 7B+ scale.\")"},{"type":"heading","level":2,"content":"KV Cache Eviction"},{"type":"text","content":"For long-context inference where the KV cache would exceed GPU memory, eviction strategies selectively discard stored K, V entries. StreamingLLM (Xiao et al., 2023) keeps the first few tokens (attention sinks, typically 4) plus a sliding window of recent tokens. Attention sink tokens receive disproportionate attention weight; discarding them causes instability. Keeping only sinks + recent tokens (window size 512–2048) enables unbounded context at constant memory. H2O (Heavy-Hitter Oracle, Zhang et al., 2023) tracks cumulative attention weight per token and evicts those with the lowest accumulated score. Tokens that repeatedly receive high attention (heavy hitters) are preserved; rarely attended tokens are evicted. ScissorHands (Liu et al., 2023) maintains a fixed sparse pattern identifying persistent heavy-hitters across generation steps. SnapKV (Li et al., 2024) compresses the KV cache by clustering similar K,V vectors within a window and retaining representative centroids. All eviction strategies trade off quality (lower eviction rate → higher quality) vs memory (higher eviction rate → smaller cache) vs latency (eviction overhead per step)."},{"type":"list","ordered":false,"items":["StreamingLLM: keep first 4 attention-sink tokens + sliding window (512-2048). Constant memory, unbounded context, small quality loss.","H2O: track cumulative attention mass per token, evict lowest-scoring entries. Dynamic and task-adaptive, ~1-2% quality loss at 50% eviction.","ScissorHands: identify persistent heavy-hitter positions; evict non-heavy-hitter tokens. Similar quality to H2O with lower per-step overhead.","SnapKV: cluster similar K,V vectors, retain centroids. Good compression ratio (~4x) with strong long-context performance.","Quantized KV cache (INT8/INT4): reduce dtype_bytes from 2 to 1 or 0.5, doubling effective batch size or sequence length at minimal quality cost.","Layer-wise eviction: deeper layers have lower attention entropy and tolerate more aggressive eviction than early layers."]},{"type":"heading","level":2,"content":"KV Cache in HuggingFace"},{"type":"text","content":"HuggingFace Transformers implements KV caching via the `use_cache=True` parameter (enabled by default in `generate()`). The model returns `past_key_values`, a tuple of (K, V) tuples — one per layer — after each forward pass. In `generate()`, past_key_values is passed automatically between decode steps. Since Transformers v4.36, the `DynamicCache` class wraps past_key_values with an explicit `.update(key_states, value_states, layer_idx)` API, making cache inspection and manipulation straightforward. Static caches (`StaticCache`) pre-allocate fixed-size tensors to avoid dynamic resizing overhead during generation — useful for production serving where max sequence length is known. Quantized KV caches (`QuantoQuantizedCache`) store K,V in INT8 or INT4, halving or quartering cache memory at the cost of a quantization/dequantization step per layer."},{"type":"code","language":"python","content":"import torch\nimport time\nfrom transformers import AutoModelForCausalLM, AutoTokenizer\n\ndef benchmark_hf_kv_cache(\n    model_name: str = \"gpt2\",\n    prompt: str = \"The KV cache is a key optimization for transformer inference because\",\n    max_new_tokens: int = 80,\n):\n    \"\"\"Compare HuggingFace generation speed with vs without KV cache.\"\"\"\n    tokenizer = AutoTokenizer.from_pretrained(model_name)\n    model = AutoModelForCausalLM.from_pretrained(model_name).eval()\n    inputs = tokenizer(prompt, return_tensors=\"pt\")\n    input_ids = inputs[\"input_ids\"]\n\n    # Inspect past_key_values from a single forward pass\n    with torch.no_grad():\n        fwd = model(input_ids, use_cache=True)\n    pkv = fwd.past_key_values  # tuple of (K, V) per layer\n    print(f\"Model: {model_name}  |  num layers in KV cache: {len(pkv)}\")\n    print(f\"Layer-0 K shape: {pkv[0][0].shape}\")  # (bsz, n_heads, seq, head_dim)\n\n    # With KV cache (default use_cache=True)\n    t0 = time.perf_counter()\n    with torch.no_grad():\n        out_cached = model.generate(input_ids, max_new_tokens=max_new_tokens, use_cache=True)\n    t_cached = time.perf_counter() - t0\n\n    # Without KV cache (recomputes all K,V at every step)\n    t0 = time.perf_counter()\n    with torch.no_grad():\n        out_uncached = model.generate(input_ids, max_new_tokens=max_new_tokens, use_cache=False)\n    t_uncached = time.perf_counter() - t0\n\n    speedup = t_uncached / t_cached\n    print(f\"use_cache=True:  {t_cached:.2f}s\")\n    print(f\"use_cache=False: {t_uncached:.2f}s\")\n    print(f\"KV cache speedup: {speedup:.1f}x  (grows with max_new_tokens)\")\n\nbenchmark_hf_kv_cache()"},{"type":"heading","level":2,"content":"Key Takeaways"},{"type":"list","ordered":false,"items":["KV cache converts O(n^2) total decode work to O(n): essential for any generation longer than ~10 tokens.","Memory = 2 * layers * KV_heads * head_dim * batch * seq * dtype_bytes; model the budget explicitly before deployment.","GQA with 8 KV heads is now the standard: 4x KV cache reduction vs MHA with negligible quality loss at 7B+ scale.","MQA (1 KV head) gives maximum cache reduction (32x for 32-head models) but risks quality degradation; used in PaLM and Falcon.","Decode phase is memory-bandwidth-bound: larger batches improve GPU utilization by amortizing weight reads across more tokens.","KV cache eviction (StreamingLLM, H2O, SnapKV) enables long-context inference beyond available GPU memory at modest quality cost.","HuggingFace DynamicCache and StaticCache provide flexible vs pre-allocated KV storage; prefer StaticCache for production generation latency.","Quantized KV cache (INT8/INT4) provides 2-4x memory reduction; combine with GQA for maximum efficiency."]},{"type":"divider"}]"
---
# KV Cache in Transformer Inference

The KV cache is the primary optimization that makes autoregressive transformer inference practical at scale. During the prefill phase, the model computes key (K) and value (V) projections for every input token in one parallel forward pass. Without caching, each subsequent decode step would recompute these projections for all previous tokens — an O(n) operation per step repeated n times, giving O(n^2) total work over an n-token generation. By storing the K and V tensors after prefill and reusing them in all subsequent decode steps, the model reduces each decode step to computing only one new pair of K, V projections for the newly generated token, then concatenating them with the cache. This drops per-step attention from O(n^2) to O(n) in sequence length.

## Overview

Transformer attention computes Attention(Q, K, V) = softmax(QK^T / sqrt(d_k)) V. In autoregressive decoding, each generated token t must attend to all t-1 previous tokens plus itself. Without caching, generating token t requires computing K_i and V_i for every prior token i, which is wasteful since K_i and V_i are deterministic functions of fixed previous input tokens and never change. The KV cache stores K_i and V_i after their first computation and reuses them indefinitely. At each decode step, only the new token's Q, K, V are computed from the new token embedding; the new K and V are appended to the cache, and attention runs against the full cached sequence. This is a pure algorithmic optimization — correctness is identical to the uncached version, with no approximation.

## Prefill vs Decode Phase

LLM inference has two computationally distinct phases. The prefill phase processes the entire prompt in a single parallel forward pass. All token positions are known, so attention can be computed as a dense matrix multiplication across all positions simultaneously. Prefill is compute-bound: arithmetic intensity (FLOPs per byte of memory bandwidth) is high, and modern GPUs achieve close to peak FLOP utilization. The decode phase generates tokens one at a time autoregressively. Each step is memory-bandwidth-bound: the GPU must read the full model weights and the full KV cache from HBM (High-Bandwidth Memory) to compute a single output token. On an A100 80GB GPU with 2 TB/s memory bandwidth, reading a 70B parameter model in bfloat16 (~140 GB) plus a 32 GB KV cache takes ~86ms per step — setting a hard floor on token generation latency. This fundamental asymmetry motivates separate optimization strategies: maximize batch size during prefill (higher arithmetic intensity), minimize KV cache size and maximize batch size during decode (higher bandwidth utilization).

## KV Cache Mechanics

At each transformer layer, the KV cache maintains two tensors: K_cache and V_cache, each of shape (batch_size, n_kv_heads, seq_len, head_dim). At decode step t, the new token embedding passes through the Q, K, V projection matrices to produce q_t, k_t, v_t, each of shape (bsz, n_kv_heads, 1, head_dim). k_t and v_t are appended to the cache: K_full = cat([K_cache, k_t], dim=2). Attention then runs against K_full and V_full with the query q_t, producing output of shape (bsz, n_heads, 1, head_dim). This output is projected and added to the residual stream. The updated cache, now containing seq_len + 1 entries, is passed to the next decode step. Across all L layers, this means the model maintains 2 * L KV cache tensors simultaneously. The total memory is proportional to L * n_kv_heads * head_dim * batch_size * seq_len * 2 * dtype_bytes.

```python
import torch
import torch.nn.functional as F
import math
import time

def decode_step_with_cache(q_new, k_new, v_new, kv_cache=None):
    """
    Single autoregressive decode step using a KV cache dict.
    q_new, k_new, v_new: (bsz, 1, head_dim) tensors for the new token.
    kv_cache: dict {'k': (bsz, past_len, d), 'v': (bsz, past_len, d)} or None.
    Returns (output, updated_kv_cache). Cache grows by 1 position each step.
    Complexity: O(n) per step with cache vs O(n^2) total without.
    """
    if kv_cache is not None:
        k = torch.cat([kv_cache['k'], k_new], dim=1)  # (bsz, past+1, head_dim)
        v = torch.cat([kv_cache['v'], v_new], dim=1)
    else:
        k, v = k_new, v_new
    new_cache = {'k': k, 'v': v}
    scale = math.sqrt(q_new.shape[-1])
    scores = torch.bmm(q_new, k.transpose(1, 2)) / scale  # (bsz, 1, seq_len)
    attn = F.softmax(scores, dim=-1)
    output = torch.bmm(attn, v)                            # (bsz, 1, head_dim)
    return output, new_cache

# Benchmark 200-step decode with KV cache
bsz, head_dim, n_steps = 1, 64, 200
cache = None
t0 = time.perf_counter()
for step in range(n_steps):
    q = torch.randn(bsz, 1, head_dim)
    out, cache = decode_step_with_cache(q, q.clone(), q.clone(), cache)
elapsed = (time.perf_counter() - t0) * 1000
print(f"Decoded {n_steps} tokens with cache in {elapsed:.1f}ms")
print(f"Final KV cache shape: {cache['k'].shape}")  # (1, 200, 64)
print("KV cache: O(n) per step -- eliminates redundant K,V recomputation.")
```

## Memory Footprint

KV cache memory is the product of six factors: 2 (K and V) × layers × KV_heads × head_dim × batch_size × seq_len × dtype_bytes. For LLaMA-3-8B (32 layers, 8 GQA heads, head_dim=128) in bfloat16 at batch=1, seq=4096: 2 × 32 × 8 × 128 × 1 × 4096 × 2 = 536 MB. At batch=32, seq=8192: 2 × 32 × 8 × 128 × 32 × 8192 × 2 = 34.4 GB. For LLaMA-3-70B (80 layers, 8 GQA heads, head_dim=128) at batch=32, seq=8192: 86 GB — more than the model weights on a single A100. KV cache allocation must be planned as part of GPU memory budgeting: a typical deployment allocates model weights first, then reserves remaining GPU memory for KV cache. The KV cache size determines the maximum achievable batch size and sequence length simultaneously — engineers must choose carefully based on expected workload.

```python
import torch
from typing import Dict, Tuple

def compute_kv_cache_bytes(
    n_layers: int,
    n_kv_heads: int,
    head_dim: int,
    batch_size: int,
    seq_len: int,
    dtype_bytes: int = 2,  # 2 = bfloat16/float16, 4 = float32
) -> int:
    """
    Total KV cache memory in bytes.
    Formula: 2 (K+V) * layers * kv_heads * head_dim * batch * seq * dtype_bytes.
    """
    return 2 * n_layers * n_kv_heads * head_dim * batch_size * seq_len * dtype_bytes

# Model configs (GQA reduces n_kv_heads far below n_query_heads)
configs = {
    "LLaMA-3-8B  (GQA-8)":  dict(n_layers=32, n_kv_heads=8,  head_dim=128),
    "LLaMA-3-70B (GQA-8)":  dict(n_layers=80, n_kv_heads=8,  head_dim=128),
    "Mistral-7B  (GQA-8)":  dict(n_layers=32, n_kv_heads=8,  head_dim=128),
    "GPT-2 Large (MHA-16)": dict(n_layers=36, n_kv_heads=16, head_dim=64),
}
weight_bytes = {"LLaMA-3-8B  (GQA-8)": 8e9*2, "LLaMA-3-70B (GQA-8)": 70e9*2,
                "Mistral-7B  (GQA-8)": 7e9*2, "GPT-2 Large (MHA-16)": 0.77e9*4}

print(f"{'Model':<26} {'bsz':>4} {'seq':>6} {'KV GB':>8} {'% of weights':>14}")
print("-" * 64)
for name, cfg in configs.items():
    for bsz, seq in [(1, 4096), (8, 4096), (32, 8192)]:
        kv = compute_kv_cache_bytes(**cfg, batch_size=bsz, seq_len=seq)
        pct = kv / weight_bytes[name] * 100
        print(f"{name:<26} {bsz:>4} {seq:>6} {kv/1e9:>7.2f}G {pct:>13.1f}%")
```

> **KV Cache Memory Warning**: The KV cache grows linearly with sequence length and batch size — a batch of 32 requests at 8K context can easily require 50+ GB of KV cache alone for a 70B model, before even storing the weights. On a single A100 80GB, storing 70B weights in bfloat16 consumes ~140 GB across multiple GPUs; KV cache must be budgeted per-GPU across the tensor-parallel split. Always profile KV cache size before deploying at batch sizes larger than 4.

| Attention Type | KV Heads (32L) | Cache Size (seq=4096, bsz=1, dim=128) | vs MHA | Notes |
| --- | --- | --- | --- | --- |
| MHA  (H=32) | 32 | ~2.15 GB | 1.0x | Full per-head K,V; GPT-2 / LLaMA-1 |
| MQA  (H=1) | 1 | ~0.067 GB | 32x smaller | Shared single K,V; PaLM, Falcon-7B |
| GQA-8 (H=8) | 8 | ~0.536 GB | 4x smaller | LLaMA-3 all sizes, Mistral-7B |
| GQA-4 (H=4) | 4 | ~0.268 GB | 8x smaller | Aggressive; viable at 13B+ scale |
| GQA-2 (H=2) | 2 | ~0.134 GB | 16x smaller | Extreme compression; quality tradeoff |

## Multi-Query and Grouped-Query Attention

Standard Multi-Head Attention (MHA) assigns each query head its own K, V projection matrices, giving n_heads KV heads. Multi-Query Attention (MQA, Shazeer 2019) uses a single shared K, V head across all query heads, reducing KV cache by a factor of n_heads. For a 32-head model, MQA cuts KV cache 32x but can degrade quality, particularly on tasks requiring diverse attention patterns per head. Grouped-Query Attention (GQA, Ainslie et al. 2023) generalizes between MHA and MQA: G groups of query heads share one K,V head each, where 1 <= G < n_heads. LLaMA-3 (8B, 70B), LLaMA-3.1, Mistral-7B, Mixtral, Gemma, and most modern open-source LLMs use GQA with G=8 KV heads. GQA with G=8 achieves 4x KV cache reduction vs MHA while maintaining near-MHA quality at 7B+ parameter scale. The quality degradation from GQA is negligible compared to the memory and throughput benefits, making GQA the default for new large LLM architectures.

```python
import torch
import math

def kv_cache_gb(
    n_layers: int, n_kv_heads: int, head_dim: int,
    batch_size: int, seq_len: int, dtype_bytes: int = 2,
) -> float:
    """KV cache memory in GB (float16/bfloat16 by default)."""
    return (2 * n_layers * n_kv_heads * head_dim
            * batch_size * seq_len * dtype_bytes) / 1e9

# Compare MHA, GQA variants, and MQA for 32-layer model, seq=4096, bsz=1
base = dict(n_layers=32, head_dim=128, batch_size=1, seq_len=4096)
attention_types = [
    ("MHA  (32 KV heads)",  32,  "GPT-2 / Llama-1 style"),
    ("GQA-8 (8 KV heads)",   8,  "LLaMA-3 / Mistral-7B"),
    ("GQA-4 (4 KV heads)",   4,  "Custom GQA-4 config"),
    ("GQA-2 (2 KV heads)",   2,  "Aggressive compression"),
    ("MQA   (1 KV head)",    1,  "PaLM / Falcon-7B style"),
]
mha_gb = kv_cache_gb(**base, n_kv_heads=32)
print(f"{'Attention Type':<24} {'KV Heads':>10} {'GB':>8} {'vs MHA':>10}  Notes")
print("-" * 75)
for label, n_kv, notes in attention_types:
    gb = kv_cache_gb(**base, n_kv_heads=n_kv)
    reduction = mha_gb / gb
    print(f"{label:<24} {n_kv:>10} {gb:>7.3f}G {reduction:>9.1f}x  {notes}")
print(f"\nBase (MHA): {mha_gb:.3f} GB at seq=4096, bsz=1, 32L, dim=128, bf16")
print("GQA-8 reduces KV cache 4x vs MHA with minimal quality loss at 7B+ scale.")
```

## KV Cache Eviction

For long-context inference where the KV cache would exceed GPU memory, eviction strategies selectively discard stored K, V entries. StreamingLLM (Xiao et al., 2023) keeps the first few tokens (attention sinks, typically 4) plus a sliding window of recent tokens. Attention sink tokens receive disproportionate attention weight; discarding them causes instability. Keeping only sinks + recent tokens (window size 512–2048) enables unbounded context at constant memory. H2O (Heavy-Hitter Oracle, Zhang et al., 2023) tracks cumulative attention weight per token and evicts those with the lowest accumulated score. Tokens that repeatedly receive high attention (heavy hitters) are preserved; rarely attended tokens are evicted. ScissorHands (Liu et al., 2023) maintains a fixed sparse pattern identifying persistent heavy-hitters across generation steps. SnapKV (Li et al., 2024) compresses the KV cache by clustering similar K,V vectors within a window and retaining representative centroids. All eviction strategies trade off quality (lower eviction rate → higher quality) vs memory (higher eviction rate → smaller cache) vs latency (eviction overhead per step).

- StreamingLLM: keep first 4 attention-sink tokens + sliding window (512-2048). Constant memory, unbounded context, small quality loss.
- H2O: track cumulative attention mass per token, evict lowest-scoring entries. Dynamic and task-adaptive, ~1-2% quality loss at 50% eviction.
- ScissorHands: identify persistent heavy-hitter positions; evict non-heavy-hitter tokens. Similar quality to H2O with lower per-step overhead.
- SnapKV: cluster similar K,V vectors, retain centroids. Good compression ratio (~4x) with strong long-context performance.
- Quantized KV cache (INT8/INT4): reduce dtype_bytes from 2 to 1 or 0.5, doubling effective batch size or sequence length at minimal quality cost.
- Layer-wise eviction: deeper layers have lower attention entropy and tolerate more aggressive eviction than early layers.

## KV Cache in HuggingFace

HuggingFace Transformers implements KV caching via the `use_cache=True` parameter (enabled by default in `generate()`). The model returns `past_key_values`, a tuple of (K, V) tuples — one per layer — after each forward pass. In `generate()`, past_key_values is passed automatically between decode steps. Since Transformers v4.36, the `DynamicCache` class wraps past_key_values with an explicit `.update(key_states, value_states, layer_idx)` API, making cache inspection and manipulation straightforward. Static caches (`StaticCache`) pre-allocate fixed-size tensors to avoid dynamic resizing overhead during generation — useful for production serving where max sequence length is known. Quantized KV caches (`QuantoQuantizedCache`) store K,V in INT8 or INT4, halving or quartering cache memory at the cost of a quantization/dequantization step per layer.

```python
import torch
import time
from transformers import AutoModelForCausalLM, AutoTokenizer

def benchmark_hf_kv_cache(
    model_name: str = "gpt2",
    prompt: str = "The KV cache is a key optimization for transformer inference because",
    max_new_tokens: int = 80,
):
    """Compare HuggingFace generation speed with vs without KV cache."""
    tokenizer = AutoTokenizer.from_pretrained(model_name)
    model = AutoModelForCausalLM.from_pretrained(model_name).eval()
    inputs = tokenizer(prompt, return_tensors="pt")
    input_ids = inputs["input_ids"]

    # Inspect past_key_values from a single forward pass
    with torch.no_grad():
        fwd = model(input_ids, use_cache=True)
    pkv = fwd.past_key_values  # tuple of (K, V) per layer
    print(f"Model: {model_name}  |  num layers in KV cache: {len(pkv)}")
    print(f"Layer-0 K shape: {pkv[0][0].shape}")  # (bsz, n_heads, seq, head_dim)

    # With KV cache (default use_cache=True)
    t0 = time.perf_counter()
    with torch.no_grad():
        out_cached = model.generate(input_ids, max_new_tokens=max_new_tokens, use_cache=True)
    t_cached = time.perf_counter() - t0

    # Without KV cache (recomputes all K,V at every step)
    t0 = time.perf_counter()
    with torch.no_grad():
        out_uncached = model.generate(input_ids, max_new_tokens=max_new_tokens, use_cache=False)
    t_uncached = time.perf_counter() - t0

    speedup = t_uncached / t_cached
    print(f"use_cache=True:  {t_cached:.2f}s")
    print(f"use_cache=False: {t_uncached:.2f}s")
    print(f"KV cache speedup: {speedup:.1f}x  (grows with max_new_tokens)")

benchmark_hf_kv_cache()
```

## Key Takeaways

- KV cache converts O(n^2) total decode work to O(n): essential for any generation longer than ~10 tokens.
- Memory = 2 * layers * KV_heads * head_dim * batch * seq * dtype_bytes; model the budget explicitly before deployment.
- GQA with 8 KV heads is now the standard: 4x KV cache reduction vs MHA with negligible quality loss at 7B+ scale.
- MQA (1 KV head) gives maximum cache reduction (32x for 32-head models) but risks quality degradation; used in PaLM and Falcon.
- Decode phase is memory-bandwidth-bound: larger batches improve GPU utilization by amortizing weight reads across more tokens.
- KV cache eviction (StreamingLLM, H2O, SnapKV) enables long-context inference beyond available GPU memory at modest quality cost.
- HuggingFace DynamicCache and StaticCache provide flexible vs pre-allocated KV storage; prefer StaticCache for production generation latency.
- Quantized KV cache (INT8/INT4) provides 2-4x memory reduction; combine with GQA for maximum efficiency.

---

