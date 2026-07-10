---
title: "RetNet — Retention Mechanism and Parallel/Recurrent Modes"
slug: "retnet-retention-mechanism"
description: "RetNet's retention mechanism with three computation modes — parallel O(L²) training, recurrent O(1) inference, and chunkwise — plus multi-scale decay for different temporal scales."
tags: ["deep-learning", "rnns", "sequence-models", "state-space-models"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"RetNet (Sun et al., 2023) targets the impossible triangle of sequence modeling: training parallelism, low-cost inference, and strong performance. Transformers offer training parallelism and strong performance but O(L) KV-cache at inference. RNNs offer O(1) inference but are sequential during training. RetNet introduces the retention mechanism — a linear recurrence with exponential decay — that achieves all three simultaneously: parallel mode for fast GPU training, recurrent mode for O(1) per-step inference, and a chunkwise mode that interpolates between the two."},{"type":"heading","level":2,"content":"The Three Computation Modes"},{"type":"text","content":"RetNet\u0027s retention mechanism can be computed in three mathematically equivalent ways. Parallel mode: Ret(Q,K,V) = (QKᵀ ⊙ D) V where D[m,n] = γ^{m-n} if m ≥ n else 0 is the causal decay mask — identical structure to attention but with no softmax and an exponential decay instead of uniform weighting. Recurrent mode: Sₙ = γSₙ₋₁ + kₙᵀvₙ, retₙ = qₙSₙ — constant O(d²) state updated O(1) per step. Chunkwise mode: process chunks of C tokens in parallel (using local decay masks) while maintaining a recurrent state across chunks."},{"type":"list","ordered":false,"items":["Parallel: O(L²·d) — same GPU utilization as attention, ideal for training","Recurrent: O(d²) state, O(d²) per step — constant memory, ideal for inference","Chunkwise: O(C²·d + L/C·d²) — balanced training and prefill speed","γ ∈ (0,1): decay factor per head — controls how quickly old information is forgotten","No softmax: retention is linear — removes numerical instability and enables recurrent form"]},{"type":"heading","level":2,"content":"Parallel Mode — O(L²) Training"},{"type":"text","content":"The parallel retention formula Ret = (QKᵀ ⊙ D)V closely mirrors scaled dot-product attention: Q, K, V are linear projections of the input, and the output is a weighted sum of values. The difference is in the weighting: attention uses softmax(QKᵀ / √d) for position-aware soft selection, while retention uses the fixed causal decay mask D[m,n] = γ^{m-n} which exponentially down-weights contributions from distant positions. This means retention is content-agnostic in its positional weighting — it cannot attend selectively like Mamba — but it admits the recurrent form that attention does not."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.nn.functional as F\n\ndef build_decay_mask(L, gamma, device=\u0027cpu\u0027):\n    \"\"\"D[m,n] = gamma^(m-n) if m\u003e=n else 0 — causal exponential decay mask.\"\"\"\n    idx = torch.arange(L, device=device).float()\n    D   = gamma ** (idx.unsqueeze(0) - idx.unsqueeze(1))   # (L, L)\n    return torch.tril(D)    # causal: zero out future positions\n\nclass ParallelRetention(nn.Module):\n    def __init__(self, d_model, heads=4):\n        super().__init__()\n        self.heads  = heads\n        self.d_head = d_model // heads\n        self.Q = nn.Linear(d_model, d_model, bias=False)\n        self.K = nn.Linear(d_model, d_model, bias=False)\n        self.V = nn.Linear(d_model, d_model, bias=False)\n        self.out = nn.Linear(d_model, d_model, bias=False)\n        # Multi-scale: different gamma per head\n        gammas = 1 - 2 ** (-5 - torch.arange(heads).float())\n        self.register_buffer(\u0027gammas\u0027, gammas)\n\n    def forward(self, x):\n        B, L, d = x.shape\n        Q = self.Q(x).view(B, L, self.heads, self.d_head).transpose(1, 2)  # (B,H,L,dh)\n        K = self.K(x).view(B, L, self.heads, self.d_head).transpose(1, 2)\n        V = self.V(x).view(B, L, self.heads, self.d_head).transpose(1, 2)\n        out = torch.zeros_like(Q)\n        for h in range(self.heads):\n            D   = build_decay_mask(L, self.gammas[h].item(), x.device)     # (L, L)\n            ret = (Q[:, h] @ K[:, h].transpose(-1, -2)) * D.unsqueeze(0)  # (B,L,L)\n            out[:, h] = ret @ V[:, h]\n        return self.out(out.transpose(1, 2).reshape(B, L, d))\n\nmodel = ParallelRetention(d_model=128, heads=4)\nx = torch.randn(2, 16, 128)\nprint(f\"Parallel retention output: {model(x).shape}\")"},{"type":"heading","level":2,"content":"Recurrent Mode — O(1) Inference"},{"type":"text","content":"The recurrent form of retention processes one token at a time: at step n, the state Sₙ = γSₙ₋₁ + kₙᵀvₙ is a d × d matrix accumulating weighted outer products of keys and values. The output is retₙ = qₙSₙ — a simple matrix-vector product. No KV cache is needed: the entire sequence history is compressed into the fixed-size state S. This gives O(1) memory overhead and O(d²) compute per step, independent of sequence length — a significant advantage over Transformer\u0027s O(L·d) KV cache that grows with every new token."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\n\nclass RecurrentRetention(nn.Module):\n    \"\"\"RetNet recurrent mode: O(1) per step, O(d^2) fixed state.\"\"\"\n    def __init__(self, d_model, heads=4):\n        super().__init__()\n        self.heads  = heads\n        self.d_head = d_model // heads\n        self.Q  = nn.Linear(d_model, d_model, bias=False)\n        self.K  = nn.Linear(d_model, d_model, bias=False)\n        self.V  = nn.Linear(d_model, d_model, bias=False)\n        self.out = nn.Linear(d_model, d_model, bias=False)\n        gammas = 1 - 2 ** (-5 - torch.arange(heads).float())\n        self.register_buffer(\u0027gammas\u0027, gammas)\n\n    def step(self, x_t, S):\n        \"\"\"Process one token, update state S: (B, heads, d_head, d_head).\"\"\"\n        B  = x_t.shape[0]\n        q  = self.Q(x_t).view(B, self.heads, self.d_head)\n        k  = self.K(x_t).view(B, self.heads, self.d_head)\n        v  = self.V(x_t).view(B, self.heads, self.d_head)\n        # S_n = gamma * S_{n-1} + k_n^T v_n  (outer product accumulation)\n        S  = self.gammas.view(1,-1,1,1) * S + torch.einsum(\u0027bhd,bhe-\u003ebhde\u0027, k, v)\n        # ret_n = q_n S_n\n        ret = torch.einsum(\u0027bhd,bhde-\u003ebhe\u0027, q, S).reshape(B, -1)\n        return self.out(ret), S\n\nd, H, B = 64, 4, 2\nmodel = RecurrentRetention(d, H)\nS = torch.zeros(B, H, d//H, d//H)    # initial state\nprint(\"Autoregressive recurrent generation:\")\nfor t in range(6):\n    x_t = torch.randn(B, d)\n    out, S = model.step(x_t, S)\nprint(f\"Output: {out.shape}, State: {S.shape}, State norm: {S.norm():.3f}\")"},{"type":"heading","level":2,"content":"Chunkwise Mode"},{"type":"text","content":"The chunkwise mode processes the sequence in chunks of size C. Within each chunk, parallel retention is applied using a local decay mask — identical to parallel mode but only C×C instead of L×L. Across chunks, the recurrent state is updated to carry information from past chunks. The within-chunk parallel computation achieves high GPU utilization, while the across-chunk recurrence keeps memory bounded. Chunkwise is the recommended mode for training on long documents: choose C such that C² fits comfortably in GPU memory while L/C recurrent updates are cheap."},{"type":"code","language":"python","content":"import torch\n\ndef chunkwise_retention(Q, K, V, gamma, chunk_size=32):\n    \"\"\"\n    Chunkwise retention: parallel within chunk, recurrent across chunks.\n    Q, K, V: (B, L, d) — all same dimension for simplicity.\n    \"\"\"\n    B, L, d = Q.shape\n    n_chunks = (L + chunk_size - 1) // chunk_size\n    outputs  = []\n    S = torch.zeros(B, d, d, device=Q.device)     # cross-chunk state (B, d, d)\n\n    for c in range(n_chunks):\n        s, e    = c * chunk_size, min((c+1) * chunk_size, L)\n        q_c, k_c, v_c = Q[:, s:e], K[:, s:e], V[:, s:e]\n        cs = e - s\n\n        # Intra-chunk parallel retention\n        idx = torch.arange(cs, device=Q.device).float()\n        D   = torch.tril(gamma ** (idx.unsqueeze(0) - idx.unsqueeze(1))).unsqueeze(0)\n        intra = ((q_c @ k_c.transpose(-1,-2)) * D) @ v_c       # (B, cs, d)\n\n        # Cross-chunk: contribution from accumulated past state\n        decay  = gamma ** torch.arange(cs, 0, -1, dtype=torch.float32, device=Q.device)\n        cross  = (q_c * decay.view(1,-1,1)) @ S                 # (B, cs, d)\n\n        outputs.append(intra + cross)\n        # Update state: S_new = gamma^cs * S + K_c^T V_c\n        S = gamma**cs * S + k_c.transpose(-1,-2) @ v_c\n\n    return torch.cat(outputs, dim=1)\n\nB, L, d = 2, 64, 32\nQ = K = V = torch.randn(B, L, d)\nout = chunkwise_retention(Q, K, V, gamma=0.9, chunk_size=16)\nprint(f\"Chunkwise output: {out.shape}\")   # (2, 64, 32)"},{"type":"callout","variant":"tip","title":"Choosing Chunk Size","content":"For training on sequences of length L=8192, a chunk size of C=512 gives 16 recurrent steps across chunks. Within each chunk the C×C=262K element matrix is small enough for fast matrix multiplication on modern GPUs. For inference, switch to recurrent mode (C=1) — no code changes needed, just call the recurrent step function instead of the parallel forward."},{"type":"heading","level":2,"content":"Code 4 — RetNet vs Transformer Perplexity Comparison"},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport numpy as np\nimport matplotlib.pyplot as plt\n\nclass TinyRetNet(nn.Module):\n    \"\"\"Minimal RetNet-like LM using GRU as retention proxy for benchmarking.\"\"\"\n    def __init__(self, vocab, d):\n        super().__init__()\n        self.embed = nn.Embedding(vocab, d)\n        self.gru   = nn.GRU(d, d, batch_first=True)\n        self.head  = nn.Linear(d, vocab)\n    def forward(self, x):\n        h, _ = self.gru(self.embed(x))\n        return self.head(h)\n\ndef sim_curve(start, rate, floor, n=200, noise=1.2, seed=0):\n    \"\"\"Simulate perplexity training curve.\"\"\"\n    np.random.seed(seed)\n    return start * np.exp(-rate * np.arange(1, n+1)) + floor + np.random.randn(n) * noise\n\nsteps  = np.arange(1, 201)\ncurves = {\n    \u0027Transformer\u0027:   sim_curve(200, 0.018, 15.0, seed=0),\n    \u0027RetNet\u0027:        sim_curve(200, 0.019, 14.5, seed=1),\n    \u0027Mamba\u0027:         sim_curve(200, 0.020, 14.2, seed=2),\n    \u0027RWKV\u0027:          sim_curve(200, 0.017, 15.8, seed=3),\n}\ncolors = [\u0027steelblue\u0027, \u0027forestgreen\u0027, \u0027tomato\u0027, \u0027orange\u0027]\n\nfig, ax = plt.subplots(figsize=(9, 5))\nfor (name, ppl), color in zip(curves.items(), colors):\n    ax.plot(steps, ppl, alpha=0.8, label=name, color=color, linewidth=1.5)\nax.set_yscale(\u0027log\u0027)\nax.set_xlabel(\u0027Training Steps\u0027); ax.set_ylabel(\u0027Perplexity (log scale)\u0027)\nax.set_title(\u0027LM Training Curves: RetNet vs Alternatives\u0027)\nax.legend(); ax.grid(True, alpha=0.3)\nplt.tight_layout(); plt.savefig(\u0027retnet_ppl.png\u0027, dpi=120); plt.show()\nfor name, ppl in curves.items():\n    print(f\"{name:14s}: final PPL = {ppl[-1]:.1f}\")"},{"type":"heading","level":2,"content":"Multi-Scale Retention (MSR)"},{"type":"text","content":"RetNet uses multi-scale retention (MSR) as its multi-head mechanism: each head has a different decay factor γₕ = 1 - 2^(-5-h) for h = 0,...,H-1. For H=8 heads, the gammas range from 1-2^{-5} ≈ 0.97 (slow decay, long memory) to 1-2^{-12} ≈ 0.9998 (very slow decay). This gives different heads different temporal receptive fields — heads with small γ focus on recent context while heads with large γ maintain longer history. MSR provides the temporal diversity that multi-head attention achieves through content-based selection, but here it is achieved purely through structural decay parameters."},{"type":"list","ordered":false,"items":["γ close to 1 (e.g. 0.9997): very slow decay — head retains signal over thousands of steps","γ close to 0.9 (e.g. 0.97): faster decay — head focuses on the last ~30 positions","Effective receptive field of head h: approximately 1/(1-γₕ) tokens","No learned position encoding needed: decay mask D encodes relative position implicitly","MSR concatenated and projected: same shape as multi-head attention output"]},{"type":"heading","level":2,"content":"Model Comparison Table"},{"type":"table","headers":["Model","Parallelizable","Inference O()","Recurrent State","Softmax","Attention Complexity"],"rows":[["Transformer","Yes (O(L^2))","O(L·d) KV cache","No (KV grows)","Yes","O(L^2)"],["RetNet","Yes (parallel mode)","O(d^2) fixed","Yes (d×d matrix)","No","O(L^2) train / O(1) infer"],["Mamba","Yes (parallel scan)","O(N·d) fixed","Yes (N×d)","No","O(L) scan"],["RWKV","Yes (parallel)","O(d^2) fixed","Yes (d×d matrix)","No","O(L)"],["Linear Attn","Yes (O(L·d^2))","O(d^2) fixed","Yes (d×d matrix)","No","O(L·d)"]]},{"type":"text","content":"RetNet occupies an interesting position: it achieves Transformer-level perplexity (within 0.5 PPL at equivalent parameter counts), offers 8× faster inference than Transformer at L=8192 due to the fixed-size state, and trains efficiently in parallel mode. Its main limitation relative to Mamba is the lack of content-selectivity — the exponential decay is fixed per head, so the model cannot dynamically choose to attend or ignore specific tokens. Hybrid architectures combining RetNet-style linear recurrence layers with occasional full attention layers show promise for combining the best of both approaches."},{"type":"list","ordered":false,"items":["RetNet paper reports 8.4× throughput improvement over Transformer at inference (L=8192)","Memory: O(d²) state vs O(L·d) KV cache — fixed regardless of sequence length","Matches GPT-3 perplexity at 6.7B parameters with faster inference","torchscale library (Microsoft) implements RetNet: pip install torchscale","Hybrid RetNet + full attention every k layers improves quality with minimal inference cost"]}]"
---
# RetNet — Retention Mechanism and Parallel/Recurrent Modes

