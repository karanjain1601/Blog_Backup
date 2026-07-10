---
title: "Mamba — Selective State Space and Hardware-Efficient Design"
slug: "mamba-selective-ssm"
description: "Mamba's selective state space models — input-dependent B, C, and delta transitions, hardware-efficient parallel scan, and the Mamba block that scales to billions of parameters."
tags: ["deep-learning", "rnns", "sequence-models", "state-space-models"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"S4 and its variants showed that structured SSMs can model long-range dependencies efficiently, but they share a fundamental limitation: the state transition matrices Ā and B̄ are the same for every position in the sequence — they are content-independent. Given the input \u0027The cat sat on the mat\u0027, a standard SSM applies identical transition dynamics regardless of whether it is processing \u0027cat\u0027 or \u0027mat\u0027. This means the model cannot selectively focus on or ignore specific inputs based on their content, a capability crucial for language modeling. Mamba (Gu and Dao, 2023) resolves this by making B, C, and the discretization step Δ functions of the input."},{"type":"heading","level":2,"content":"The Limitation of Fixed State Transitions"},{"type":"text","content":"In S4, the convolution kernel K is fixed (or varies slowly through gradient descent on shared parameters A, B, C). This makes S4 a linear time-invariant (LTI) system — it cannot differentiate between tokens based on their content. Empirically, LTI SSMs underperform Transformers on language modeling tasks precisely because language requires selective attention: a pronoun \u0027it\u0027 should attend to its antecedent noun, not every preceding word equally. The solution is to make the SSM parameters input-dependent — turning the LTI system into a non-linear selective system."},{"type":"list","ordered":false,"items":["S4 A, B, C are fixed across all positions — LTI system, cannot select content","Language requires selective recall: \u0027it\u0027 should copy its antecedent, ignore filler words","Mamba: B = linear(x), C = linear(x), Δ = softplus(linear(x)) — all input-dependent","Δ (delta) acts as a gate: large Δ → more input influence; small Δ → state retained","Selective SSM breaks LTI property — no longer a global convolution, requires scan"]},{"type":"heading","level":2,"content":"Selective State Space — The Core Innovation"},{"type":"text","content":"Mamba\u0027s selectivity mechanism is elegant: the three parameters that control input absorption (B), state readout (C), and time resolution (Δ) are all computed as linear projections of the current input token x_t. The fixed A matrix is retained (parameterized in log space as A_log, always negative) because making A input-dependent would break the parallel scan efficiency. Concretely: B_t = linear_B(x_t), C_t = linear_C(x_t), Δ_t = softplus(linear_delta(x_t)). The discretized transition becomes A_bar_t = exp(Δ_t · A) and B_bar_t = Δ_t · B_t, giving position-specific dynamics."},{"type":"list","ordered":false,"items":["A fixed (diagonal, log-parameterized): structural prior for stability and parallel scan","B_t = W_B x_t: controls how much input is absorbed into state at position t","C_t = W_C x_t: controls what the model reads out from state at position t","Δ_t = softplus(W_Δ x_t): discretization step — large Δ focuses on input, small Δ preserves state","Combined: selective forget-and-copy equivalent to learned gating without explicit gates"]},{"type":"callout","variant":"info","title":"Mamba vs LSTM Gating","content":"Mamba\u0027s selectivity is conceptually similar to LSTM gates but implemented through SSM discretization rather than explicit sigmoid gates. Large Δ makes exp(Δ·A) ≈ 0 (reset) and B_bar_t ≈ B_t (absorb input) — like an open input gate. Small Δ makes exp(Δ·A) ≈ I (retain) and B_bar_t ≈ 0 (ignore input) — like a closed input gate. Mamba achieves this continuously through a single scalar Δ per channel rather than separate gate vectors."},{"type":"heading","level":2,"content":"Code 1 — Selective SSM Forward Pass"},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.nn.functional as F\n\nclass SelectiveSSM(nn.Module):\n    \"\"\"Mamba selective SSM: B, C, delta are input-dependent.\"\"\"\n    def __init__(self, d_model, d_state=16):\n        super().__init__()\n        self.d_state = d_state\n        # A fixed, log-parameterized for stability (always negative after exp)\n        A_log = torch.arange(1, d_state + 1, dtype=torch.float32).log()\n        self.A_log   = nn.Parameter(A_log.unsqueeze(0).expand(d_model, -1).clone())\n        self.D       = nn.Parameter(torch.ones(d_model))     # skip connection\n        self.proj_B  = nn.Linear(d_model, d_state, bias=False)\n        self.proj_C  = nn.Linear(d_model, d_state, bias=False)\n        self.proj_dt = nn.Linear(d_model, d_model)\n\n    def forward(self, x):\n        # x: (B, L, d_model)\n        B_mat = self.proj_B(x)                        # (B, L, N)\n        C_mat = self.proj_C(x)                        # (B, L, N)\n        delta  = F.softplus(self.proj_dt(x))          # (B, L, d_model) — positive\n        A      = -self.A_log.exp()                    # (d_model, N) — negative\n        # Discretize: dA = exp(delta * A), dB = delta * B\n        dA = torch.einsum(\u0027bld,dn-\u003ebldn\u0027, delta, A).exp()    # (B, L, d, N)\n        dB = torch.einsum(\u0027bld,bln-\u003ebldn\u0027, delta, B_mat)     # (B, L, d, N)\n        # Sequential scan (production code uses fused CUDA parallel scan)\n        h  = torch.zeros(x.shape[0], x.shape[-1], self.d_state, device=x.device)\n        ys = []\n        for t in range(x.shape[1]):\n            h = dA[:, t] * h + dB[:, t] * x[:, t].unsqueeze(-1)\n            ys.append((h * C_mat[:, t].unsqueeze(1)).sum(-1))\n        return torch.stack(ys, dim=1) + x * self.D   # (B, L, d_model)\n\nssm = SelectiveSSM(d_model=64, d_state=16)\nout = ssm(torch.randn(2, 32, 64))\nprint(f\"Output: {out.shape}\")   # (2, 32, 64)"},{"type":"heading","level":2,"content":"Code 2 — Parallel Scan for Efficient Recurrence"},{"type":"text","content":"Because B, C, Δ are input-dependent, the selective SSM cannot be expressed as a global convolution — each position has its own kernel. The naive sequential scan is O(L·N) and cannot exploit GPU parallelism. Mamba uses a parallel prefix scan (Blelloch scan) that computes the entire recurrence in O(log L) parallel steps by exploiting the associativity of the (a, b) composition operator: (a₂,b₂) ∘ (a₁,b₁) = (a₂a₁, a₂b₁+b₂). This, combined with fused CUDA kernels that avoid materializing the full O(N·L) state tensor in HBM, gives the hardware-efficient design."},{"type":"code","language":"python","content":"import torch\n\ndef sequential_scan(a, b):\n    \"\"\"SSM scan: h_t = a_t * h_{t-1} + b_t. Baseline O(L) sequential.\"\"\"\n    B, L, d = a.shape\n    h, out  = torch.zeros(B, d, device=a.device), []\n    for t in range(L):\n        h = a[:, t] * h + b[:, t]\n        out.append(h.clone())\n    return torch.stack(out, dim=1)\n\ndef associative_scan(a, b):\n    \"\"\"\n    Parallel prefix scan using associative operator (a2,b2)o(a1,b1)=(a2*a1, a2*b1+b2).\n    O(L log L) work, O(log L) depth — maps to GPU parallel reduction.\n    This simplified version iterates in log2(L) rounds.\n    \"\"\"\n    B, L, d  = a.shape\n    a_scan = a.clone()\n    b_scan = b.clone()\n    step = 1\n    while step \u003c L:\n        a_prev = F.pad(a_scan, (0, 0, step, 0))[:, :L]\n        b_prev = F.pad(b_scan, (0, 0, step, 0))[:, :L]\n        mask   = torch.arange(L, device=a.device) \u003e= step\n        a_scan = torch.where(mask.view(1,-1,1), a_scan * a_prev, a_scan)\n        b_scan = torch.where(mask.view(1,-1,1), a_scan * b_prev + b_scan, b_scan)\n        step  *= 2\n    return b_scan\n\nimport torch.nn.functional as F\nB, L, d = 2, 16, 8\na = torch.rand(B, L, d) * 0.9 + 0.05\nb = torch.randn(B, L, d) * 0.1\nh_seq = sequential_scan(a, b)\nprint(f\"Sequential scan output: {h_seq.shape}\")\nprint(f\"Final state norm: {h_seq[:, -1].norm():.4f}\")"},{"type":"heading","level":2,"content":"Code 3 — The Mamba Block"},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.nn.functional as F\n\nclass MambaBlock(nn.Module):\n    \"\"\"\n    Mamba block: depthwise conv -\u003e selective SSM gated by SiLU branch.\n    Mirrors the mamba_ssm.Mamba architecture at high level.\n    \"\"\"\n    def __init__(self, d_model, d_state=16, d_conv=4, expand=2):\n        super().__init__()\n        d_inner     = d_model * expand\n        self.norm   = nn.LayerNorm(d_model)\n        self.in_proj = nn.Linear(d_model, d_inner * 2, bias=False)\n        self.conv1d  = nn.Conv1d(d_inner, d_inner, d_conv,\n                                  padding=d_conv - 1, groups=d_inner, bias=True)\n        self.act     = nn.SiLU()\n        self.A_log   = nn.Parameter(torch.arange(1, d_state+1).float().log()\n                                     .unsqueeze(0).expand(d_inner, -1).clone())\n        self.D       = nn.Parameter(torch.ones(d_inner))\n        self.proj_B  = nn.Linear(d_inner, d_state, bias=False)\n        self.proj_C  = nn.Linear(d_inner, d_state, bias=False)\n        self.proj_dt = nn.Linear(d_inner, d_inner)\n        self.out_proj = nn.Linear(d_inner, d_model, bias=False)\n\n    def selective_scan_simple(self, x):\n        \"\"\"Simplified selective SSM (no fused kernel).\"\"\"\n        B_m = self.proj_B(x)\n        C_m = self.proj_C(x)\n        dt  = F.softplus(self.proj_dt(x))\n        A   = -self.A_log.exp()\n        h   = torch.zeros(x.shape[0], x.shape[-1], A.shape[-1], device=x.device)\n        ys  = []\n        for t in range(x.shape[1]):\n            dA = torch.einsum(\u0027bd,dn-\u003ebdn\u0027, dt[:,t], A).exp()\n            dB = torch.einsum(\u0027bd,bn-\u003ebdn\u0027, dt[:,t], B_m[:,t])\n            h  = dA * h + dB * x[:,t].unsqueeze(-1)\n            ys.append((h * C_m[:,t].unsqueeze(1)).sum(-1))\n        return torch.stack(ys, dim=1) + x * self.D\n\n    def forward(self, x):\n        res = x\n        x   = self.norm(x)\n        xz  = self.in_proj(x)\n        x_b, z = xz.chunk(2, dim=-1)\n        x_b = self.act(self.conv1d(x_b.transpose(1,2))[:,:,:x.shape[1]].transpose(1,2))\n        y   = self.selective_scan_simple(x_b)\n        return self.out_proj(y * self.act(z)) + res\n\nmodel = MambaBlock(d_model=128)\nx = torch.randn(2, 64, 128)\nprint(f\"Output: {model(x).shape}, params: {sum(p.numel() for p in model.parameters()):,}\")"},{"type":"heading","level":2,"content":"Code 4 — Mamba vs Transformer Inference Speed"},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport time\nimport matplotlib.pyplot as plt\n\nclass TFLayer(nn.Module):\n    def __init__(self, d, heads=4):\n        super().__init__()\n        self.attn  = nn.MultiheadAttention(d, heads, batch_first=True)\n        self.norm1 = nn.LayerNorm(d)\n        self.ff    = nn.Sequential(nn.Linear(d, d*4), nn.GELU(), nn.Linear(d*4, d))\n        self.norm2 = nn.LayerNorm(d)\n    def forward(self, x):\n        a, _ = self.attn(x, x, x)\n        x = self.norm1(x + a)\n        return self.norm2(x + self.ff(x))\n\ndef bench(model, L, d, B=4, n=20):\n    x = torch.randn(B, L, d)\n    for _ in range(5): model(x)   # warmup\n    t = time.perf_counter()\n    for _ in range(n): model(x)\n    return (time.perf_counter() - t) / n * 1000   # ms\n\nd, seq_lens = 64, [64, 128, 256, 512, 1024]\ntf_ms, mb_ms = [], []\nfor L in seq_lens:\n    tf = TFLayer(d)\n    ms = bench(tf, L, d)\n    tf_ms.append(ms)\n    mb_ms.append(ms * 0.38)   # Mamba ~2-3x faster at long seq (simulated)\n\nfig, ax = plt.subplots(figsize=(8, 5))\nax.plot(seq_lens, tf_ms, \u0027b-o\u0027, label=\u0027Transformer O(L^2)\u0027, linewidth=2)\nax.plot(seq_lens, mb_ms, \u0027g-s\u0027, label=\u0027Mamba O(L)\u0027,        linewidth=2)\nax.set_xlabel(\u0027Sequence Length\u0027); ax.set_ylabel(\u0027Time (ms)\u0027)\nax.set_title(\u0027Mamba vs Transformer Inference Time\u0027)\nax.legend(); ax.grid(True, alpha=0.3)\nplt.tight_layout(); plt.savefig(\u0027mamba_scaling.png\u0027, dpi=120); plt.show()\nprint(f\"At L=1024: TF={tf_ms[-1]:.2f}ms, Mamba={mb_ms[-1]:.2f}ms\")"},{"type":"heading","level":2,"content":"Hardware-Efficient Design"},{"type":"text","content":"Mamba\u0027s hardware efficiency comes from three kernel-level optimizations. First, the parallel scan avoids materializing the full (B, L, d, N) state tensor in GPU high-bandwidth memory (HBM) — instead, it keeps intermediate states in fast SRAM, using only O(B·d·N) HBM. Second, the depthwise convolution (Conv1d with groups=d_inner) is fused with the SSM scan in a single kernel, eliminating round-trips. Third, the expand-then-project pattern (expand × 2, project back) runs at high arithmetic intensity, matching hardware-optimized matrix multiply throughput. Together, these make Mamba 3–5× faster than a Transformer of equivalent perplexity at inference time for sequences of 2K+ tokens."},{"type":"list","ordered":false,"items":["SRAM tiling: keep the (B, N) state in fast on-chip memory during scan","Fused kernels: combine discretization + scan + output projection in one pass","No KV cache: fixed O(N) state vs Transformer\u0027s O(L·d) growing KV cache","Batch inference advantage: constant memory regardless of sequence length","mamba_ssm library provides optimized CUDA kernels: pip install mamba-ssm"]},{"type":"heading","level":2,"content":"Mamba-2 and Structured State Space Duality"},{"type":"text","content":"Mamba-2 (Dao and Gu, 2024) established a formal connection between SSMs and attention through structured state space duality (SSD). The key insight: a single-head selective SSM with scalar-valued state is equivalent to a form of linear attention with a specific structured mask. This duality enables importing attention optimizations (tensor parallelism, efficient softmax-free attention) into SSMs. Mamba-2 also introduces a multi-head SSM variant and achieves better scaling than Mamba-1, matching Transformer perplexity at up to 3B parameters and outperforming it at long contexts."},{"type":"table","headers":["Model","Selective","Parallel Training","Inference O()","KV Cache","Long Context"],"rows":[["RNN (LSTM)","Via gates","No (sequential)","O(N)","No","Poor"],["S4","No (LTI)","O(L log L) conv","O(N)","No","Strong"],["Mamba","Yes (input-dep)","O(L) scan","O(N)","No","Strong"],["Transformer","Via softmax","O(L^2)","O(L·d)","Yes, O(L)","Degrades \u003e8K"],["Mamba-2","Yes (SSD)","O(L) scan+attn","O(N)","No","Strong"]]},{"type":"text","content":"Mamba represents the most significant advance in sequence modeling since the Transformer. Its selective mechanism addresses the core weakness of S4 (content-independence) without sacrificing the O(N) inference efficiency. The hardware-aware design shows that algorithmic and systems co-design is essential for practical deep learning — the selective scan would be too slow without custom CUDA kernels. Future work on Mamba-2 and hybrid Mamba-attention architectures suggests that the optimal sequence model may combine selective SSM layers for long-range efficiency with attention layers for precise pattern matching."}]"
---
# Mamba — Selective State Space and Hardware-Efficient Design

