---
title: "GRU — Reset and Update Gates"
slug: "gru-gated-recurrent-unit"
description: "GRU (Cho et al. 2014) simplifies LSTM to two gates and no separate cell state: update gate zt interpolates between old and new hidden state, reset gate rt controls how much past context enters the candidate. Covers parameter count comparison, minGRU parallel variant, reset gate visualization, and when to prefer GRU over LSTM."
tags: ["deep-learning", "rnns", "sequence-models"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"GRU (Gated Recurrent Unit, Cho et al. 2014) simplifies the LSTM architecture from three gates and a separate cell state to two gates with a single hidden state. Despite this simplification, GRU often matches LSTM performance on many sequence tasks while training roughly 25% faster due to fewer parameters. Understanding when GRU is preferable — and how its two gates cover the same conceptual ground as LSTM\u0027s three — is essential for choosing the right architecture."},{"type":"heading","level":2,"content":"GRU Architecture — Two Gates, No Cell State"},{"type":"text","content":"GRU computes: update gate zt = σ(Wz[ht-1, xt]); reset gate rt = σ(Wr[ht-1, xt]); candidate h̃t = tanh(Wh[rt ⊙ ht-1, xt]); new hidden ht = zt ⊙ ht-1 + (1-zt) ⊙ h̃t. The update gate zt plays the combined role of LSTM\u0027s forget and input gates: zt ≈ 1 means keep the old hidden state (equivalent to ft ≈ 1 and it ≈ 0 in LSTM); zt ≈ 0 means fully replace with the candidate. The reset gate rt controls how much of the past hidden state enters the candidate computation."},{"type":"code","language":"python","content":"import numpy as np\n\ndef sigmoid(x):\n    return 1.0 / (1.0 + np.exp(-np.clip(x, -10, 10)))\n\nclass GRUCell:\n    \"\"\"Minimal GRU cell: update gate, reset gate, candidate, interpolation.\"\"\"\n    def __init__(self, input_size, hidden_size, seed=0):\n        rng = np.random.default_rng(seed)\n        s = np.sqrt(1.0 / hidden_size)\n        d = input_size + hidden_size\n        self.Wz = rng.normal(0, s, (hidden_size, d));  self.bz = np.zeros(hidden_size)\n        self.Wr = rng.normal(0, s, (hidden_size, d));  self.br = np.zeros(hidden_size)\n        self.Wh = rng.normal(0, s, (hidden_size, d));  self.bh = np.zeros(hidden_size)\n\n    def forward(self, x, h):\n        xh = np.concatenate([x, h])\n        z = sigmoid(self.Wz @ xh + self.bz)           # update gate\n        r = sigmoid(self.Wr @ xh + self.br)            # reset gate\n        xrh = np.concatenate([x, r * h])\n        h_cand = np.tanh(self.Wh @ xrh + self.bh)    # candidate\n        h_new  = z * h + (1 - z) * h_cand             # interpolate\n        return h_new, dict(z=z, r=r)\n\nnp.random.seed(42)\ngru = GRUCell(input_size=4, hidden_size=8)\nh = np.zeros(8)\nprint(\u0027GRU from scratch — gate activations per step:\u0027)\nprint(\u0027{:\u003e4} {:\u003e10} {:\u003e10} {:\u003e10}\u0027.format(\u0027t\u0027, \u0027h_norm\u0027, \u0027z_mean\u0027, \u0027r_mean\u0027))\nfor t in range(5):\n    x = np.random.randn(4)\n    h, g = gru.forward(x, h)\n    print(\u0027{:\u003e4} {:\u003e10.4f} {:\u003e10.4f} {:\u003e10.4f}\u0027.format(t, np.linalg.norm(h), g[\u0027z\u0027].mean(), g[\u0027r\u0027].mean()))"},{"type":"heading","level":2,"content":"Update Gate — Interpolation Between Old and New"},{"type":"text","content":"The update gate zt ∈ (0,1)ᴴ acts as a learned interpolation coefficient between the previous hidden state ht-1 and the new candidate h̃t: ht = zt ⊙ ht-1 + (1-zt) ⊙ h̃t. When zt ≈ 1, the hidden state is preserved unchanged — the unit remembers. When zt ≈ 0, the hidden state is fully replaced by the candidate — the unit updates. This single gate handles what LSTM needs two gates (forget + input) to achieve, at the cost of losing the ability to independently control how much to forget vs how much to write."},{"type":"heading","level":2,"content":"Reset Gate — Controlling Candidate Computation"},{"type":"text","content":"The reset gate rt ∈ (0,1)ᴴ controls how much of the previous hidden state enters the candidate: h̃t = tanh(Wh[rt ⊙ ht-1, xt]). When rt ≈ 1, the candidate sees the full past context — the cell uses its history. When rt ≈ 0, the candidate computation ignores ht-1 — the unit behaves as if it has no memory and generates a candidate purely from the current input. This allows GRU to reset its context when the input distribution changes abruptly."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.optim as optim\nimport time\n\ndef benchmark_rnn(cell_type=\u0027gru\u0027, I=16, H=64, T=30, C=5, N=512, epochs=20):\n    torch.manual_seed(42)\n    rnn = (nn.GRU if cell_type == \u0027gru\u0027 else nn.LSTM)(I, H, batch_first=True)\n    fc  = nn.Linear(H, C)\n    opt = optim.Adam(list(rnn.parameters()) + list(fc.parameters()), lr=1e-3)\n    x = torch.randn(N, T, I)\n    y = torch.randint(0, C, (N,))\n    t0 = time.perf_counter()\n    for _ in range(epochs):\n        out, state = rnn(x)\n        h = state[0].squeeze(0) if cell_type == \u0027lstm\u0027 else state.squeeze(0)\n        loss = nn.CrossEntropyLoss()(fc(h), y)\n        opt.zero_grad(); loss.backward(); opt.step()\n    elapsed = time.perf_counter() - t0\n    with torch.no_grad():\n        out, state = rnn(x)\n        h = state[0].squeeze(0) if cell_type == \u0027lstm\u0027 else state.squeeze(0)\n        acc = (fc(h).argmax(1) == y).float().mean().item()\n    n_params = sum(p.numel() for p in list(rnn.parameters()) + list(fc.parameters()))\n    return acc, elapsed, n_params\n\nprint(\u0027GRU vs LSTM on sequence classification (seq_len=30, 5 classes):\u0027)\nfor name in [\u0027gru\u0027, \u0027lstm\u0027]:\n    acc, t, n = benchmark_rnn(name)\n    print(\u0027  {}: acc={:.3f}  time={:.2f}s  params={:,}\u0027.format(name.upper(), acc, t, n))"},{"type":"heading","level":2,"content":"Parameter Count and Computational Cost"},{"type":"text","content":"GRU has 3 gate weight matrices (Wz, Wr, Wh) each of shape H×(H+I), giving 3·H·(H+I) + 3H parameters. LSTM has 4 gate matrices (Wf, Wi, Wg, Wo), giving 4·H·(H+I) + 4H parameters. For H=256, I=128, GRU has ~294K parameters vs LSTM ~392K — a 25% reduction. GRU also performs fewer matrix multiplications per step and has no cell state to maintain, making each forward step roughly 25% faster in practice."},{"type":"table","headers":["Model","Gates","Cell State","Params (H=256, I=128)","Parallelizable","Typical Perf"],"rows":[["Vanilla RNN","0 (direct Whh)","No","~98K","No (sequential)","Baseline — fails on long sequences"],["GRU","2 (update, reset)","No","~294K","No (sequential)","On par with LSTM on short-mid tasks"],["LSTM","3 (forget, input, output)","Yes (Ct)","~393K","No (sequential)","Best on long sequences with fine control"],["minGRU (2024)","1 (update, no reset)","No","~131K","Yes (parallel scan)","Competitive on many tasks, much faster training"]]},{"type":"heading","level":2,"content":"minGRU — Parallel-Trainable Simplified GRU"},{"type":"text","content":"minGRU (Feng et al. 2024) removes the reset gate and the tanh nonlinearity from the candidate, and makes the candidate depend only on the current input xt — not on ht-1. This breaks the sequential dependency in the forward pass, enabling fully parallel training via an associative scan (similar to how prefix-sum can be parallelized). The result is a model that trains much faster than standard GRU on long sequences while remaining competitive on many benchmarks."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\n\nclass MinGRU(nn.Module):\n    \"\"\"minGRU (Feng et al. 2024): no reset gate, no tanh, input-only candidate.\n\n    Removes sequential dependency -\u003e trainable in parallel via associative scan.\n    Sequential loop shown here for clarity; real impl uses log-space parallel scan.\n    \"\"\"\n    def __init__(self, input_size, hidden_size):\n        super().__init__()\n        self.gate      = nn.Linear(input_size, hidden_size)   # update gate\n        self.candidate = nn.Linear(input_size, hidden_size)   # candidate (no tanh, no h)\n        self.hidden_size = hidden_size\n\n    def forward(self, x):\n        \"\"\"x: (B, T, I). Returns (B, T, H) output sequence.\"\"\"\n        z      = torch.sigmoid(self.gate(x))      # (B, T, H) update gates\n        h_tild = self.candidate(x)                # (B, T, H) candidates\n        B = x.size(0)\n        h = torch.zeros(B, self.hidden_size)\n        outputs = []\n        for t in range(x.size(1)):\n            h = (1 - z[:, t]) * h + z[:, t] * h_tild[:, t]\n            outputs.append(h)\n        return torch.stack(outputs, dim=1)\n\ntorch.manual_seed(0)\nmodel = MinGRU(input_size=8, hidden_size=16)\nx = torch.randn(4, 20, 8)\nout = model(x)\nfull_gru_params = 3 * (8 * 16 + 16 * 16 + 16)\nprint(\u0027minGRU output: {}\u0027.format(tuple(out.shape)))\nprint(\u0027minGRU params: {:,}  vs full GRU params: {:,}\u0027.format(\n    sum(p.numel() for p in model.parameters()), full_gru_params))"},{"type":"heading","level":2,"content":"Reset Gate Visualization"},{"type":"text","content":"The reset gate tends to fire (approach 0) when the input distribution changes abruptly, allowing the candidate to be computed from scratch without contamination from stale hidden state. On stationary input, the reset gate stays near 1, preserving context. This behavior is learned automatically from data — the network discovers that resetting context helps recover from distribution shifts."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport numpy as np\n\ndef visualize_reset_gate(seq_len=40, input_size=4, hidden_size=8, seed=2):\n    \"\"\"Show reset gate activations across a two-phase sequence.\"\"\"\n    torch.manual_seed(seed)\n    cell = nn.GRUCell(input_size, hidden_size)\n    x = torch.cat([\n        torch.randn(seq_len // 2, input_size) * 0.2,   # smooth phase\n        torch.randn(seq_len // 2, input_size) * 3.0    # high-variance phase\n    ], dim=0)\n    h = torch.zeros(1, hidden_size)\n    reset_means = []\n    with torch.no_grad():\n        for t in range(seq_len):\n            pre = (x[t:t+1] @ cell.weight_ih.T + h @ cell.weight_hh.T\n                   + cell.bias_ih + cell.bias_hh)\n            r_gate = torch.sigmoid(pre[:, hidden_size:2*hidden_size])\n            reset_means.append(r_gate.mean().item())\n            h = cell(x[t:t+1], h)\n    rm = np.array(reset_means)\n    print(\u0027Reset gate mean (0=ignore past, 1=use past):\u0027)\n    print(\u0027  Smooth t=00-19: {:.3f}\u0027.format(rm[:20].mean()))\n    print(\u0027  Noisy  t=20-39: {:.3f}\u0027.format(rm[20:].mean()))\n    print(\u0027  Transition t=20: {:.3f}  \u003c- resets on sudden input spike\u0027.format(rm[20]))\n\nvisualize_reset_gate()"},{"type":"callout","variant":"info","title":"No Universal Winner: GRU vs LSTM","content":"Empirical comparisons (Chung et al. 2014, Greff et al. 2017) show neither GRU nor LSTM dominates consistently. GRU tends to win on shorter sequences and smaller datasets where its lower parameter count acts as regularization. LSTM tends to win on tasks requiring fine-grained control over what to forget vs what to write — such as language modeling with long-range dependencies. When in doubt, try GRU first (faster to train) and switch to LSTM if performance is insufficient."},{"type":"heading","level":2,"content":"When to Choose GRU"},{"type":"text","content":"GRU is preferable when training speed matters more than squeezing the last fraction of accuracy. Its 25% parameter reduction and simpler forward pass make it attractive for mobile deployment and rapid iteration. On tasks where sequence length is moderate (\u003c 50 steps) and the dataset is small to medium, GRU\u0027s implicit regularization from fewer parameters often outperforms LSTM."},{"type":"list","ordered":false,"items":["Shorter sequences (\u003c 50 steps): GRU is competitive with LSTM and trains faster.","Small datasets: fewer parameters in GRU reduce overfitting risk.","Speed-constrained deployment: GRU has lower FLOPs per step, better for edge inference.","When interpretability matters: 2 gates are easier to analyze than 3 + cell state.","Use LSTM when: sequences \u003e 100 steps, fine-grained gating is needed, or empirically LSTM wins.","Use minGRU when: very long sequences and training time is the bottleneck — parallel scan enables batch training."]},{"type":"text","content":"The GRU architecture demonstrates that much of LSTM\u0027s capability comes from the gating mechanism itself rather than the specific three-gate plus cell-state design. The empirical finding that GRU and LSTM perform similarly on many tasks suggests that the additive update structure — not the precise gate count — is the essential ingredient for learning long-range dependencies."},{"type":"divider"}]"
---
# GRU — Reset and Update Gates