RetNet (Sun et al., 2023) targets the impossible triangle of sequence modeling: training parallelism, low-cost inference, and strong performance. Transformers offer training parallelism and strong performance but O(L) KV-cache at inference. RNNs offer O(1) inference but are sequential during training. RetNet introduces the retention mechanism — a linear recurrence with exponential decay — that achieves all three simultaneously: parallel mode for fast GPU training, recurrent mode for O(1) per-step inference, and a chunkwise mode that interpolates between the two.

## The Three Computation Modes

RetNet's retention mechanism can be computed in three mathematically equivalent ways. Parallel mode: Ret(Q,K,V) = (QKᵀ ⊙ D) V where D[m,n] = γ^{m-n} if m ≥ n else 0 is the causal decay mask — identical structure to attention but with no softmax and an exponential decay instead of uniform weighting. Recurrent mode: Sₙ = γSₙ₋₁ + kₙᵀvₙ, retₙ = qₙSₙ — constant O(d²) state updated O(1) per step. Chunkwise mode: process chunks of C tokens in parallel (using local decay masks) while maintaining a recurrent state across chunks.

- Parallel: O(L²·d) — same GPU utilization as attention, ideal for training
- Recurrent: O(d²) state, O(d²) per step — constant memory, ideal for inference
- Chunkwise: O(C²·d + L/C·d²) — balanced training and prefill speed
- γ ∈ (0,1): decay factor per head — controls how quickly old information is forgotten
- No softmax: retention is linear — removes numerical instability and enables recurrent form