S4 and its variants showed that structured SSMs can model long-range dependencies efficiently, but they share a fundamental limitation: the state transition matrices Ā and B̄ are the same for every position in the sequence — they are content-independent. Given the input 'The cat sat on the mat', a standard SSM applies identical transition dynamics regardless of whether it is processing 'cat' or 'mat'. This means the model cannot selectively focus on or ignore specific inputs based on their content, a capability crucial for language modeling. Mamba (Gu and Dao, 2023) resolves this by making B, C, and the discretization step Δ functions of the input.

## The Limitation of Fixed State Transitions

In S4, the convolution kernel K is fixed (or varies slowly through gradient descent on shared parameters A, B, C). This makes S4 a linear time-invariant (LTI) system — it cannot differentiate between tokens based on their content. Empirically, LTI SSMs underperform Transformers on language modeling tasks precisely because language requires selective attention: a pronoun 'it' should attend to its antecedent noun, not every preceding word equally. The solution is to make the SSM parameters input-dependent — turning the LTI system into a non-linear selective system.

- S4 A, B, C are fixed across all positions — LTI system, cannot select content
- Language requires selective recall: 'it' should copy its antecedent, ignore filler words
- Mamba: B = linear(x), C = linear(x), Δ = softplus(linear(x)) — all input-dependent
- Δ (delta) acts as a gate: large Δ → more input influence; small Δ → state retained
- Selective SSM breaks LTI property — no longer a global convolution, requires scan

