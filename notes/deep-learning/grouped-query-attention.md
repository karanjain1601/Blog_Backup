---
title: "Grouped Query Attention (GQA) — Interpolating MHA and MQA"
slug: "grouped-query-attention"
description: "Implement GQA from scratch, convert MHA checkpoints to GQA by mean-pooling K/V heads, build a GQA inference KV cache, and benchmark MHA vs GQA vs MQA on quality and memory."
tags: ["deep-learning", "transformers", "attention-efficiency"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"Grouped Query Attention (GQA), introduced by Ainslie et al. (2023), generalises both Multi-Head Attention (MHA) and Multi-Query Attention (MQA) by dividing the h query heads into G groups. Each group shares a single K and V projection, so the model keeps h query heads but only G KV heads. When G = h every head has its own K and V — identical to MHA. When G = 1 all heads share one K and V — identical to MQA. The KV cache at inference is proportional to G rather than h, giving an h/G× memory reduction while maintaining quality close to MHA."},{"type":"heading","level":2,"content":"Standard MHA and the KV Cache Bottleneck"},{"type":"text","content":"At inference the transformer KV cache stores past keys and values for every layer to avoid recomputation. For MHA with h heads and head dimension d_head the cache per layer is 2 × h × d_head × L elements. For LLaMA 2 70B (h=64, d_head=128, L=4096, float16) this is ~64 MB per layer, ~5 GB across 80 layers — just for KV. MQA (G=1) reduces this h× but degrades output quality by 1–3% on long-document tasks. GQA with G=8 achieves a 4–8× KV reduction with negligible quality loss, making long-context inference practical on commodity GPU memory."},{"type":"heading","level":2,"content":"GQA: Grouping Query Heads and Sharing K, V"},{"type":"text","content":"In GQA the h query heads are partitioned into G groups of size h/G. Each group uses one shared K projection and one shared V projection. W_Q remains (h × d_head) × d_model, but W_K and W_V shrink to (G × d_head) × d_model. During the forward pass K and V are expanded from G to h by repeating each group\u0027s representation h/G times — a cheap memory operation with no extra learnable parameters."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.nn.functional as F\nimport math\n\nclass GroupedQueryAttention(nn.Module):\n    def __init__(self, d_model, num_heads, num_kv_groups):\n        super().__init__()\n        assert num_heads % num_kv_groups == 0\n        self.h = num_heads\n        self.G = num_kv_groups\n        self.qpg = num_heads // num_kv_groups  # queries per group\n        self.d_head = d_model // num_heads\n        self.W_q = nn.Linear(d_model, num_heads * self.d_head, bias=False)\n        self.W_k = nn.Linear(d_model, num_kv_groups * self.d_head, bias=False)\n        self.W_v = nn.Linear(d_model, num_kv_groups * self.d_head, bias=False)\n        self.W_o = nn.Linear(num_heads * self.d_head, d_model, bias=False)\n\n    def forward(self, x):\n        B, L, _ = x.shape\n        Q = self.W_q(x).view(B, L, self.h, self.d_head).transpose(1, 2)\n        K = self.W_k(x).view(B, L, self.G, self.d_head).transpose(1, 2)\n        V = self.W_v(x).view(B, L, self.G, self.d_head).transpose(1, 2)\n        K = K.repeat_interleave(self.qpg, dim=1)  # expand G -\u003e h\n        V = V.repeat_interleave(self.qpg, dim=1)\n        attn = F.softmax(Q @ K.transpose(-2, -1) / math.sqrt(self.d_head), dim=-1)\n        out = (attn @ V).transpose(1, 2).reshape(B, L, -1)\n        return self.W_o(out)\n\nfor G in [1, 2, 4, 8]:  # G=1: MQA, G=8: MHA (h=8)\n    m = GroupedQueryAttention(d_model=256, num_heads=8, num_kv_groups=G)\n    x = torch.randn(2, 16, 256)\n    out = m(x)\n    kv = sum(p.numel() for n, p in m.named_parameters() if \u0027_k\u0027 in n or \u0027_v\u0027 in n)\n    print(f\u0027G={G}: out={out.shape}, KV params={kv}, KV cache ratio={8//G}x vs MHA\u0027)"},{"type":"heading","level":2,"content":"Converting MHA to GQA by Mean-Pooling"},{"type":"text","content":"LLaMA 2 34B and 70B were originally trained as MHA models and then converted to GQA before release. The conversion: reshape the K weight from (h × d_head, d_model) into (G, h/G, d_head, d_model), mean-pool across the h/G heads within each group, yielding (G, d_head, d_model). This minimum-distortion approximation is followed by a brief fine-tuning phase. Ainslie et al. showed that uptrained GQA matches scratch-trained GQA quality after sufficient fine-tuning steps."},{"type":"code","language":"python","content":"import torch\n\ndef mha_to_gqa(W_k, W_v, num_heads, num_kv_groups, d_head):\n    \"\"\"Convert MHA K,V weight matrices to GQA by mean-pooling within groups.\n    W_k shape: (num_heads * d_head, d_model)\n    Returns:   (num_kv_groups * d_head, d_model)\n    \"\"\"\n    qpg = num_heads // num_kv_groups\n    d_model = W_k.shape[1]\n    Wk = W_k.view(num_kv_groups, qpg, d_head, d_model).mean(dim=1)\n    Wv = W_v.view(num_kv_groups, qpg, d_head, d_model).mean(dim=1)\n    return Wk.reshape(num_kv_groups * d_head, d_model), Wv.reshape(num_kv_groups * d_head, d_model)\n\ntorch.manual_seed(0)\nh, G, d_head, d_model = 8, 2, 32, 256\nWk_mha = torch.randn(h * d_head, d_model)\nWv_mha = torch.randn(h * d_head, d_model)\nWk_gqa, Wv_gqa = mha_to_gqa(Wk_mha, Wv_mha, h, G, d_head)\nprint(f\u0027MHA W_K: {Wk_mha.shape}  -\u003e GQA W_K: {Wk_gqa.shape}\u0027)\nprint(f\u0027MHA KV params: {Wk_mha.numel()*2}  -\u003e GQA: {Wk_gqa.numel()*2}  ({h//G}x reduction)\u0027)\nprint(f\u0027LLaMA 2 70B: h=64, G=8 -\u003e 8x KV reduction via this mean-pool + fine-tune.\u0027)\nprint(\u0027Cosine sim of first group (original vs pooled):\u0027)\norig_group0 = Wk_mha.view(G, h//G, d_head, d_model)[0].mean(0)  # expected pooled\nprint(f\u0027  {torch.nn.functional.cosine_similarity(orig_group0.flatten(), Wk_gqa[:d_head].flatten(), dim=0).item():.6f}\u0027)"},{"type":"heading","level":2,"content":"GQA KV Cache at Inference"},{"type":"text","content":"The KV cache stores G × d_head × 2 values per token per layer (vs h × d_head × 2 for MHA). At each generation step: project Q to h heads, project K and V to G groups, append new K,V slices to the cache, expand the full cache from G to h via repeat_interleave, then compute attention over the cached sequence. The cache growth per token is G/h of MHA — for G=8, h=64, that is 8× less memory allocated per new token."},{"type":"code","language":"python","content":"import torch\nimport torch.nn.functional as F\nimport math\n\nclass GQAKVCache:\n    def __init__(self, max_len, G, d_head):\n        self.G, self.d, self.t = G, d_head, 0\n        self.K = torch.zeros(1, G, max_len, d_head)\n        self.V = torch.zeros(1, G, max_len, d_head)\n\n    def step(self, q, k, v):\n        \"\"\"q: (1,h,1,d)  k/v: (1,G,1,d). Returns (1,h,1,d).\"\"\"\n        self.K[:, :, self.t:self.t+1] = k\n        self.V[:, :, self.t:self.t+1] = v\n        self.t += 1\n        Kc = self.K[:, :, :self.t]  # (1,G,t,d)\n        Vc = self.V[:, :, :self.t]\n        h = q.shape[1]\n        Kc = Kc.repeat_interleave(h // self.G, dim=1)\n        Vc = Vc.repeat_interleave(h // self.G, dim=1)\n        scores = q @ Kc.transpose(-2, -1) / math.sqrt(self.d)\n        return F.softmax(scores, dim=-1) @ Vc\n\nh, G, d, max_len = 8, 2, 32, 128\ncache = GQAKVCache(max_len, G, d)\nfor _ in range(20):\n    out = cache.step(torch.randn(1,h,1,d), torch.randn(1,G,1,d), torch.randn(1,G,1,d))\nprint(f\u0027After {cache.t} steps: cache K = {cache.K[:,:,:cache.t].shape}\u0027)\nfor g, label in [(h,\u0027MHA\u0027), (G,\u0027GQA\u0027)]:\n    kb = g * d * max_len * 2 * 2 / 1024  # K+V, float16\n    print(f\u0027{label} (G={g}): {kb:.1f} KB/layer  ratio={h//g}x\u0027)"},{"type":"heading","level":2,"content":"Benchmark: MHA vs GQA vs MQA"},{"type":"text","content":"The throughput benefit of GQA at inference is dominated by KV cache size. When the cache fits in HBM rather than DRAM, generation can be 2–4× faster due to reduced memory bandwidth pressure. During training, smaller W_K and W_V matrices reduce the KV projection FLOPs by G/h, but this is usually a small fraction of total compute. The quality gap between MHA and GQA (G=8) is \u003c0.5 perplexity points on language modelling benchmarks; MQA (G=1) shows 1–3% degradation on long-document QA."},{"type":"code","language":"python","content":"import torch\nimport torch.nn.functional as F\nimport math\nimport time\n\ndef gqa_attn(Q, K, V, G):\n    \"\"\"Q: (B,h,L,d), K/V: (B,G,L,d). Returns (B,h,L,d).\"\"\"\n    h = Q.shape[1]\n    K = K.repeat_interleave(h // G, dim=1)\n    V = V.repeat_interleave(h // G, dim=1)\n    return F.softmax(Q @ K.transpose(-2,-1) / math.sqrt(Q.shape[-1]), dim=-1) @ V\n\ntorch.manual_seed(0)\nB, L, h, d = 2, 256, 8, 64\nprint(f\"{\u0027Method\u0027:\u003e8} {\u0027G\u0027:\u003e4} {\u0027KV cache KB\u0027:\u003e13} {\u0027ms/fwd\u0027:\u003e9} {\u0027KV ratio\u0027:\u003e10}\")\nfor G in [h, 4, 2, 1]:\n    Q = torch.randn(B, h, L, d)\n    K = torch.randn(B, G, L, d)\n    V = torch.randn(B, G, L, d)\n    runs = 30\n    t0 = time.perf_counter()\n    for _ in range(runs):\n        _ = gqa_attn(Q, K, V, G)\n    ms = (time.perf_counter() - t0) / runs * 1000\n    kv_kb = G * d * L * 2 * 2 / 1024  # K+V, float16\n    label = \u0027MHA\u0027 if G == h else (\u0027MQA\u0027 if G == 1 else f\u0027GQA-{G}\u0027)\n    print(f\u0027{label:\u003e8} {G:\u003e4} {kv_kb:\u003e13.1f} {ms:\u003e9.2f} {h//G:\u003e9}x\u0027)"},{"type":"table","headers":["Method","G value","KV heads","Quality vs MHA","KV cache ratio","Used in LLMs","MHA conversion"],"rows":[["MHA","G = h","h (all unique)","Baseline (best)","1× (largest)","GPT-2, BERT, early LLaMA","N/A"],["MQA","G = 1","1 (all shared)","−1–3% on long-doc QA","h× smaller","PaLM, Falcon-7B","Mean-pool all h heads to 1"],["GQA","1 \u003c G \u003c h","G (grouped)","≈MHA with G ≥ 4","h/G× smaller","LLaMA 2/3, Mistral, Gemma, Qwen","Mean-pool h/G heads per group"]]},{"type":"heading","level":2,"content":"Quality and Efficiency Trade-offs"},{"type":"text","content":"Ainslie et al. benchmarked GQA on T5-Large and T5-XXL. With G = h/8, GQA matches MHA perplexity on language modelling and stays within 0.5% on summarisation. The KV cache is h/G× smaller: for LLaMA 70B (h=64, G=8), that is an 8× reduction. Batch throughput at long-context inference increases 2–3× because the smaller cache lets more sequences fit in GPU memory simultaneously, raising batch size and GPU utilisation."},{"type":"callout","variant":"info","title":"GQA Design Rule","content":"Set G so that h/G is a power of 2 and G divides h evenly. LLaMA 2/3 use G=8 for large models (h=64 for 70B → 8 KV heads). Mistral 7B uses G=8 with h=32 → 4 KV heads. Smaller models may use G=4 or G=2. MQA (G=1) is only recommended when memory is severely constrained and quality degradation is acceptable."},{"type":"heading","level":2,"content":"Models and Configurations Using GQA"},{"type":"text","content":"GQA has become the de facto standard for large transformer models since 2023. LLaMA 2 introduced it for 34B and 70B variants (7B and 13B retained MHA). LLaMA 3 uses GQA across all sizes including 8B. Mistral 7B, Mixtral MoE, Gemma, Gemma 2, and Qwen2 all adopt GQA. The consistent adoption demonstrates that G=8 is a well-validated configuration balancing quality and inference efficiency."},{"type":"list","ordered":false,"items":["LLaMA 2: h=32, G=8 for 34B; h=64, G=8 for 70B — converted from MHA via mean-pool + fine-tune.","LLaMA 3: all sizes use GQA — 8B: h=32, G=8; 70B: h=64, G=8.","Mistral 7B: h=32, G=8 → 4 KV heads; combined with sliding window attention.","Gemma 2: G=1 (MQA) for 2B; G=4 for 9B and 27B variants.","Qwen2: GQA across all sizes; 72B uses h=64, G=8.","Falcon 40B+: uses MQA (G=1); earlier Falcon models used full MHA."]},{"type":"divider"}]"
---
# Grouped Query Attention (GQA) — Interpolating MHA and MQA

Grouped Query Attention (GQA), introduced by Ainslie et al. (2023), generalises both Multi-Head Attention (MHA) and Multi-Query Attention (MQA) by dividing the h query heads into G groups. Each group shares a single K and V projection, so the model keeps h query heads but only G KV heads. When G = h every head has its own K and V — identical to MHA. When G = 1 all heads share one K and V — identical to MQA. The KV cache at inference is proportional to G rather than h, giving an h/G× memory reduction while maintaining quality close to MHA.

## Standard MHA and the KV Cache Bottleneck

At inference the transformer KV cache stores past keys and values for every layer to avoid recomputation. For MHA with h heads and head dimension d_head the cache per layer is 2 × h × d_head × L elements. For LLaMA 2 70B (h=64, d_head=128, L=4096, float16) this is ~64 MB per layer, ~5 GB across 80 layers — just for KV. MQA (G=1) reduces this h× but degrades output quality by 1–3% on long-document tasks. GQA with G=8 achieves a 4–8× KV reduction with negligible quality loss, making long-context inference practical on commodity GPU memory.

## GQA: Grouping Query Heads and Sharing K, V

In GQA the h query heads are partitioned into G groups of size h/G. Each group uses one shared K projection and one shared V projection. W_Q remains (h × d_head) × d_model, but W_K and W_V shrink to (G × d_head) × d_model. During the forward pass K and V are expanded from G to h by repeating each group's representation h/G times — a cheap memory operation with no extra learnable parameters.

```python
import torch
import torch.nn as nn
import torch.nn.functional as F
import math

class GroupedQueryAttention(nn.Module):
    def __init__(self, d_model, num_heads, num_kv_groups):
        super().__init__()
        assert num_heads % num_kv_groups == 0
        self.h = num_heads
        self.G = num_kv_groups
        self.qpg = num_heads // num_kv_groups  # queries per group
        self.d_head = d_model // num_heads
        self.W_q = nn.Linear(d_model, num_heads * self.d_head, bias=False)
        self.W_k = nn.Linear(d_model, num_kv_groups * self.d_head, bias=False)
        self.W_v = nn.Linear(d_model, num_kv_groups * self.d_head, bias=False)
        self.W_o = nn.Linear(num_heads * self.d_head, d_model, bias=False)

    def forward(self, x):
        B, L, _ = x.shape
        Q = self.W_q(x).view(B, L, self.h, self.d_head).transpose(1, 2)
        K = self.W_k(x).view(B, L, self.G, self.d_head).transpose(1, 2)
        V = self.W_v(x).view(B, L, self.G, self.d_head).transpose(1, 2)
        K = K.repeat_interleave(self.qpg, dim=1)  # expand G -> h
        V = V.repeat_interleave(self.qpg, dim=1)
        attn = F.softmax(Q @ K.transpose(-2, -1) / math.sqrt(self.d_head), dim=-1)
        out = (attn @ V).transpose(1, 2).reshape(B, L, -1)
        return self.W_o(out)

for G in [1, 2, 4, 8]:  # G=1: MQA, G=8: MHA (h=8)
    m = GroupedQueryAttention(d_model=256, num_heads=8, num_kv_groups=G)
    x = torch.randn(2, 16, 256)
    out = m(x)
    kv = sum(p.numel() for n, p in m.named_parameters() if '_k' in n or '_v' in n)
    print(f'G={G}: out={out.shape}, KV params={kv}, KV cache ratio={8//G}x vs MHA')
```

## Converting MHA to GQA by Mean-Pooling

LLaMA 2 34B and 70B were originally trained as MHA models and then converted to GQA before release. The conversion: reshape the K weight from (h × d_head, d_model) into (G, h/G, d_head, d_model), mean-pool across the h/G heads within each group, yielding (G, d_head, d_model). This minimum-distortion approximation is followed by a brief fine-tuning phase. Ainslie et al. showed that uptrained GQA matches scratch-trained GQA quality after sufficient fine-tuning steps.

```python
import torch

def mha_to_gqa(W_k, W_v, num_heads, num_kv_groups, d_head):
    """Convert MHA K,V weight matrices to GQA by mean-pooling within groups.
    W_k shape: (num_heads * d_head, d_model)
    Returns:   (num_kv_groups * d_head, d_model)
    """
    qpg = num_heads // num_kv_groups
    d_model = W_k.shape[1]
    Wk = W_k.view(num_kv_groups, qpg, d_head, d_model).mean(dim=1)
    Wv = W_v.view(num_kv_groups, qpg, d_head, d_model).mean(dim=1)
    return Wk.reshape(num_kv_groups * d_head, d_model), Wv.reshape(num_kv_groups * d_head, d_model)

torch.manual_seed(0)
h, G, d_head, d_model = 8, 2, 32, 256
Wk_mha = torch.randn(h * d_head, d_model)
Wv_mha = torch.randn(h * d_head, d_model)
Wk_gqa, Wv_gqa = mha_to_gqa(Wk_mha, Wv_mha, h, G, d_head)
print(f'MHA W_K: {Wk_mha.shape}  -> GQA W_K: {Wk_gqa.shape}')
print(f'MHA KV params: {Wk_mha.numel()*2}  -> GQA: {Wk_gqa.numel()*2}  ({h//G}x reduction)')
print(f'LLaMA 2 70B: h=64, G=8 -> 8x KV reduction via this mean-pool + fine-tune.')
print('Cosine sim of first group (original vs pooled):')
orig_group0 = Wk_mha.view(G, h//G, d_head, d_model)[0].mean(0)  # expected pooled
print(f'  {torch.nn.functional.cosine_similarity(orig_group0.flatten(), Wk_gqa[:d_head].flatten(), dim=0).item():.6f}')
```

## GQA KV Cache at Inference

The KV cache stores G × d_head × 2 values per token per layer (vs h × d_head × 2 for MHA). At each generation step: project Q to h heads, project K and V to G groups, append new K,V slices to the cache, expand the full cache from G to h via repeat_interleave, then compute attention over the cached sequence. The cache growth per token is G/h of MHA — for G=8, h=64, that is 8× less memory allocated per new token.

```python
import torch
import torch.nn.functional as F
import math

class GQAKVCache:
    def __init__(self, max_len, G, d_head):
        self.G, self.d, self.t = G, d_head, 0
        self.K = torch.zeros(1, G, max_len, d_head)
        self.V = torch.zeros(1, G, max_len, d_head)

    def step(self, q, k, v):
        """q: (1,h,1,d)  k/v: (1,G,1,d). Returns (1,h,1,d)."""
        self.K[:, :, self.t:self.t+1] = k
        self.V[:, :, self.t:self.t+1] = v
        self.t += 1
        Kc = self.K[:, :, :self.t]  # (1,G,t,d)
        Vc = self.V[:, :, :self.t]
        h = q.shape[1]
        Kc = Kc.repeat_interleave(h // self.G, dim=1)
        Vc = Vc.repeat_interleave(h // self.G, dim=1)
        scores = q @ Kc.transpose(-2, -1) / math.sqrt(self.d)
        return F.softmax(scores, dim=-1) @ Vc

h, G, d, max_len = 8, 2, 32, 128
cache = GQAKVCache(max_len, G, d)
for _ in range(20):
    out = cache.step(torch.randn(1,h,1,d), torch.randn(1,G,1,d), torch.randn(1,G,1,d))
print(f'After {cache.t} steps: cache K = {cache.K[:,:,:cache.t].shape}')
for g, label in [(h,'MHA'), (G,'GQA')]:
    kb = g * d * max_len * 2 * 2 / 1024  # K+V, float16
    print(f'{label} (G={g}): {kb:.1f} KB/layer  ratio={h//g}x')
```

## Benchmark: MHA vs GQA vs MQA

The throughput benefit of GQA at inference is dominated by KV cache size. When the cache fits in HBM rather than DRAM, generation can be 2–4× faster due to reduced memory bandwidth pressure. During training, smaller W_K and W_V matrices reduce the KV projection FLOPs by G/h, but this is usually a small fraction of total compute. The quality gap between MHA and GQA (G=8) is <0.5 perplexity points on language modelling benchmarks; MQA (G=1) shows 1–3% degradation on long-document QA.

```python
import torch
import torch.nn.functional as F
import math
import time

def gqa_attn(Q, K, V, G):
    """Q: (B,h,L,d), K/V: (B,G,L,d). Returns (B,h,L,d)."""
    h = Q.shape[1]
    K = K.repeat_interleave(h // G, dim=1)
    V = V.repeat_interleave(h // G, dim=1)
    return F.softmax(Q @ K.transpose(-2,-1) / math.sqrt(Q.shape[-1]), dim=-1) @ V

torch.manual_seed(0)
B, L, h, d = 2, 256, 8, 64
print(f"{'Method':>8} {'G':>4} {'KV cache KB':>13} {'ms/fwd':>9} {'KV ratio':>10}")
for G in [h, 4, 2, 1]:
    Q = torch.randn(B, h, L, d)
    K = torch.randn(B, G, L, d)
    V = torch.randn(B, G, L, d)
    runs = 30
    t0 = time.perf_counter()
    for _ in range(runs):
        _ = gqa_attn(Q, K, V, G)
    ms = (time.perf_counter() - t0) / runs * 1000
    kv_kb = G * d * L * 2 * 2 / 1024  # K+V, float16
    label = 'MHA' if G == h else ('MQA' if G == 1 else f'GQA-{G}')
    print(f'{label:>8} {G:>4} {kv_kb:>13.1f} {ms:>9.2f} {h//G:>9}x')
```

| Method | G value | KV heads | Quality vs MHA | KV cache ratio | Used in LLMs | MHA conversion |
| --- | --- | --- | --- | --- | --- | --- |
| MHA | G = h | h (all unique) | Baseline (best) | 1× (largest) | GPT-2, BERT, early LLaMA | N/A |
| MQA | G = 1 | 1 (all shared) | −1–3% on long-doc QA | h× smaller | PaLM, Falcon-7B | Mean-pool all h heads to 1 |
| GQA | 1 < G < h | G (grouped) | ≈MHA with G ≥ 4 | h/G× smaller | LLaMA 2/3, Mistral, Gemma, Qwen | Mean-pool h/G heads per group |

## Quality and Efficiency Trade-offs

Ainslie et al. benchmarked GQA on T5-Large and T5-XXL. With G = h/8, GQA matches MHA perplexity on language modelling and stays within 0.5% on summarisation. The KV cache is h/G× smaller: for LLaMA 70B (h=64, G=8), that is an 8× reduction. Batch throughput at long-context inference increases 2–3× because the smaller cache lets more sequences fit in GPU memory simultaneously, raising batch size and GPU utilisation.

> **GQA Design Rule**: Set G so that h/G is a power of 2 and G divides h evenly. LLaMA 2/3 use G=8 for large models (h=64 for 70B → 8 KV heads). Mistral 7B uses G=8 with h=32 → 4 KV heads. Smaller models may use G=4 or G=2. MQA (G=1) is only recommended when memory is severely constrained and quality degradation is acceptable.

## Models and Configurations Using GQA

GQA has become the de facto standard for large transformer models since 2023. LLaMA 2 introduced it for 34B and 70B variants (7B and 13B retained MHA). LLaMA 3 uses GQA across all sizes including 8B. Mistral 7B, Mixtral MoE, Gemma, Gemma 2, and Qwen2 all adopt GQA. The consistent adoption demonstrates that G=8 is a well-validated configuration balancing quality and inference efficiency.

- LLaMA 2: h=32, G=8 for 34B; h=64, G=8 for 70B — converted from MHA via mean-pool + fine-tune.
- LLaMA 3: all sizes use GQA — 8B: h=32, G=8; 70B: h=64, G=8.
- Mistral 7B: h=32, G=8 → 4 KV heads; combined with sliding window attention.
- Gemma 2: G=1 (MQA) for 2B; G=4 for 9B and 27B variants.
- Qwen2: GQA across all sizes; 72B uses h=64, G=8.
- Falcon 40B+: uses MQA (G=1); earlier Falcon models used full MHA.

---