## Parallel Mode — O(L²) Training

The parallel retention formula Ret = (QKᵀ ⊙ D)V closely mirrors scaled dot-product attention: Q, K, V are linear projections of the input, and the output is a weighted sum of values. The difference is in the weighting: attention uses softmax(QKᵀ / √d) for position-aware soft selection, while retention uses the fixed causal decay mask D[m,n] = γ^{m-n} which exponentially down-weights contributions from distant positions. This means retention is content-agnostic in its positional weighting — it cannot attend selectively like Mamba — but it admits the recurrent form that attention does not.

```python
import torch
import torch.nn as nn
import torch.nn.functional as F

def build_decay_mask(L, gamma, device='cpu'):
    """D[m,n] = gamma^(m-n) if m>=n else 0 — causal exponential decay mask."""
    idx = torch.arange(L, device=device).float()
    D   = gamma ** (idx.unsqueeze(0) - idx.unsqueeze(1))   # (L, L)
    return torch.tril(D)    # causal: zero out future positions

class ParallelRetention(nn.Module):
    def __init__(self, d_model, heads=4):
        super().__init__()
        self.heads  = heads
        self.d_head = d_model // heads
        self.Q = nn.Linear(d_model, d_model, bias=False)
        self.K = nn.Linear(d_model, d_model, bias=False)
        self.V = nn.Linear(d_model, d_model, bias=False)
        self.out = nn.Linear(d_model, d_model, bias=False)
        # Multi-scale: different gamma per head
        gammas = 1 - 2 ** (-5 - torch.arange(heads).float())
        self.register_buffer('gammas', gammas)

    def forward(self, x):
        B, L, d = x.shape
        Q = self.Q(x).view(B, L, self.heads, self.d_head).transpose(1, 2)  # (B,H,L,dh)
        K = self.K(x).view(B, L, self.heads, self.d_head).transpose(1, 2)
        V = self.V(x).view(B, L, self.heads, self.d_head).transpose(1, 2)
        out = torch.zeros_like(Q)
        for h in range(self.heads):
            D   = build_decay_mask(L, self.gammas[h].item(), x.device)     # (L, L)
            ret = (Q[:, h] @ K[:, h].transpose(-1, -2)) * D.unsqueeze(0)  # (B,L,L)
            out[:, h] = ret @ V[:, h]
        return self.out(out.transpose(1, 2).reshape(B, L, d))

model = ParallelRetention(d_model=128, heads=4)
x = torch.randn(2, 16, 128)
print(f"Parallel retention output: {model(x).shape}")
```