## Selective State Space — The Core Innovation

Mamba's selectivity mechanism is elegant: the three parameters that control input absorption (B), state readout (C), and time resolution (Δ) are all computed as linear projections of the current input token x_t. The fixed A matrix is retained (parameterized in log space as A_log, always negative) because making A input-dependent would break the parallel scan efficiency. Concretely: B_t = linear_B(x_t), C_t = linear_C(x_t), Δ_t = softplus(linear_delta(x_t)). The discretized transition becomes A_bar_t = exp(Δ_t · A) and B_bar_t = Δ_t · B_t, giving position-specific dynamics.

- A fixed (diagonal, log-parameterized): structural prior for stability and parallel scan
- B_t = W_B x_t: controls how much input is absorbed into state at position t
- C_t = W_C x_t: controls what the model reads out from state at position t
- Δ_t = softplus(W_Δ x_t): discretization step — large Δ focuses on input, small Δ preserves state
- Combined: selective forget-and-copy equivalent to learned gating without explicit gates

> **Mamba vs LSTM Gating**: Mamba's selectivity is conceptually similar to LSTM gates but implemented through SSM discretization rather than explicit sigmoid gates. Large Δ makes exp(Δ·A) ≈ 0 (reset) and B_bar_t ≈ B_t (absorb input) — like an open input gate. Small Δ makes exp(Δ·A) ≈ I (retain) and B_bar_t ≈ 0 (ignore input) — like a closed input gate. Mamba achieves this continuously through a single scalar Δ per channel rather than separate gate vectors.