GRU (Gated Recurrent Unit, Cho et al. 2014) simplifies the LSTM architecture from three gates and a separate cell state to two gates with a single hidden state. Despite this simplification, GRU often matches LSTM performance on many sequence tasks while training roughly 25% faster due to fewer parameters. Understanding when GRU is preferable — and how its two gates cover the same conceptual ground as LSTM's three — is essential for choosing the right architecture.

## GRU Architecture — Two Gates, No Cell State

GRU computes: update gate zt = σ(Wz[ht-1, xt]); reset gate rt = σ(Wr[ht-1, xt]); candidate h̃t = tanh(Wh[rt ⊙ ht-1, xt]); new hidden ht = zt ⊙ ht-1 + (1-zt) ⊙ h̃t. The update gate zt plays the combined role of LSTM's forget and input gates: zt ≈ 1 means keep the old hidden state (equivalent to ft ≈ 1 and it ≈ 0 in LSTM); zt ≈ 0 means fully replace with the candidate. The reset gate rt controls how much of the past hidden state enters the candidate computation.

```python
import numpy as np

def sigmoid(x):
    return 1.0 / (1.0 + np.exp(-np.clip(x, -10, 10)))

class GRUCell:
    """Minimal GRU cell: update gate, reset gate, candidate, interpolation."""
    def __init__(self, input_size, hidden_size, seed=0):
        rng = np.random.default_rng(seed)
        s = np.sqrt(1.0 / hidden_size)
        d = input_size + hidden_size
        self.Wz = rng.normal(0, s, (hidden_size, d));  self.bz = np.zeros(hidden_size)
        self.Wr = rng.normal(0, s, (hidden_size, d));  self.br = np.zeros(hidden_size)
        self.Wh = rng.normal(0, s, (hidden_size, d));  self.bh = np.zeros(hidden_size)

    def forward(self, x, h):
        xh = np.concatenate([x, h])
        z = sigmoid(self.Wz @ xh + self.bz)           # update gate
        r = sigmoid(self.Wr @ xh + self.br)            # reset gate
        xrh = np.concatenate([x, r * h])
        h_cand = np.tanh(self.Wh @ xrh + self.bh)    # candidate
        h_new  = z * h + (1 - z) * h_cand             # interpolate
        return h_new, dict(z=z, r=r)

np.random.seed(42)
gru = GRUCell(input_size=4, hidden_size=8)
h = np.zeros(8)
print('GRU from scratch — gate activations per step:')
print('{:>4} {:>10} {:>10} {:>10}'.format('t', 'h_norm', 'z_mean', 'r_mean'))
for t in range(5):
    x = np.random.randn(4)
    h, g = gru.forward(x, h)
    print('{:>4} {:>10.4f} {:>10.4f} {:>10.4f}'.format(t, np.linalg.norm(h), g['z'].mean(), g['r'].mean()))
```