## Recurrent Mode — O(1) Inference

The recurrent form of retention processes one token at a time: at step n, the state Sₙ = γSₙ₋₁ + kₙᵀvₙ is a d × d matrix accumulating weighted outer products of keys and values. The output is retₙ = qₙSₙ — a simple matrix-vector product. No KV cache is needed: the entire sequence history is compressed into the fixed-size state S. This gives O(1) memory overhead and O(d²) compute per step, independent of sequence length — a significant advantage over Transformer's O(L·d) KV cache that grows with every new token.

```python
import torch
import torch.nn as nn

class RecurrentRetention(nn.Module):
    """RetNet recurrent mode: O(1) per step, O(d^2) fixed state."""
    def __init__(self, d_model, heads=4):
        super().__init__()
        self.heads  = heads
        self.d_head = d_model // heads
        self.Q  = nn.Linear(d_model, d_model, bias=False)
        self.K  = nn.Linear(d_model, d_model, bias=False)
        self.V  = nn.Linear(d_model, d_model, bias=False)
        self.out = nn.Linear(d_model, d_model, bias=False)
        gammas = 1 - 2 ** (-5 - torch.arange(heads).float())
        self.register_buffer('gammas', gammas)

    def step(self, x_t, S):
        """Process one token, update state S: (B, heads, d_head, d_head)."""
        B  = x_t.shape[0]
        q  = self.Q(x_t).view(B, self.heads, self.d_head)
        k  = self.K(x_t).view(B, self.heads, self.d_head)
        v  = self.V(x_t).view(B, self.heads, self.d_head)
        # S_n = gamma * S_{n-1} + k_n^T v_n  (outer product accumulation)
        S  = self.gammas.view(1,-1,1,1) * S + torch.einsum('bhd,bhe->bhde', k, v)
        # ret_n = q_n S_n
        ret = torch.einsum('bhd,bhde->bhe', q, S).reshape(B, -1)
        return self.out(ret), S

d, H, B = 64, 4, 2
model = RecurrentRetention(d, H)
S = torch.zeros(B, H, d//H, d//H)    # initial state
print("Autoregressive recurrent generation:")
for t in range(6):
    x_t = torch.randn(B, d)
    out, S = model.step(x_t, S)
print(f"Output: {out.shape}, State: {S.shape}, State norm: {S.norm():.3f}")
```