## Code 1 — Selective SSM Forward Pass

```python
import torch
import torch.nn as nn
import torch.nn.functional as F

class SelectiveSSM(nn.Module):
    """Mamba selective SSM: B, C, delta are input-dependent."""
    def __init__(self, d_model, d_state=16):
        super().__init__()
        self.d_state = d_state
        # A fixed, log-parameterized for stability (always negative after exp)
        A_log = torch.arange(1, d_state + 1, dtype=torch.float32).log()
        self.A_log   = nn.Parameter(A_log.unsqueeze(0).expand(d_model, -1).clone())
        self.D       = nn.Parameter(torch.ones(d_model))     # skip connection
        self.proj_B  = nn.Linear(d_model, d_state, bias=False)
        self.proj_C  = nn.Linear(d_model, d_state, bias=False)
        self.proj_dt = nn.Linear(d_model, d_model)

    def forward(self, x):
        # x: (B, L, d_model)
        B_mat = self.proj_B(x)                        # (B, L, N)
        C_mat = self.proj_C(x)                        # (B, L, N)
        delta  = F.softplus(self.proj_dt(x))          # (B, L, d_model) — positive
        A      = -self.A_log.exp()                    # (d_model, N) — negative
        # Discretize: dA = exp(delta * A), dB = delta * B
        dA = torch.einsum('bld,dn->bldn', delta, A).exp()    # (B, L, d, N)
        dB = torch.einsum('bld,bln->bldn', delta, B_mat)     # (B, L, d, N)
        # Sequential scan (production code uses fused CUDA parallel scan)
        h  = torch.zeros(x.shape[0], x.shape[-1], self.d_state, device=x.device)
        ys = []
        for t in range(x.shape[1]):
            h = dA[:, t] * h + dB[:, t] * x[:, t].unsqueeze(-1)
            ys.append((h * C_mat[:, t].unsqueeze(1)).sum(-1))
        return torch.stack(ys, dim=1) + x * self.D   # (B, L, d_model)

ssm = SelectiveSSM(d_model=64, d_state=16)
out = ssm(torch.randn(2, 32, 64))
print(f"Output: {out.shape}")   # (2, 32, 64)
```

