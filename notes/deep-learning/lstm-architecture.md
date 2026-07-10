---
title: "LSTM — Forget Gate, Input Gate, Output Gate, and Cell State"
slug: "lstm-architecture"
description: "Derive all four LSTM gates from scratch, implement stateful PyTorch nn.LSTM, benchmark on the adding problem, visualise gate activations, and compare parameter count with GRU and vanilla RNN."
tags: ["deep-learning", "rnns", "sequence-models"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"The Long Short-Term Memory (LSTM) network was introduced by Hochreiter and Schmidhuber (1997) to solve the vanishing gradient problem in plain RNNs. The key innovation is a separate cell state Cₜ that acts as long-term memory, updated additively rather than through repeated matrix multiplication. Three gating mechanisms — forget (fₜ), input (iₜ), and output (oₜ) gates — control information flow using sigmoid activations (0 = block completely, 1 = pass completely). The forget gate bias is initialised to 1 (Jozefowicz 2015), which keeps the cell state active by default and significantly improves learning on long-range tasks. An LSTM has 4× the parameters of a vanilla RNN: four weight matrices of size H×(H+I) instead of one."},{"type":"heading","level":2,"content":"The Cell State — Long-Term Memory"},{"type":"text","content":"The cell state Cₜ ∈ ℝᴴ is the LSTM\u0027s long-term memory. Its update equation Cₜ = fₜ⊙Cₜ₋₁ + iₜ⊙C̃ₜ is additive — unlike the RNN hidden state which is overwritten at each step. The additive structure means the gradient ∂Cₜ/∂Cₜ₋₁ = diag(fₜ) is a diagonal matrix, not a full Wₕₕᵀ. With forget gates near 1, the gradient flows back through the cell state without exponential decay — the constant error carousel effect. The hidden state hₜ = oₜ⊙tanh(Cₜ) is a filtered version of the cell state, shared with downstream layers."},{"type":"heading","level":2,"content":"Gate Equations"},{"type":"text","content":"All four gates take the same input — the concatenation [hₜ₋₁, xₜ] — and differ only in their weight matrices and roles. Forget gate: fₜ = σ(Wf[hₜ₋₁,xₜ]+bf). Input gate: iₜ = σ(Wi[hₜ₋₁,xₜ]+bi). Candidate cell: C̃ₜ = tanh(Wc[hₜ₋₁,xₜ]+bc). Cell update: Cₜ = fₜ⊙Cₜ₋₁ + iₜ⊙C̃ₜ. Output gate: oₜ = σ(Wo[hₜ₋₁,xₜ]+bo). Hidden state: hₜ = oₜ⊙tanh(Cₜ). The sigmoid gates produce values in (0,1), enabling soft gating — partial forgetting or partial writing — rather than hard binary decisions."},{"type":"code","language":"python","content":"import numpy as np\n\nclass LSTMCell:\n    def __init__(self, input_size, hidden_size):\n        H, I = hidden_size, input_size\n        scale = 1.0 / np.sqrt(H)\n        # Combined weight matrix for all 4 gates [f, i, g, o]\n        self.W = np.random.randn(4 * H, H + I) * scale\n        self.b = np.zeros((4 * H, 1))\n        # Forget gate bias = 1 (Jozefowicz 2015 recommendation)\n        self.b[:H] = 1.0\n        self.H = H\n\n    def _sigmoid(self, x):\n        return 1.0 / (1.0 + np.exp(-np.clip(x, -20, 20)))\n\n    def forward(self, x, h_prev, c_prev):\n        H = self.H\n        z = self.W @ np.vstack([h_prev, x]) + self.b  # (4H, 1)\n        f = self._sigmoid(z[:H])        # forget gate\n        i = self._sigmoid(z[H:2*H])     # input gate\n        g = np.tanh(z[2*H:3*H])         # candidate cell\n        o = self._sigmoid(z[3*H:])      # output gate\n        c = f * c_prev + i * g          # additive cell update\n        h = o * np.tanh(c)              # hidden state\n        return h, c, dict(f=f, i=i, g=g, o=o)\n\nnp.random.seed(42)\nI, H, T = 8, 16, 6\ncell = LSTMCell(I, H)\nh = np.zeros((H, 1)); c = np.zeros((H, 1))\nfor t in range(T):\n    x = np.random.randn(I, 1)\n    h, c, gates = cell.forward(x, h, c)\n    print(f\u0027t={t}: |h|={np.linalg.norm(h):.4f}, |c|={np.linalg.norm(c):.4f}, \u0027\n          f\u0027f_mean={gates[\"f\"].mean():.3f}, i_mean={gates[\"i\"].mean():.3f}\u0027)"},{"type":"heading","level":2,"content":"PyTorch nn.LSTM"},{"type":"text","content":"PyTorch\u0027s nn.LSTM is an optimised fused implementation of the four gate equations. It returns two tensors: out (all hidden states) and a tuple (h_n, c_n) of the final hidden and cell states. For stateful processing, both h_n and c_n must be passed as the initial state to the next chunk. PyTorch\u0027s gate order is [input, forget, cell, output] — different from the conventional [forget, input, cell, output]. The bias layout is bias_ih (input-hidden bias) and bias_hh (hidden-hidden bias) each of shape 4×H, concatenated in gate order."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\n\ntorch.manual_seed(42)\nI, H, num_layers, B, T = 16, 32, 2, 8, 20\n\nlstm = nn.LSTM(input_size=I, hidden_size=H,\n               num_layers=num_layers, batch_first=True)\nx = torch.randn(B, T, I)\n\n# Single pass over full sequence\nout, (h_n, c_n) = lstm(x)\nprint(f\u0027out shape:  {out.shape}  (B, T, H)\u0027)\nprint(f\u0027h_n shape:  {h_n.shape}  (num_layers, B, H)\u0027)\nprint(f\u0027c_n shape:  {c_n.shape}  (num_layers, B, H)\u0027)\n\n# Stateful: split into chunks, carry both h and c\nchunk = 5\nh_s = torch.zeros(num_layers, B, H)\nc_s = torch.zeros(num_layers, B, H)\nchunk_outs = []\nfor start in range(0, T, chunk):\n    xc = x[:, start:start + chunk, :]\n    out_c, (h_s, c_s) = lstm(xc, (h_s, c_s))\n    h_s = h_s.detach(); c_s = c_s.detach()\n    chunk_outs.append(out_c)\nall_out = torch.cat(chunk_outs, dim=1)\n\nprint(f\u0027Stateful vs single-pass max diff: {(out.detach() - all_out).abs().max():.4e}\u0027)\nn_params = sum(p.numel() for p in lstm.parameters())\nprint(f\u0027LSTM params ({num_layers}L, H={H}, I={I}): {n_params}\u0027)\n# 4 gates x (H*H + H*I + H_bias) x num_layers\nexpected = num_layers * 4 * (H * H + H * I + 2 * H)\nprint(f\u0027Expected: {expected}  (4 gates * (H^2 + H*I + 2*H) * num_layers)\u0027)"},{"type":"heading","level":2,"content":"The Adding Problem — Long-Range Dependency Benchmark"},{"type":"text","content":"The adding problem (Hochreiter and Schmidhuber 1997) tests long-range dependency learning. A sequence of length T contains random values in [0,1] with a binary mask that marks exactly two positions. The task is to output the sum of the two marked values. The LSTM must remember the first marked value (potentially at t=0) until it sees the second marker (potentially at t=T-1) — a lag of up to T steps. The baseline MSE for always predicting the mean (1.0) is 0.1667 for uniform [0,1] inputs. An LSTM trained with BPTT can solve this for T up to several hundred; a vanilla RNN fails for T\u003e20–30."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\n\ntorch.manual_seed(42)\n\ndef make_adding_batch(B=64, T=100, device=\u0027cpu\u0027):\n    seq  = torch.rand(B, T, device=device)\n    mask = torch.zeros(B, T, device=device)\n    for b in range(B):\n        idx = torch.randperm(T)[:2]\n        mask[b, idx] = 1.0\n    target = (seq * mask).sum(dim=1)   # scalar target per sequence\n    x = torch.stack([seq, mask], dim=2)  # (B, T, 2)\n    return x, target\n\nH, B, epochs = 64, 128, 400\nbaseline_mse  = 0.1667  # Var[U1+U2] for U ~ Uniform[0,1]\n\nfor T in [30, 100, 200]:\n    lstm = nn.LSTM(input_size=2, hidden_size=H, batch_first=True)\n    fc   = nn.Linear(H, 1)\n    opt  = torch.optim.Adam(list(lstm.parameters()) + list(fc.parameters()), lr=1e-3)\n    for ep in range(epochs):\n        x, y  = make_adding_batch(B, T)\n        out, _ = lstm(x)\n        pred   = fc(out[:, -1, :]).squeeze(1)\n        loss   = nn.functional.mse_loss(pred, y)\n        opt.zero_grad(); loss.backward(); opt.step()\n    with torch.no_grad():\n        x, y  = make_adding_batch(512, T)\n        pred  = fc(lstm(x)[0][:, -1, :]).squeeze(1)\n        mse   = nn.functional.mse_loss(pred, y).item()\n    solved = mse \u003c 0.01 * baseline_mse\n    print(f\u0027T={T:3d}: test MSE={mse:.6f}, baseline={baseline_mse:.4f}, \u0027\n          f\u0027solved={solved}\u0027)"},{"type":"heading","level":2,"content":"Gate Activation Visualization"},{"type":"text","content":"Visualising the forget gate activations reveals the LSTM\u0027s learned memory management strategy. On tasks requiring long-range memory (e.g., the adding problem), the forget gate near the marker position typically drops below 0.5 (selectively overwriting memory), while remaining above 0.9 for filler steps (preserving the stored value). The input gate shows the complementary pattern: high activation only when meaningful new information arrives. Inspecting gate statistics — mean, variance, fraction near 0 or 1 — is a key diagnostic for understanding LSTM failure modes."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport numpy as np\n\ntorch.manual_seed(0)\nI, H, T, B = 4, 8, 20, 1\n\nlstm = nn.LSTM(I, H, batch_first=True)\n# Initialise forget gate bias to 2.0 for strong default memory\nwith torch.no_grad():\n    # PyTorch gate order: [input(i), forget(f), cell(g), output(o)]\n    lstm.bias_ih_l0[H:2*H] = 2.0   # forget gate bias in bias_ih\n    lstm.bias_hh_l0[H:2*H] = 2.0   # forget gate bias in bias_hh\n\nx = torch.randn(B, T, I)\nforget_gates = []; input_gates = []\nh = torch.zeros(1, B, H); c = torch.zeros(1, B, H)\n\nwith torch.no_grad():\n    for t in range(T):\n        xt = x[:, t:t+1, :]              # (B, 1, I)\n        _, (h, c) = lstm(xt, (h, c))\n        # Recompute gates for inspection\n        W_ih = lstm.weight_ih_l0          # (4H, I)\n        W_hh = lstm.weight_hh_l0          # (4H, H)\n        gates_raw = (W_ih @ xt.squeeze() +\n                     W_hh @ h.squeeze() +\n                     lstm.bias_ih_l0 + lstm.bias_hh_l0)\n        i_gate = torch.sigmoid(gates_raw[:H])\n        f_gate = torch.sigmoid(gates_raw[H:2*H])\n        forget_gates.append(f_gate.numpy().copy())\n        input_gates.append(i_gate.numpy().copy())\n\nfg = np.array(forget_gates)  # (T, H)\nig = np.array(input_gates)\nprint(f\u0027Forget gate -- mean: {fg.mean():.4f}, std: {fg.std():.4f}\u0027)\nprint(f\u0027Input  gate -- mean: {ig.mean():.4f}, std: {ig.std():.4f}\u0027)\nprint(f\u0027Fraction forget \u003e 0.9 (preserving): {(fg \u003e 0.9).mean():.2%}\u0027)\nprint(f\u0027Fraction input  \u003c 0.1 (blocking):   {(ig \u003c 0.1).mean():.2%}\u0027)"},{"type":"heading","level":2,"content":"Parameter Count and Initialization"},{"type":"text","content":"An LSTM with hidden size H and input size I has 4×(H×H + H×I + H) parameters (for bias): 4 gates × (Wₕₕ + Wₕₓ + b). For H=512, I=256: 4×(262144 + 131072 + 512) = 1,574,912 ≈ 1.6M parameters per layer. The GRU uses 3 gates: 3×(H²+H×I+H) ≈ 75% of the LSTM parameter count. A vanilla RNN uses 1 set: H²+H×I+H ≈ 25% of LSTM. The forget gate bias should be initialised to 1.0 (not 0.0): Jozefowicz et al. (2015) showed that forget gate bias = 1 outperforms 0 on nearly all tasks by ensuring the cell state is preserved by default at the start of training."},{"type":"callout","variant":"tip","title":"Forget Gate Bias Initialisation","content":"Always initialise the LSTM forget gate bias to 1.0 (or higher, up to 3.0 for tasks with very long dependencies). In PyTorch: with torch.no_grad(): lstm.bias_ih_l0[H:2*H].fill_(1.0); lstm.bias_hh_l0[H:2*H].fill_(1.0). This ensures the cell state is preserved by default at the start of training, giving gradients a clear path back through time from the first epoch. Forget bias = 0 (PyTorch default) causes the network to forget everything initially, making early gradient signal sparse."},{"type":"heading","level":2,"content":"LSTM Equations Summary"},{"type":"table","headers":["Gate / State","Equation","Purpose","Output Range"],"rows":[["Forget gate","fₜ = σ(Wf·[hₜ₋₁, xₜ] + bf)","Decides what fraction of Cₜ₋₁ to keep","(0, 1) per dimension"],["Input gate","iₜ = σ(Wi·[hₜ₋₁, xₜ] + bi)","Decides what to write into cell state","(0, 1) per dimension"],["Candidate cell","C̃ₜ = tanh(Wc·[hₜ₋₁, xₜ] + bc)","New content to potentially write","(-1, 1)"],["Cell update","Cₜ = fₜ⊙Cₜ₋₁ + iₜ⊙C̃ₜ","Additive update — linear gradient highway","ℝ (unbounded)"],["Output gate","oₜ = σ(Wo·[hₜ₋₁, xₜ] + bo)","Decides what to expose as hidden state","(0, 1) per dimension"],["Hidden state","hₜ = oₜ⊙tanh(Cₜ)","Output passed to next layer / decoder","(-1, 1)"]]},{"type":"heading","level":2,"content":"LSTM Variants"},{"type":"text","content":"Several LSTM variants have been proposed to reduce parameters or improve performance. Peephole connections (Gers \u0026 Schmidhuber 2000) allow gates to depend on the cell state Cₜ₋₁ directly, adding H parameters per gate. The GRU (Cho 2014) merges the forget and input gates into a single update gate and eliminates the cell state, using 3 gates and 75% of LSTM parameters — often matching LSTM quality. Coupled input-forget gates (iₜ = 1−fₜ) reduce to 3 parameters sets while maintaining the additive update structure. Empirically, plain LSTM with forget bias = 1 is competitive with all variants on most benchmarks."},{"type":"list","ordered":false,"items":["Cell state Cₜ: long-term memory with additive update -- avoids repeated Whh multiplication.","Forget gate bias = 1.0: critical init trick; PyTorch default is 0 -- always override.","Parameter count: 4*(H^2 + H*I + H) per layer; ~4x vanilla RNN, ~1.33x GRU.","Peephole connections: gates read Ct-1 directly -- adds H params per gate, minor improvement.","GRU: 3 gates, no cell state, ht = (1-zt)*ht-1 + zt*h_tilde -- simpler, often comparable.","Stacked LSTM: multiple layers (num_layers \u003e 1 in PyTorch) -- each layer takes hidden states of previous as input.","Dropout in LSTM: apply between layers (not within time steps) -- variational dropout for temporal consistency."]},{"type":"divider"}]"
---
# LSTM — Forget Gate, Input Gate, Output Gate, and Cell State

The Long Short-Term Memory (LSTM) network was introduced by Hochreiter and Schmidhuber (1997) to solve the vanishing gradient problem in plain RNNs. The key innovation is a separate cell state Cₜ that acts as long-term memory, updated additively rather than through repeated matrix multiplication. Three gating mechanisms — forget (fₜ), input (iₜ), and output (oₜ) gates — control information flow using sigmoid activations (0 = block completely, 1 = pass completely). The forget gate bias is initialised to 1 (Jozefowicz 2015), which keeps the cell state active by default and significantly improves learning on long-range tasks. An LSTM has 4× the parameters of a vanilla RNN: four weight matrices of size H×(H+I) instead of one.

## The Cell State — Long-Term Memory

The cell state Cₜ ∈ ℝᴴ is the LSTM's long-term memory. Its update equation Cₜ = fₜ⊙Cₜ₋₁ + iₜ⊙C̃ₜ is additive — unlike the RNN hidden state which is overwritten at each step. The additive structure means the gradient ∂Cₜ/∂Cₜ₋₁ = diag(fₜ) is a diagonal matrix, not a full Wₕₕᵀ. With forget gates near 1, the gradient flows back through the cell state without exponential decay — the constant error carousel effect. The hidden state hₜ = oₜ⊙tanh(Cₜ) is a filtered version of the cell state, shared with downstream layers.

## Gate Equations

All four gates take the same input — the concatenation [hₜ₋₁, xₜ] — and differ only in their weight matrices and roles. Forget gate: fₜ = σ(Wf[hₜ₋₁,xₜ]+bf). Input gate: iₜ = σ(Wi[hₜ₋₁,xₜ]+bi). Candidate cell: C̃ₜ = tanh(Wc[hₜ₋₁,xₜ]+bc). Cell update: Cₜ = fₜ⊙Cₜ₋₁ + iₜ⊙C̃ₜ. Output gate: oₜ = σ(Wo[hₜ₋₁,xₜ]+bo). Hidden state: hₜ = oₜ⊙tanh(Cₜ). The sigmoid gates produce values in (0,1), enabling soft gating — partial forgetting or partial writing — rather than hard binary decisions.

```python
import numpy as np

class LSTMCell:
    def __init__(self, input_size, hidden_size):
        H, I = hidden_size, input_size
        scale = 1.0 / np.sqrt(H)
        # Combined weight matrix for all 4 gates [f, i, g, o]
        self.W = np.random.randn(4 * H, H + I) * scale
        self.b = np.zeros((4 * H, 1))
        # Forget gate bias = 1 (Jozefowicz 2015 recommendation)
        self.b[:H] = 1.0
        self.H = H

    def _sigmoid(self, x):
        return 1.0 / (1.0 + np.exp(-np.clip(x, -20, 20)))

    def forward(self, x, h_prev, c_prev):
        H = self.H
        z = self.W @ np.vstack([h_prev, x]) + self.b  # (4H, 1)
        f = self._sigmoid(z[:H])        # forget gate
        i = self._sigmoid(z[H:2*H])     # input gate
        g = np.tanh(z[2*H:3*H])         # candidate cell
        o = self._sigmoid(z[3*H:])      # output gate
        c = f * c_prev + i * g          # additive cell update
        h = o * np.tanh(c)              # hidden state
        return h, c, dict(f=f, i=i, g=g, o=o)

np.random.seed(42)
I, H, T = 8, 16, 6
cell = LSTMCell(I, H)
h = np.zeros((H, 1)); c = np.zeros((H, 1))
for t in range(T):
    x = np.random.randn(I, 1)
    h, c, gates = cell.forward(x, h, c)
    print(f't={t}: |h|={np.linalg.norm(h):.4f}, |c|={np.linalg.norm(c):.4f}, '
          f'f_mean={gates["f"].mean():.3f}, i_mean={gates["i"].mean():.3f}')
```

## PyTorch nn.LSTM

PyTorch's nn.LSTM is an optimised fused implementation of the four gate equations. It returns two tensors: out (all hidden states) and a tuple (h_n, c_n) of the final hidden and cell states. For stateful processing, both h_n and c_n must be passed as the initial state to the next chunk. PyTorch's gate order is [input, forget, cell, output] — different from the conventional [forget, input, cell, output]. The bias layout is bias_ih (input-hidden bias) and bias_hh (hidden-hidden bias) each of shape 4×H, concatenated in gate order.

```python
import torch
import torch.nn as nn

torch.manual_seed(42)
I, H, num_layers, B, T = 16, 32, 2, 8, 20

lstm = nn.LSTM(input_size=I, hidden_size=H,
               num_layers=num_layers, batch_first=True)
x = torch.randn(B, T, I)

# Single pass over full sequence
out, (h_n, c_n) = lstm(x)
print(f'out shape:  {out.shape}  (B, T, H)')
print(f'h_n shape:  {h_n.shape}  (num_layers, B, H)')
print(f'c_n shape:  {c_n.shape}  (num_layers, B, H)')

# Stateful: split into chunks, carry both h and c
chunk = 5
h_s = torch.zeros(num_layers, B, H)
c_s = torch.zeros(num_layers, B, H)
chunk_outs = []
for start in range(0, T, chunk):
    xc = x[:, start:start + chunk, :]
    out_c, (h_s, c_s) = lstm(xc, (h_s, c_s))
    h_s = h_s.detach(); c_s = c_s.detach()
    chunk_outs.append(out_c)
all_out = torch.cat(chunk_outs, dim=1)

print(f'Stateful vs single-pass max diff: {(out.detach() - all_out).abs().max():.4e}')
n_params = sum(p.numel() for p in lstm.parameters())
print(f'LSTM params ({num_layers}L, H={H}, I={I}): {n_params}')
# 4 gates x (H*H + H*I + H_bias) x num_layers
expected = num_layers * 4 * (H * H + H * I + 2 * H)
print(f'Expected: {expected}  (4 gates * (H^2 + H*I + 2*H) * num_layers)')
```

## The Adding Problem — Long-Range Dependency Benchmark

The adding problem (Hochreiter and Schmidhuber 1997) tests long-range dependency learning. A sequence of length T contains random values in [0,1] with a binary mask that marks exactly two positions. The task is to output the sum of the two marked values. The LSTM must remember the first marked value (potentially at t=0) until it sees the second marker (potentially at t=T-1) — a lag of up to T steps. The baseline MSE for always predicting the mean (1.0) is 0.1667 for uniform [0,1] inputs. An LSTM trained with BPTT can solve this for T up to several hundred; a vanilla RNN fails for T>20–30.

```python
import torch
import torch.nn as nn

torch.manual_seed(42)

def make_adding_batch(B=64, T=100, device='cpu'):
    seq  = torch.rand(B, T, device=device)
    mask = torch.zeros(B, T, device=device)
    for b in range(B):
        idx = torch.randperm(T)[:2]
        mask[b, idx] = 1.0
    target = (seq * mask).sum(dim=1)   # scalar target per sequence
    x = torch.stack([seq, mask], dim=2)  # (B, T, 2)
    return x, target

H, B, epochs = 64, 128, 400
baseline_mse  = 0.1667  # Var[U1+U2] for U ~ Uniform[0,1]

for T in [30, 100, 200]:
    lstm = nn.LSTM(input_size=2, hidden_size=H, batch_first=True)
    fc   = nn.Linear(H, 1)
    opt  = torch.optim.Adam(list(lstm.parameters()) + list(fc.parameters()), lr=1e-3)
    for ep in range(epochs):
        x, y  = make_adding_batch(B, T)
        out, _ = lstm(x)
        pred   = fc(out[:, -1, :]).squeeze(1)
        loss   = nn.functional.mse_loss(pred, y)
        opt.zero_grad(); loss.backward(); opt.step()
    with torch.no_grad():
        x, y  = make_adding_batch(512, T)
        pred  = fc(lstm(x)[0][:, -1, :]).squeeze(1)
        mse   = nn.functional.mse_loss(pred, y).item()
    solved = mse < 0.01 * baseline_mse
    print(f'T={T:3d}: test MSE={mse:.6f}, baseline={baseline_mse:.4f}, '
          f'solved={solved}')
```

## Gate Activation Visualization

Visualising the forget gate activations reveals the LSTM's learned memory management strategy. On tasks requiring long-range memory (e.g., the adding problem), the forget gate near the marker position typically drops below 0.5 (selectively overwriting memory), while remaining above 0.9 for filler steps (preserving the stored value). The input gate shows the complementary pattern: high activation only when meaningful new information arrives. Inspecting gate statistics — mean, variance, fraction near 0 or 1 — is a key diagnostic for understanding LSTM failure modes.

```python
import torch
import torch.nn as nn
import numpy as np

torch.manual_seed(0)
I, H, T, B = 4, 8, 20, 1

lstm = nn.LSTM(I, H, batch_first=True)
# Initialise forget gate bias to 2.0 for strong default memory
with torch.no_grad():
    # PyTorch gate order: [input(i), forget(f), cell(g), output(o)]
    lstm.bias_ih_l0[H:2*H] = 2.0   # forget gate bias in bias_ih
    lstm.bias_hh_l0[H:2*H] = 2.0   # forget gate bias in bias_hh

x = torch.randn(B, T, I)
forget_gates = []; input_gates = []
h = torch.zeros(1, B, H); c = torch.zeros(1, B, H)

with torch.no_grad():
    for t in range(T):
        xt = x[:, t:t+1, :]              # (B, 1, I)
        _, (h, c) = lstm(xt, (h, c))
        # Recompute gates for inspection
        W_ih = lstm.weight_ih_l0          # (4H, I)
        W_hh = lstm.weight_hh_l0          # (4H, H)
        gates_raw = (W_ih @ xt.squeeze() +
                     W_hh @ h.squeeze() +
                     lstm.bias_ih_l0 + lstm.bias_hh_l0)
        i_gate = torch.sigmoid(gates_raw[:H])
        f_gate = torch.sigmoid(gates_raw[H:2*H])
        forget_gates.append(f_gate.numpy().copy())
        input_gates.append(i_gate.numpy().copy())

fg = np.array(forget_gates)  # (T, H)
ig = np.array(input_gates)
print(f'Forget gate -- mean: {fg.mean():.4f}, std: {fg.std():.4f}')
print(f'Input  gate -- mean: {ig.mean():.4f}, std: {ig.std():.4f}')
print(f'Fraction forget > 0.9 (preserving): {(fg > 0.9).mean():.2%}')
print(f'Fraction input  < 0.1 (blocking):   {(ig < 0.1).mean():.2%}')
```

## Parameter Count and Initialization

An LSTM with hidden size H and input size I has 4×(H×H + H×I + H) parameters (for bias): 4 gates × (Wₕₕ + Wₕₓ + b). For H=512, I=256: 4×(262144 + 131072 + 512) = 1,574,912 ≈ 1.6M parameters per layer. The GRU uses 3 gates: 3×(H²+H×I+H) ≈ 75% of the LSTM parameter count. A vanilla RNN uses 1 set: H²+H×I+H ≈ 25% of LSTM. The forget gate bias should be initialised to 1.0 (not 0.0): Jozefowicz et al. (2015) showed that forget gate bias = 1 outperforms 0 on nearly all tasks by ensuring the cell state is preserved by default at the start of training.

> **Forget Gate Bias Initialisation**: Always initialise the LSTM forget gate bias to 1.0 (or higher, up to 3.0 for tasks with very long dependencies). In PyTorch: with torch.no_grad(): lstm.bias_ih_l0[H:2*H].fill_(1.0); lstm.bias_hh_l0[H:2*H].fill_(1.0). This ensures the cell state is preserved by default at the start of training, giving gradients a clear path back through time from the first epoch. Forget bias = 0 (PyTorch default) causes the network to forget everything initially, making early gradient signal sparse.

## LSTM Equations Summary

| Gate / State | Equation | Purpose | Output Range |
| --- | --- | --- | --- |
| Forget gate | fₜ = σ(Wf·[hₜ₋₁, xₜ] + bf) | Decides what fraction of Cₜ₋₁ to keep | (0, 1) per dimension |
| Input gate | iₜ = σ(Wi·[hₜ₋₁, xₜ] + bi) | Decides what to write into cell state | (0, 1) per dimension |
| Candidate cell | C̃ₜ = tanh(Wc·[hₜ₋₁, xₜ] + bc) | New content to potentially write | (-1, 1) |
| Cell update | Cₜ = fₜ⊙Cₜ₋₁ + iₜ⊙C̃ₜ | Additive update — linear gradient highway | ℝ (unbounded) |
| Output gate | oₜ = σ(Wo·[hₜ₋₁, xₜ] + bo) | Decides what to expose as hidden state | (0, 1) per dimension |
| Hidden state | hₜ = oₜ⊙tanh(Cₜ) | Output passed to next layer / decoder | (-1, 1) |

## LSTM Variants

Several LSTM variants have been proposed to reduce parameters or improve performance. Peephole connections (Gers & Schmidhuber 2000) allow gates to depend on the cell state Cₜ₋₁ directly, adding H parameters per gate. The GRU (Cho 2014) merges the forget and input gates into a single update gate and eliminates the cell state, using 3 gates and 75% of LSTM parameters — often matching LSTM quality. Coupled input-forget gates (iₜ = 1−fₜ) reduce to 3 parameters sets while maintaining the additive update structure. Empirically, plain LSTM with forget bias = 1 is competitive with all variants on most benchmarks.

- Cell state Cₜ: long-term memory with additive update -- avoids repeated Whh multiplication.
- Forget gate bias = 1.0: critical init trick; PyTorch default is 0 -- always override.
- Parameter count: 4*(H^2 + H*I + H) per layer; ~4x vanilla RNN, ~1.33x GRU.
- Peephole connections: gates read Ct-1 directly -- adds H params per gate, minor improvement.
- GRU: 3 gates, no cell state, ht = (1-zt)*ht-1 + zt*h_tilde -- simpler, often comparable.
- Stacked LSTM: multiple layers (num_layers > 1 in PyTorch) -- each layer takes hidden states of previous as input.
- Dropout in LSTM: apply between layers (not within time steps) -- variational dropout for temporal consistency.

---