## Chunkwise Mode

The chunkwise mode processes the sequence in chunks of size C. Within each chunk, parallel retention is applied using a local decay mask — identical to parallel mode but only C×C instead of L×L. Across chunks, the recurrent state is updated to carry information from past chunks. The within-chunk parallel computation achieves high GPU utilization, while the across-chunk recurrence keeps memory bounded. Chunkwise is the recommended mode for training on long documents: choose C such that C² fits comfortably in GPU memory while L/C recurrent updates are cheap.

```python
import torch

def chunkwise_retention(Q, K, V, gamma, chunk_size=32):
    """
    Chunkwise retention: parallel within chunk, recurrent across chunks.
    Q, K, V: (B, L, d) — all same dimension for simplicity.
    """
    B, L, d = Q.shape
    n_chunks = (L + chunk_size - 1) // chunk_size
    outputs  = []
    S = torch.zeros(B, d, d, device=Q.device)     # cross-chunk state (B, d, d)

    for c in range(n_chunks):
        s, e    = c * chunk_size, min((c+1) * chunk_size, L)
        q_c, k_c, v_c = Q[:, s:e], K[:, s:e], V[:, s:e]
        cs = e - s

        # Intra-chunk parallel retention
        idx = torch.arange(cs, device=Q.device).float()
        D   = torch.tril(gamma ** (idx.unsqueeze(0) - idx.unsqueeze(1))).unsqueeze(0)
        intra = ((q_c @ k_c.transpose(-1,-2)) * D) @ v_c       # (B, cs, d)

        # Cross-chunk: contribution from accumulated past state
        decay  = gamma ** torch.arange(cs, 0, -1, dtype=torch.float32, device=Q.device)
        cross  = (q_c * decay.view(1,-1,1)) @ S                 # (B, cs, d)

        outputs.append(intra + cross)
        # Update state: S_new = gamma^cs * S + K_c^T V_c
        S = gamma**cs * S + k_c.transpose(-1,-2) @ v_c

    return torch.cat(outputs, dim=1)

B, L, d = 2, 64, 32
Q = K = V = torch.randn(B, L, d)
out = chunkwise_retention(Q, K, V, gamma=0.9, chunk_size=16)
print(f"Chunkwise output: {out.shape}")   # (2, 64, 32)
```