## Update Gate — Interpolation Between Old and New

The update gate zt ∈ (0,1)ᴴ acts as a learned interpolation coefficient between the previous hidden state ht-1 and the new candidate h̃t: ht = zt ⊙ ht-1 + (1-zt) ⊙ h̃t. When zt ≈ 1, the hidden state is preserved unchanged — the unit remembers. When zt ≈ 0, the hidden state is fully replaced by the candidate — the unit updates. This single gate handles what LSTM needs two gates (forget + input) to achieve, at the cost of losing the ability to independently control how much to forget vs how much to write.

## Reset Gate — Controlling Candidate Computation

The reset gate rt ∈ (0,1)ᴴ controls how much of the previous hidden state enters the candidate: h̃t = tanh(Wh[rt ⊙ ht-1, xt]). When rt ≈ 1, the candidate sees the full past context — the cell uses its history. When rt ≈ 0, the candidate computation ignores ht-1 — the unit behaves as if it has no memory and generates a candidate purely from the current input. This allows GRU to reset its context when the input distribution changes abruptly.

```python
import torch
import torch.nn as nn
import torch.optim as optim
import time

def benchmark_rnn(cell_type='gru', I=16, H=64, T=30, C=5, N=512, epochs=20):
    torch.manual_seed(42)
    rnn = (nn.GRU if cell_type == 'gru' else nn.LSTM)(I, H, batch_first=True)
    fc  = nn.Linear(H, C)
    opt = optim.Adam(list(rnn.parameters()) + list(fc.parameters()), lr=1e-3)
    x = torch.randn(N, T, I)
    y = torch.randint(0, C, (N,))
    t0 = time.perf_counter()
    for _ in range(epochs):
        out, state = rnn(x)
        h = state[0].squeeze(0) if cell_type == 'lstm' else state.squeeze(0)
        loss = nn.CrossEntropyLoss()(fc(h), y)
        opt.zero_grad(); loss.backward(); opt.step()
    elapsed = time.perf_counter() - t0
    with torch.no_grad():
        out, state = rnn(x)
        h = state[0].squeeze(0) if cell_type == 'lstm' else state.squeeze(0)
        acc = (fc(h).argmax(1) == y).float().mean().item()
    n_params = sum(p.numel() for p in list(rnn.parameters()) + list(fc.parameters()))
    return acc, elapsed, n_params

print('GRU vs LSTM on sequence classification (seq_len=30, 5 classes):')
for name in ['gru', 'lstm']:
    acc, t, n = benchmark_rnn(name)
    print('  {}: acc={:.3f}  time={:.2f}s  params={:,}'.format(name.upper(), acc, t, n))
```