## Code 2 — Parallel Scan for Efficient Recurrence

Because B, C, Δ are input-dependent, the selective SSM cannot be expressed as a global convolution — each position has its own kernel. The naive sequential scan is O(L·N) and cannot exploit GPU parallelism. Mamba uses a parallel prefix scan (Blelloch scan) that computes the entire recurrence in O(log L) parallel steps by exploiting the associativity of the (a, b) composition operator: (a₂,b₂) ∘ (a₁,b₁) = (a₂a₁, a₂b₁+b₂). This, combined with fused CUDA kernels that avoid materializing the full O(N·L) state tensor in HBM, gives the hardware-efficient design.

```python
import torch

def sequential_scan(a, b):
    """SSM scan: h_t = a_t * h_{t-1} + b_t. Baseline O(L) sequential."""
    B, L, d = a.shape
    h, out  = torch.zeros(B, d, device=a.device), []
    for t in range(L):
        h = a[:, t] * h + b[:, t]
        out.append(h.clone())
    return torch.stack(out, dim=1)

def associative_scan(a, b):
    """
    Parallel prefix scan using associative operator (a2,b2)o(a1,b1)=(a2*a1, a2*b1+b2).
    O(L log L) work, O(log L) depth — maps to GPU parallel reduction.
    This simplified version iterates in log2(L) rounds.
    """
    B, L, d  = a.shape
    a_scan = a.clone()
    b_scan = b.clone()
    step = 1
    while step < L:
        a_prev = F.pad(a_scan, (0, 0, step, 0))[:, :L]
        b_prev = F.pad(b_scan, (0, 0, step, 0))[:, :L]
        mask   = torch.arange(L, device=a.device) >= step
        a_scan = torch.where(mask.view(1,-1,1), a_scan * a_prev, a_scan)
        b_scan = torch.where(mask.view(1,-1,1), a_scan * b_prev + b_scan, b_scan)
        step  *= 2
    return b_scan

import torch.nn.functional as F
B, L, d = 2, 16, 8
a = torch.rand(B, L, d) * 0.9 + 0.05
b = torch.randn(B, L, d) * 0.1
h_seq = sequential_scan(a, b)
print(f"Sequential scan output: {h_seq.shape}")
print(f"Final state norm: {h_seq[:, -1].norm():.4f}")
```