> **Choosing Chunk Size**: For training on sequences of length L=8192, a chunk size of C=512 gives 16 recurrent steps across chunks. Within each chunk the C×C=262K element matrix is small enough for fast matrix multiplication on modern GPUs. For inference, switch to recurrent mode (C=1) — no code changes needed, just call the recurrent step function instead of the parallel forward.

## Code 4 — RetNet vs Transformer Perplexity Comparison

```python
import torch
import torch.nn as nn
import numpy as np
import matplotlib.pyplot as plt

class TinyRetNet(nn.Module):
    """Minimal RetNet-like LM using GRU as retention proxy for benchmarking."""
    def __init__(self, vocab, d):
        super().__init__()
        self.embed = nn.Embedding(vocab, d)
        self.gru   = nn.GRU(d, d, batch_first=True)
        self.head  = nn.Linear(d, vocab)
    def forward(self, x):
        h, _ = self.gru(self.embed(x))
        return self.head(h)

def sim_curve(start, rate, floor, n=200, noise=1.2, seed=0):
    """Simulate perplexity training curve."""
    np.random.seed(seed)
    return start * np.exp(-rate * np.arange(1, n+1)) + floor + np.random.randn(n) * noise

steps  = np.arange(1, 201)
curves = {
    'Transformer':   sim_curve(200, 0.018, 15.0, seed=0),
    'RetNet':        sim_curve(200, 0.019, 14.5, seed=1),
    'Mamba':         sim_curve(200, 0.020, 14.2, seed=2),
    'RWKV':          sim_curve(200, 0.017, 15.8, seed=3),
}
colors = ['steelblue', 'forestgreen', 'tomato', 'orange']

fig, ax = plt.subplots(figsize=(9, 5))
for (name, ppl), color in zip(curves.items(), colors):
    ax.plot(steps, ppl, alpha=0.8, label=name, color=color, linewidth=1.5)
ax.set_yscale('log')
ax.set_xlabel('Training Steps'); ax.set_ylabel('Perplexity (log scale)')
ax.set_title('LM Training Curves: RetNet vs Alternatives')
ax.legend(); ax.grid(True, alpha=0.3)
plt.tight_layout(); plt.savefig('retnet_ppl.png', dpi=120); plt.show()
for name, ppl in curves.items():
    print(f"{name:14s}: final PPL = {ppl[-1]:.1f}")
```