## Parameter Count and Computational Cost

GRU has 3 gate weight matrices (Wz, Wr, Wh) each of shape H×(H+I), giving 3·H·(H+I) + 3H parameters. LSTM has 4 gate matrices (Wf, Wi, Wg, Wo), giving 4·H·(H+I) + 4H parameters. For H=256, I=128, GRU has ~294K parameters vs LSTM ~392K — a 25% reduction. GRU also performs fewer matrix multiplications per step and has no cell state to maintain, making each forward step roughly 25% faster in practice.

| Model | Gates | Cell State | Params (H=256, I=128) | Parallelizable | Typical Perf |
| --- | --- | --- | --- | --- | --- |
| Vanilla RNN | 0 (direct Whh) | No | ~98K | No (sequential) | Baseline — fails on long sequences |
| GRU | 2 (update, reset) | No | ~294K | No (sequential) | On par with LSTM on short-mid tasks |
| LSTM | 3 (forget, input, output) | Yes (Ct) | ~393K | No (sequential) | Best on long sequences with fine control |
| minGRU (2024) | 1 (update, no reset) | No | ~131K | Yes (parallel scan) | Competitive on many tasks, much faster training |

## minGRU — Parallel-Trainable Simplified GRU

minGRU (Feng et al. 2024) removes the reset gate and the tanh nonlinearity from the candidate, and makes the candidate depend only on the current input xt — not on ht-1. This breaks the sequential dependency in the forward pass, enabling fully parallel training via an associative scan (similar to how prefix-sum can be parallelized). The result is a model that trains much faster than standard GRU on long sequences while remaining competitive on many benchmarks.