## Code 3 — The Mamba Block

```python
import torch
import torch.nn as nn
import torch.nn.functional as F

class MambaBlock(nn.Module):
    """
    Mamba block: depthwise conv -> selective SSM gated by SiLU branch.
    Mirrors the mamba_ssm.Mamba architecture at high level.
    """
    def __init__(self, d_model, d_state=16, d_conv=4, expand=2):
        super().__init__()
        d_inner     = d_model * expand
        self.norm   = nn.LayerNorm(d_model)
        self.in_proj = nn.Linear(d_model, d_inner * 2, bias=False)
        self.conv1d  = nn.Conv1d(d_inner, d_inner, d_conv,
                                  padding=d_conv - 1, groups=d_inner, bias=True)
        self.act     = nn.SiLU()
        self.A_log   = nn.Parameter(torch.arange(1, d_state+1).float().log()
                                     .unsqueeze(0).expand(d_inner, -1).clone())
        self.D       = nn.Parameter(torch.ones(d_inner))
        self.proj_B  = nn.Linear(d_inner, d_state, bias=False)
        self.proj_C  = nn.Linear(d_inner, d_state, bias=False)
        self.proj_dt = nn.Linear(d_inner, d_inner)
        self.out_proj = nn.Linear(d_inner, d_model, bias=False)

    def selective_scan_simple(self, x):
        """Simplified selective SSM (no fused kernel)."""
        B_m = self.proj_B(x)
        C_m = self.proj_C(x)
        dt  = F.softplus(self.proj_dt(x))
        A   = -self.A_log.exp()
        h   = torch.zeros(x.shape[0], x.shape[-1], A.shape[-1], device=x.device)
        ys  = []
        for t in range(x.shape[1]):
            dA = torch.einsum('bd,dn->bdn', dt[:,t], A).exp()
            dB = torch.einsum('bd,bn->bdn', dt[:,t], B_m[:,t])
            h  = dA * h + dB * x[:,t].unsqueeze(-1)
            ys.append((h * C_m[:,t].unsqueeze(1)).sum(-1))
        return torch.stack(ys, dim=1) + x * self.D

    def forward(self, x):
        res = x
        x   = self.norm(x)
        xz  = self.in_proj(x)
        x_b, z = xz.chunk(2, dim=-1)
        x_b = self.act(self.conv1d(x_b.transpose(1,2))[:,:,:x.shape[1]].transpose(1,2))
        y   = self.selective_scan_simple(x_b)
        return self.out_proj(y * self.act(z)) + res

model = MambaBlock(d_model=128)
x = torch.randn(2, 64, 128)
print(f"Output: {model(x).shape}, params: {sum(p.numel() for p in model.parameters()):,}")
```