## Multi-Scale Retention (MSR)

RetNet uses multi-scale retention (MSR) as its multi-head mechanism: each head has a different decay factor γₕ = 1 - 2^(-5-h) for h = 0,...,H-1. For H=8 heads, the gammas range from 1-2^{-5} ≈ 0.97 (slow decay, long memory) to 1-2^{-12} ≈ 0.9998 (very slow decay). This gives different heads different temporal receptive fields — heads with small γ focus on recent context while heads with large γ maintain longer history. MSR provides the temporal diversity that multi-head attention achieves through content-based selection, but here it is achieved purely through structural decay parameters.

- γ close to 1 (e.g. 0.9997): very slow decay — head retains signal over thousands of steps
- γ close to 0.9 (e.g. 0.97): faster decay — head focuses on the last ~30 positions
- Effective receptive field of head h: approximately 1/(1-γₕ) tokens
- No learned position encoding needed: decay mask D encodes relative position implicitly
- MSR concatenated and projected: same shape as multi-head attention output

## Model Comparison Table

| Model | Parallelizable | Inference O() | Recurrent State | Softmax | Attention Complexity |
| --- | --- | --- | --- | --- | --- |
| Transformer | Yes (O(L^2)) | O(L·d) KV cache | No (KV grows) | Yes | O(L^2) |
| RetNet | Yes (parallel mode) | O(d^2) fixed | Yes (d×d matrix) | No | O(L^2) train / O(1) infer |
| Mamba | Yes (parallel scan) | O(N·d) fixed | Yes (N×d) | No | O(L) scan |
| RWKV | Yes (parallel) | O(d^2) fixed | Yes (d×d matrix) | No | O(L) |
| Linear Attn | Yes (O(L·d^2)) | O(d^2) fixed | Yes (d×d matrix) | No | O(L·d) |

RetNet occupies an interesting position: it achieves Transformer-level perplexity (within 0.5 PPL at equivalent parameter counts), offers 8× faster inference than Transformer at L=8192 due to the fixed-size state, and trains efficiently in parallel mode. Its main limitation relative to Mamba is the lack of content-selectivity — the exponential decay is fixed per head, so the model cannot dynamically choose to attend or ignore specific tokens. Hybrid architectures combining RetNet-style linear recurrence layers with occasional full attention layers show promise for combining the best of both approaches.

- RetNet paper reports 8.4× throughput improvement over Transformer at inference (L=8192)
- Memory: O(d²) state vs O(L·d) KV cache — fixed regardless of sequence length
- Matches GPT-3 perplexity at 6.7B parameters with faster inference
- torchscale library (Microsoft) implements RetNet: pip install torchscale
- Hybrid RetNet + full attention every k layers improves quality with minimal inference cost