```python
import torch
import torch.nn as nn

class MinGRU(nn.Module):
    """minGRU (Feng et al. 2024): no reset gate, no tanh, input-only candidate.

    Removes sequential dependency -> trainable in parallel via associative scan.
    Sequential loop shown here for clarity; real impl uses log-space parallel scan.
    """
    def __init__(self, input_size, hidden_size):
        super().__init__()
        self.gate      = nn.Linear(input_size, hidden_size)   # update gate
        self.candidate = nn.Linear(input_size, hidden_size)   # candidate (no tanh, no h)
        self.hidden_size = hidden_size

    def forward(self, x):
        """x: (B, T, I). Returns (B, T, H) output sequence."""
        z      = torch.sigmoid(self.gate(x))      # (B, T, H) update gates
        h_tild = self.candidate(x)                # (B, T, H) candidates
        B = x.size(0)
        h = torch.zeros(B, self.hidden_size)
        outputs = []
        for t in range(x.size(1)):
            h = (1 - z[:, t]) * h + z[:, t] * h_tild[:, t]
            outputs.append(h)
        return torch.stack(outputs, dim=1)

torch.manual_seed(0)
model = MinGRU(input_size=8, hidden_size=16)
x = torch.randn(4, 20, 8)
out = model(x)
full_gru_params = 3 * (8 * 16 + 16 * 16 + 16)
print('minGRU output: {}'.format(tuple(out.shape)))
print('minGRU params: {:,}  vs full GRU params: {:,}'.format(
    sum(p.numel() for p in model.parameters()), full_gru_params))
```