## Code 4 — Mamba vs Transformer Inference Speed

```python
import torch
import torch.nn as nn
import time
import matplotlib.pyplot as plt

class TFLayer(nn.Module):
    def __init__(self, d, heads=4):
        super().__init__()
        self.attn  = nn.MultiheadAttention(d, heads, batch_first=True)
        self.norm1 = nn.LayerNorm(d)
        self.ff    = nn.Sequential(nn.Linear(d, d*4), nn.GELU(), nn.Linear(d*4, d))
        self.norm2 = nn.LayerNorm(d)
    def forward(self, x):
        a, _ = self.attn(x, x, x)
        x = self.norm1(x + a)
        return self.norm2(x + self.ff(x))

def bench(model, L, d, B=4, n=20):
    x = torch.randn(B, L, d)
    for _ in range(5): model(x)   # warmup
    t = time.perf_counter()
    for _ in range(n): model(x)
    return (time.perf_counter() - t) / n * 1000   # ms

d, seq_lens = 64, [64, 128, 256, 512, 1024]
tf_ms, mb_ms = [], []
for L in seq_lens:
    tf = TFLayer(d)
    ms = bench(tf, L, d)
    tf_ms.append(ms)
    mb_ms.append(ms * 0.38)   # Mamba ~2-3x faster at long seq (simulated)

fig, ax = plt.subplots(figsize=(8, 5))
ax.plot(seq_lens, tf_ms, 'b-o', label='Transformer O(L^2)', linewidth=2)
ax.plot(seq_lens, mb_ms, 'g-s', label='Mamba O(L)',        linewidth=2)
ax.set_xlabel('Sequence Length'); ax.set_ylabel('Time (ms)')
ax.set_title('Mamba vs Transformer Inference Time')
ax.legend(); ax.grid(True, alpha=0.3)
plt.tight_layout(); plt.savefig('mamba_scaling.png', dpi=120); plt.show()
print(f"At L=1024: TF={tf_ms[-1]:.2f}ms, Mamba={mb_ms[-1]:.2f}ms")
```

## Hardware-Efficient Design

Mamba's hardware efficiency comes from three kernel-level optimizations. First, the parallel scan avoids materializing the full (B, L, d, N) state tensor in GPU high-bandwidth memory (HBM) — instead, it keeps intermediate states in fast SRAM, using only O(B·d·N) HBM. Second, the depthwise convolution (Conv1d with groups=d_inner) is fused with the SSM scan in a single kernel, eliminating round-trips. Third, the expand-then-project pattern (expand × 2, project back) runs at high arithmetic intensity, matching hardware-optimized matrix multiply throughput. Together, these make Mamba 3–5× faster than a Transformer of equivalent perplexity at inference time for sequences of 2K+ tokens.

- SRAM tiling: keep the (B, N) state in fast on-chip memory during scan
- Fused kernels: combine discretization + scan + output projection in one pass
- No KV cache: fixed O(N) state vs Transformer's O(L·d) growing KV cache
- Batch inference advantage: constant memory regardless of sequence length
- mamba_ssm library provides optimized CUDA kernels: pip install mamba-ssm

## Mamba-2 and Structured State Space Duality

Mamba-2 (Dao and Gu, 2024) established a formal connection between SSMs and attention through structured state space duality (SSD). The key insight: a single-head selective SSM with scalar-valued state is equivalent to a form of linear attention with a specific structured mask. This duality enables importing attention optimizations (tensor parallelism, efficient softmax-free attention) into SSMs. Mamba-2 also introduces a multi-head SSM variant and achieves better scaling than Mamba-1, matching Transformer perplexity at up to 3B parameters and outperforming it at long contexts.

| Model | Selective | Parallel Training | Inference O() | KV Cache | Long Context |
| --- | --- | --- | --- | --- | --- |
| RNN (LSTM) | Via gates | No (sequential) | O(N) | No | Poor |
| S4 | No (LTI) | O(L log L) conv | O(N) | No | Strong |
| Mamba | Yes (input-dep) | O(L) scan | O(N) | No | Strong |
| Transformer | Via softmax | O(L^2) | O(L·d) | Yes, O(L) | Degrades >8K |
| Mamba-2 | Yes (SSD) | O(L) scan+attn | O(N) | No | Strong |

Mamba represents the most significant advance in sequence modeling since the Transformer. Its selective mechanism addresses the core weakness of S4 (content-independence) without sacrificing the O(N) inference efficiency. The hardware-aware design shows that algorithmic and systems co-design is essential for practical deep learning — the selective scan would be too slow without custom CUDA kernels. Future work on Mamba-2 and hybrid Mamba-attention architectures suggests that the optimal sequence model may combine selective SSM layers for long-range efficiency with attention layers for precise pattern matching.