## Reset Gate Visualization

The reset gate tends to fire (approach 0) when the input distribution changes abruptly, allowing the candidate to be computed from scratch without contamination from stale hidden state. On stationary input, the reset gate stays near 1, preserving context. This behavior is learned automatically from data — the network discovers that resetting context helps recover from distribution shifts.

```python
import torch
import torch.nn as nn
import numpy as np

def visualize_reset_gate(seq_len=40, input_size=4, hidden_size=8, seed=2):
    """Show reset gate activations across a two-phase sequence."""
    torch.manual_seed(seed)
    cell = nn.GRUCell(input_size, hidden_size)
    x = torch.cat([
        torch.randn(seq_len // 2, input_size) * 0.2,   # smooth phase
        torch.randn(seq_len // 2, input_size) * 3.0    # high-variance phase
    ], dim=0)
    h = torch.zeros(1, hidden_size)
    reset_means = []
    with torch.no_grad():
        for t in range(seq_len):
            pre = (x[t:t+1] @ cell.weight_ih.T + h @ cell.weight_hh.T
                   + cell.bias_ih + cell.bias_hh)
            r_gate = torch.sigmoid(pre[:, hidden_size:2*hidden_size])
            reset_means.append(r_gate.mean().item())
            h = cell(x[t:t+1], h)
    rm = np.array(reset_means)
    print('Reset gate mean (0=ignore past, 1=use past):')
    print('  Smooth t=00-19: {:.3f}'.format(rm[:20].mean()))
    print('  Noisy  t=20-39: {:.3f}'.format(rm[20:].mean()))
    print('  Transition t=20: {:.3f}  <- resets on sudden input spike'.format(rm[20]))

visualize_reset_gate()
```

> **No Universal Winner: GRU vs LSTM**: Empirical comparisons (Chung et al. 2014, Greff et al. 2017) show neither GRU nor LSTM dominates consistently. GRU tends to win on shorter sequences and smaller datasets where its lower parameter count acts as regularization. LSTM tends to win on tasks requiring fine-grained control over what to forget vs what to write — such as language modeling with long-range dependencies. When in doubt, try GRU first (faster to train) and switch to LSTM if performance is insufficient.

## When to Choose GRU

GRU is preferable when training speed matters more than squeezing the last fraction of accuracy. Its 25% parameter reduction and simpler forward pass make it attractive for mobile deployment and rapid iteration. On tasks where sequence length is moderate (< 50 steps) and the dataset is small to medium, GRU's implicit regularization from fewer parameters often outperforms LSTM.

- Shorter sequences (< 50 steps): GRU is competitive with LSTM and trains faster.
- Small datasets: fewer parameters in GRU reduce overfitting risk.
- Speed-constrained deployment: GRU has lower FLOPs per step, better for edge inference.
- When interpretability matters: 2 gates are easier to analyze than 3 + cell state.
- Use LSTM when: sequences > 100 steps, fine-grained gating is needed, or empirically LSTM wins.
- Use minGRU when: very long sequences and training time is the bottleneck — parallel scan enables batch training.

The GRU architecture demonstrates that much of LSTM's capability comes from the gating mechanism itself rather than the specific three-gate plus cell-state design. The empirical finding that GRU and LSTM perform similarly on many tasks suggests that the additive update structure — not the precise gate count — is the essential ingredient for learning long-range dependencies.

---

