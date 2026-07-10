---
title: "Backpropagation Through Time (BPTT) — Unrolling and Gradient Computation"
slug: "backprop-through-time"
description: "Derive BPTT by unrolling the RNN computational graph, compute gradient products across timesteps, visualise vanishing and exploding gradients, implement full vs truncated BPTT, and apply gradient clipping."
tags: ["deep-learning", "rnns", "sequence-models"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"Backpropagation Through Time (BPTT) is the algorithm used to train RNNs. The key idea is to unroll the RNN for T steps, creating a deep feedforward computational graph with shared weights. Standard backpropagation is then applied to this unrolled graph. The gradient of the loss with respect to the recurrent weight matrix Wₕₕ accumulates contributions from every timestep: dL/dWₕₕ = Σₜ dLₜ/dWₕₕ. Each term involves a product of Jacobians ∂hₜ/∂hₜ₋₁ = Wₕₕᵀ · diag(tanh\u0027(hₜ)), which causes gradients to either vanish (if ‖Wₕₕ‖\u003c1) or explode (if ‖Wₕₕ‖\u003e1) exponentially with T."},{"type":"heading","level":2,"content":"Unrolling the Computational Graph"},{"type":"text","content":"Unrolling creates T copies of the RNN cell sharing the same weights. The computational graph has T nodes for hidden states h₀, h₁, ..., hₜ₋₁ and T nodes for outputs y₀, ..., yₜ₋₁. All edges from hₜ₋₁ to hₜ pass through the same Wₕₕ. During forward pass, all T hidden states must be computed sequentially and stored in memory for the backward pass — this gives O(T·H) memory requirement. The backward pass then traverses the graph in reverse: from the final loss back through every hidden state to the first."},{"type":"code","language":"python","content":"import numpy as np\n\nnp.random.seed(42)\nT, I, H, O = 10, 4, 8, 2\n\n# Initialize weights\nWxh = np.random.randn(H, I) * 0.1\nWhh = np.random.randn(H, H) * 0.1\nWhy = np.random.randn(O, H) * 0.1\nbh  = np.zeros((H, 1))\nby  = np.zeros((O, 1))\nxs  = [np.random.randn(I, 1) for _ in range(T)]\n\n# Forward pass -- store all hidden states (needed for backward)\nhs  = {-1: np.zeros((H, 1))}\nraw = {}\nfor t in range(T):\n    raw[t] = Wxh @ xs[t] + Whh @ hs[t-1] + bh\n    hs[t]  = np.tanh(raw[t])\nout = Why @ hs[T-1] + by\n\n# Backward pass through time -- unroll all T steps\ndy   = out - np.ones((O, 1))   # gradient of MSE loss\ndWhy = dy @ hs[T-1].T\ndWxh = np.zeros_like(Wxh)\ndWhh = np.zeros_like(Whh)\ndbh  = np.zeros_like(bh)\ndh   = Why.T @ dy\ngrad_norms = []\n\nfor t in reversed(range(T)):\n    dtanh = (1 - hs[t]**2) * dh   # backprop through tanh\n    dWhh += dtanh @ hs[t-1].T     # accumulate Whh gradient\n    dWxh += dtanh @ xs[t].T\n    dbh  += dtanh\n    grad_norms.append(float(np.linalg.norm(dh)))\n    dh    = Whh.T @ dtanh          # propagate through Whh\n\nprint(\u0027BPTT gradient norms flowing back through time (latest to earliest):\u0027)\nfor i, n in enumerate(grad_norms):\n    print(f\u0027  step {T-1-i:2d}: {n:.6f}\u0027)"},{"type":"heading","level":2,"content":"Gradient Flow Through Time"},{"type":"text","content":"The gradient of the loss at step T with respect to the hidden state at step k is: dLₜ/dhₖ = (dLₜ/dhₜ) · Πⱼ₌ₖ₊₁ᵀ (∂hⱼ/∂hⱼ₋₁). Each factor ∂hⱼ/∂hⱼ₋₁ = Wₕₕᵀ · diag(1 - hⱼ²). If the largest singular value σ_max(Wₕₕ) \u003c 1, then ‖∂hⱼ/∂hⱼ₋₁‖ \u003c 1 and the product decays exponentially with T-k. If σ_max \u003e 1, the product grows exponentially. The tanh saturation factor (1-hⱼ²) ∈ [0,1] further reduces gradient magnitude, making vanishing more likely than exploding in practice."},{"type":"code","language":"python","content":"import numpy as np\n\nnp.random.seed(0)\nT, H, I = 30, 16, 4\n\ndef gradient_norm_profile(Whh_scale, T=30, H=16, I=4):\n    np.random.seed(0)\n    Wxh = np.random.randn(H, I) * 0.1\n    Whh = np.random.randn(H, H) * Whh_scale / np.sqrt(H)\n    bh  = np.zeros((H, 1))\n    xs  = [np.random.randn(I, 1) for _ in range(T)]\n    hs  = {-1: np.zeros((H, 1))}\n    for t in range(T):\n        hs[t] = np.tanh(Wxh @ xs[t] + Whh @ hs[t-1] + bh)\n    dh = np.ones((H, 1)) / H\n    norms = {}\n    for t in reversed(range(T)):\n        norms[t] = float(np.linalg.norm(dh))\n        dtanh    = (1 - hs[t]**2) * dh\n        dh       = Whh.T @ dtanh\n    return [norms[t] for t in range(T)]\n\nprint(f\u0027Gradient magnitude at selected timesteps (loss at t={T-1}):\u0027)\nprint(f\u0027{\"Scale\":\u003e8} {\"t=T-1\":\u003e10} {\"t=T/2\":\u003e10} {\"t=0\":\u003e10} {\"Regime\":\u003e12}\u0027)\nfor scale, label in [(0.5, \u0027vanishing\u0027), (1.0, \u0027marginal\u0027), (2.0, \u0027exploding\u0027)]:\n    norms = gradient_norm_profile(scale)\n    t_half = T // 2\n    print(f\u0027{scale:\u003e8.1f} {norms[T-1]:\u003e10.4e} {norms[t_half]:\u003e10.4e} \u0027\n          f\u0027{norms[0]:\u003e10.4e} {label:\u003e12}\u0027)\nprint(\u0027Ratio norms[0]/norms[T-1] shows exponential change across T steps.\u0027)"},{"type":"heading","level":2,"content":"Gradient Vanishing and Exploding Analysis"},{"type":"text","content":"Vanishing gradient: when ‖Wₕₕ‖ \u003c 1, gradients approaching from far-away timesteps become negligibly small. The weight update dL/dWₕₕ = Σₜ dLₜ/dWₕₕ is dominated by recent timesteps; the model cannot learn dependencies longer than ~10–20 steps with random initialisation. Exploding gradient: when ‖Wₕₕ‖ \u003e 1, gradients blow up, causing NaN losses. Gradient clipping — scaling the gradient when ‖g‖ \u003e threshold — is the standard fix for explosions. Clipping does not fix vanishing gradients; that requires architectural changes (LSTM/GRU) or careful initialisation."},{"type":"heading","level":2,"content":"Full BPTT vs Truncated BPTT"},{"type":"text","content":"Full BPTT unrolls the entire sequence of T steps. For T=1000 and H=512, storing all hidden states requires 1000×512×4 bytes ≈ 2 MB per sequence (per batch element). More importantly, the backward pass is also sequential over T steps. Truncated BPTT (TBPTT) limits the backward pass to the last k steps: the sequence is split into chunks of size k, the hidden state is carried forward (without gradient) from one chunk to the next, and backpropagation only goes k steps back. This reduces memory to O(k·H) and enables approximate but practical training."},{"type":"code","language":"python","content":"import numpy as np\n\nnp.random.seed(7)\nT, I, H = 40, 4, 8\nWhh_scale = 0.5   # vanishing regime for clear demonstration\n\nWxh = np.random.randn(H, I) * 0.1\nWhh = np.random.randn(H, H) * Whh_scale / np.sqrt(H)\nbh  = np.zeros((H, 1))\nxs  = [np.random.randn(I, 1) for _ in range(T)]\n\ndef forward_all(xs, h0):\n    hs = {-1: h0}\n    for t, x in enumerate(xs):\n        hs[t] = np.tanh(Wxh @ x + Whh @ hs[t-1] + bh)\n    return hs\n\ndef bptt_gradient(xs, hs, k_back):\n    dh = np.ones((H, 1)) / H; dW = np.zeros_like(Whh)\n    T_chunk = len(xs)\n    for t in reversed(range(max(0, T_chunk - k_back), T_chunk)):\n        dt = (1 - hs[t]**2) * dh\n        dW += dt @ hs[t-1].T\n        dh  = Whh.T @ dt\n    return dW\n\nhs_full = forward_all(xs, np.zeros((H, 1)))\ndW_full = bptt_gradient(xs, hs_full, T)   # full BPTT\n\nprint(f\u0027Full BPTT (k={T}): dWhh norm = {np.linalg.norm(dW_full):.6f}\u0027)\nfor k in [5, 10, 20, T]:\n    dW_k = bptt_gradient(xs, hs_full, k)\n    cos  = np.dot(dW_full.ravel(), dW_k.ravel()) / (\n               np.linalg.norm(dW_full) * np.linalg.norm(dW_k) + 1e-9)\n    print(f\u0027  Truncated k={k:2d}: cosine similarity={cos:.4f}, norm={np.linalg.norm(dW_k):.4f}\u0027)"},{"type":"heading","level":2,"content":"Detaching Hidden State"},{"type":"text","content":"In PyTorch, h.detach() creates a new tensor that shares the same data but has no gradient tracking. When passed as the initial state to the next chunk, gradients from that chunk cannot flow back through the detached tensor into the previous chunk\u0027s computation graph. This is essential for memory-efficient training of long sequences: without detach, the backward pass would need to traverse the entire accumulated graph, defeating the purpose of chunking. The pattern is: h = h.detach() before each chunk\u0027s forward pass."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\n\ntorch.manual_seed(42)\nT, chunk, I, H, O, B = 100, 20, 8, 32, 4, 4\n\nrnn = nn.RNN(I, H, batch_first=True)\nfc  = nn.Linear(H, O)\nopt = torch.optim.Adam(list(rnn.parameters()) + list(fc.parameters()), lr=1e-3)\nx   = torch.randn(B, T, I)\ny   = torch.randn(B, T, O)\n\ntotal_loss = 0.0\nh = torch.zeros(1, B, H)\nfor start in range(0, T, chunk):\n    xc   = x[:, start:start + chunk, :]\n    yc   = y[:, start:start + chunk, :]\n    h_in = h.detach()          # stop gradient from flowing into prev chunk\n    opt.zero_grad()\n    out, h = rnn(xc, h_in)\n    loss = nn.functional.mse_loss(fc(out), yc)\n    loss.backward()\n    torch.nn.utils.clip_grad_norm_(rnn.parameters(), max_norm=1.0)\n    opt.step()\n    total_loss += loss.item()\n\nn_chunks = T // chunk\nprint(f\u0027TBPTT training: {n_chunks} chunks x {chunk} steps\u0027)\nprint(f\u0027Avg chunk loss: {total_loss / n_chunks:.6f}\u0027)\nprint(\u0027h.detach() breaks gradient graph -- memory is O(chunk * H) per step.\u0027)\nprint(f\u0027Savings vs full BPTT: {T // chunk}x less graph nodes to store.\u0027)"},{"type":"heading","level":2,"content":"Memory Requirements"},{"type":"text","content":"Full BPTT must store all T hidden states for the backward pass: O(T·H·B·4) bytes (float32). For T=1000, H=512, B=32: 1000×512×32×4 ≈ 64 MB per layer. Truncated BPTT with chunk k stores only k hidden states: O(k·H·B·4) bytes. Additionally, storing raw pre-activation values for backpropagating through tanh doubles this estimate. Gradient checkpointing can trade recomputation for memory, storing only every √T hidden state and recomputing the rest during backward — reducing memory to O(√T·H) at the cost of ~1.5x forward passes."},{"type":"callout","variant":"info","title":"Gradient Clipping Is Essential","content":"Always apply gradient clipping when training RNNs. The standard threshold is max_norm=1.0 to 5.0 (use torch.nn.utils.clip_grad_norm_). Without clipping, a single step with ‖Wₕₕ‖\u003e1 can cause explosive gradient growth, resulting in NaN parameters. Clipping does not prevent vanishing gradients — for that, use LSTM/GRU architectures or gradient highway connections."},{"type":"heading","level":2,"content":"Gradient Clipping"},{"type":"text","content":"Gradient clipping rescales the gradient vector when its norm exceeds a threshold: if ‖g‖ \u003e θ, set g ← g·(θ/‖g‖). This preserves gradient direction while bounding its magnitude. The threshold θ is a hyperparameter typically set between 1.0 and 10.0; lower values are safer but may slow convergence. Global clipping (across all parameters) is preferred over per-parameter clipping. Monitoring the fraction of steps where clipping activates is useful diagnostics: \u003e50% activation suggests the threshold is too low; 0% means it may be too high or gradients are well-behaved."},{"type":"table","headers":["Method","Memory","Gradient Quality","Parallelizable","Long-Range Capture"],"rows":[["Full BPTT","O(T·H·B) — stores all hidden states","Exact gradient","No — sequential unroll over T","Yes — gradient flows from t=T to t=0"],["Truncated BPTT (k)","O(k·H·B) — only k states","Approximation — local gradient only","No — still sequential","Only within k steps; no signal for lag \u003e k"],["Real-Time Recurrent Learning","O(H²) per step — online","Exact but online (per-step)","Yes — one step at a time","Yes — H² parameter gradients per step"]]},{"type":"list","ordered":false,"items":["Full BPTT: exact gradients but O(T) memory and time; infeasible for T \u003e a few hundred.","Truncated BPTT: standard in practice; chunk sizes of 35–256 are common; gradient is biased for long lags.","Gradient checkpointing: O(sqrt(T)) memory, 1.5x compute; useful when T is large but not extreme.","RTRL: online learning with exact gradients but O(H^4) compute per step — only practical for tiny H.","Gradient clipping (max_norm=1-5): prevents explosions; mandatory for stable RNN training.","Orthogonal Whh init: spectral radius = 1 at initialisation; delays vanishing gradient onset."]},{"type":"divider"}]"
---
# Backpropagation Through Time (BPTT) — Unrolling and Gradient Computation

Backpropagation Through Time (BPTT) is the algorithm used to train RNNs. The key idea is to unroll the RNN for T steps, creating a deep feedforward computational graph with shared weights. Standard backpropagation is then applied to this unrolled graph. The gradient of the loss with respect to the recurrent weight matrix Wₕₕ accumulates contributions from every timestep: dL/dWₕₕ = Σₜ dLₜ/dWₕₕ. Each term involves a product of Jacobians ∂hₜ/∂hₜ₋₁ = Wₕₕᵀ · diag(tanh'(hₜ)), which causes gradients to either vanish (if ‖Wₕₕ‖<1) or explode (if ‖Wₕₕ‖>1) exponentially with T.

## Unrolling the Computational Graph

Unrolling creates T copies of the RNN cell sharing the same weights. The computational graph has T nodes for hidden states h₀, h₁, ..., hₜ₋₁ and T nodes for outputs y₀, ..., yₜ₋₁. All edges from hₜ₋₁ to hₜ pass through the same Wₕₕ. During forward pass, all T hidden states must be computed sequentially and stored in memory for the backward pass — this gives O(T·H) memory requirement. The backward pass then traverses the graph in reverse: from the final loss back through every hidden state to the first.

```python
import numpy as np

np.random.seed(42)
T, I, H, O = 10, 4, 8, 2

# Initialize weights
Wxh = np.random.randn(H, I) * 0.1
Whh = np.random.randn(H, H) * 0.1
Why = np.random.randn(O, H) * 0.1
bh  = np.zeros((H, 1))
by  = np.zeros((O, 1))
xs  = [np.random.randn(I, 1) for _ in range(T)]

# Forward pass -- store all hidden states (needed for backward)
hs  = {-1: np.zeros((H, 1))}
raw = {}
for t in range(T):
    raw[t] = Wxh @ xs[t] + Whh @ hs[t-1] + bh
    hs[t]  = np.tanh(raw[t])
out = Why @ hs[T-1] + by

# Backward pass through time -- unroll all T steps
dy   = out - np.ones((O, 1))   # gradient of MSE loss
dWhy = dy @ hs[T-1].T
dWxh = np.zeros_like(Wxh)
dWhh = np.zeros_like(Whh)
dbh  = np.zeros_like(bh)
dh   = Why.T @ dy
grad_norms = []

for t in reversed(range(T)):
    dtanh = (1 - hs[t]**2) * dh   # backprop through tanh
    dWhh += dtanh @ hs[t-1].T     # accumulate Whh gradient
    dWxh += dtanh @ xs[t].T
    dbh  += dtanh
    grad_norms.append(float(np.linalg.norm(dh)))
    dh    = Whh.T @ dtanh          # propagate through Whh

print('BPTT gradient norms flowing back through time (latest to earliest):')
for i, n in enumerate(grad_norms):
    print(f'  step {T-1-i:2d}: {n:.6f}')
```

## Gradient Flow Through Time

The gradient of the loss at step T with respect to the hidden state at step k is: dLₜ/dhₖ = (dLₜ/dhₜ) · Πⱼ₌ₖ₊₁ᵀ (∂hⱼ/∂hⱼ₋₁). Each factor ∂hⱼ/∂hⱼ₋₁ = Wₕₕᵀ · diag(1 - hⱼ²). If the largest singular value σ_max(Wₕₕ) < 1, then ‖∂hⱼ/∂hⱼ₋₁‖ < 1 and the product decays exponentially with T-k. If σ_max > 1, the product grows exponentially. The tanh saturation factor (1-hⱼ²) ∈ [0,1] further reduces gradient magnitude, making vanishing more likely than exploding in practice.

```python
import numpy as np

np.random.seed(0)
T, H, I = 30, 16, 4

def gradient_norm_profile(Whh_scale, T=30, H=16, I=4):
    np.random.seed(0)
    Wxh = np.random.randn(H, I) * 0.1
    Whh = np.random.randn(H, H) * Whh_scale / np.sqrt(H)
    bh  = np.zeros((H, 1))
    xs  = [np.random.randn(I, 1) for _ in range(T)]
    hs  = {-1: np.zeros((H, 1))}
    for t in range(T):
        hs[t] = np.tanh(Wxh @ xs[t] + Whh @ hs[t-1] + bh)
    dh = np.ones((H, 1)) / H
    norms = {}
    for t in reversed(range(T)):
        norms[t] = float(np.linalg.norm(dh))
        dtanh    = (1 - hs[t]**2) * dh
        dh       = Whh.T @ dtanh
    return [norms[t] for t in range(T)]

print(f'Gradient magnitude at selected timesteps (loss at t={T-1}):')
print(f'{"Scale":>8} {"t=T-1":>10} {"t=T/2":>10} {"t=0":>10} {"Regime":>12}')
for scale, label in [(0.5, 'vanishing'), (1.0, 'marginal'), (2.0, 'exploding')]:
    norms = gradient_norm_profile(scale)
    t_half = T // 2
    print(f'{scale:>8.1f} {norms[T-1]:>10.4e} {norms[t_half]:>10.4e} '
          f'{norms[0]:>10.4e} {label:>12}')
print('Ratio norms[0]/norms[T-1] shows exponential change across T steps.')
```

## Gradient Vanishing and Exploding Analysis

Vanishing gradient: when ‖Wₕₕ‖ < 1, gradients approaching from far-away timesteps become negligibly small. The weight update dL/dWₕₕ = Σₜ dLₜ/dWₕₕ is dominated by recent timesteps; the model cannot learn dependencies longer than ~10–20 steps with random initialisation. Exploding gradient: when ‖Wₕₕ‖ > 1, gradients blow up, causing NaN losses. Gradient clipping — scaling the gradient when ‖g‖ > threshold — is the standard fix for explosions. Clipping does not fix vanishing gradients; that requires architectural changes (LSTM/GRU) or careful initialisation.

## Full BPTT vs Truncated BPTT

Full BPTT unrolls the entire sequence of T steps. For T=1000 and H=512, storing all hidden states requires 1000×512×4 bytes ≈ 2 MB per sequence (per batch element). More importantly, the backward pass is also sequential over T steps. Truncated BPTT (TBPTT) limits the backward pass to the last k steps: the sequence is split into chunks of size k, the hidden state is carried forward (without gradient) from one chunk to the next, and backpropagation only goes k steps back. This reduces memory to O(k·H) and enables approximate but practical training.

```python
import numpy as np

np.random.seed(7)
T, I, H = 40, 4, 8
Whh_scale = 0.5   # vanishing regime for clear demonstration

Wxh = np.random.randn(H, I) * 0.1
Whh = np.random.randn(H, H) * Whh_scale / np.sqrt(H)
bh  = np.zeros((H, 1))
xs  = [np.random.randn(I, 1) for _ in range(T)]

def forward_all(xs, h0):
    hs = {-1: h0}
    for t, x in enumerate(xs):
        hs[t] = np.tanh(Wxh @ x + Whh @ hs[t-1] + bh)
    return hs

def bptt_gradient(xs, hs, k_back):
    dh = np.ones((H, 1)) / H; dW = np.zeros_like(Whh)
    T_chunk = len(xs)
    for t in reversed(range(max(0, T_chunk - k_back), T_chunk)):
        dt = (1 - hs[t]**2) * dh
        dW += dt @ hs[t-1].T
        dh  = Whh.T @ dt
    return dW

hs_full = forward_all(xs, np.zeros((H, 1)))
dW_full = bptt_gradient(xs, hs_full, T)   # full BPTT

print(f'Full BPTT (k={T}): dWhh norm = {np.linalg.norm(dW_full):.6f}')
for k in [5, 10, 20, T]:
    dW_k = bptt_gradient(xs, hs_full, k)
    cos  = np.dot(dW_full.ravel(), dW_k.ravel()) / (
               np.linalg.norm(dW_full) * np.linalg.norm(dW_k) + 1e-9)
    print(f'  Truncated k={k:2d}: cosine similarity={cos:.4f}, norm={np.linalg.norm(dW_k):.4f}')
```

## Detaching Hidden State

In PyTorch, h.detach() creates a new tensor that shares the same data but has no gradient tracking. When passed as the initial state to the next chunk, gradients from that chunk cannot flow back through the detached tensor into the previous chunk's computation graph. This is essential for memory-efficient training of long sequences: without detach, the backward pass would need to traverse the entire accumulated graph, defeating the purpose of chunking. The pattern is: h = h.detach() before each chunk's forward pass.

```python
import torch
import torch.nn as nn

torch.manual_seed(42)
T, chunk, I, H, O, B = 100, 20, 8, 32, 4, 4

rnn = nn.RNN(I, H, batch_first=True)
fc  = nn.Linear(H, O)
opt = torch.optim.Adam(list(rnn.parameters()) + list(fc.parameters()), lr=1e-3)
x   = torch.randn(B, T, I)
y   = torch.randn(B, T, O)

total_loss = 0.0
h = torch.zeros(1, B, H)
for start in range(0, T, chunk):
    xc   = x[:, start:start + chunk, :]
    yc   = y[:, start:start + chunk, :]
    h_in = h.detach()          # stop gradient from flowing into prev chunk
    opt.zero_grad()
    out, h = rnn(xc, h_in)
    loss = nn.functional.mse_loss(fc(out), yc)
    loss.backward()
    torch.nn.utils.clip_grad_norm_(rnn.parameters(), max_norm=1.0)
    opt.step()
    total_loss += loss.item()

n_chunks = T // chunk
print(f'TBPTT training: {n_chunks} chunks x {chunk} steps')
print(f'Avg chunk loss: {total_loss / n_chunks:.6f}')
print('h.detach() breaks gradient graph -- memory is O(chunk * H) per step.')
print(f'Savings vs full BPTT: {T // chunk}x less graph nodes to store.')
```

## Memory Requirements

Full BPTT must store all T hidden states for the backward pass: O(T·H·B·4) bytes (float32). For T=1000, H=512, B=32: 1000×512×32×4 ≈ 64 MB per layer. Truncated BPTT with chunk k stores only k hidden states: O(k·H·B·4) bytes. Additionally, storing raw pre-activation values for backpropagating through tanh doubles this estimate. Gradient checkpointing can trade recomputation for memory, storing only every √T hidden state and recomputing the rest during backward — reducing memory to O(√T·H) at the cost of ~1.5x forward passes.

> **Gradient Clipping Is Essential**: Always apply gradient clipping when training RNNs. The standard threshold is max_norm=1.0 to 5.0 (use torch.nn.utils.clip_grad_norm_). Without clipping, a single step with ‖Wₕₕ‖>1 can cause explosive gradient growth, resulting in NaN parameters. Clipping does not prevent vanishing gradients — for that, use LSTM/GRU architectures or gradient highway connections.

## Gradient Clipping

Gradient clipping rescales the gradient vector when its norm exceeds a threshold: if ‖g‖ > θ, set g ← g·(θ/‖g‖). This preserves gradient direction while bounding its magnitude. The threshold θ is a hyperparameter typically set between 1.0 and 10.0; lower values are safer but may slow convergence. Global clipping (across all parameters) is preferred over per-parameter clipping. Monitoring the fraction of steps where clipping activates is useful diagnostics: >50% activation suggests the threshold is too low; 0% means it may be too high or gradients are well-behaved.

| Method | Memory | Gradient Quality | Parallelizable | Long-Range Capture |
| --- | --- | --- | --- | --- |
| Full BPTT | O(T·H·B) — stores all hidden states | Exact gradient | No — sequential unroll over T | Yes — gradient flows from t=T to t=0 |
| Truncated BPTT (k) | O(k·H·B) — only k states | Approximation — local gradient only | No — still sequential | Only within k steps; no signal for lag > k |
| Real-Time Recurrent Learning | O(H²) per step — online | Exact but online (per-step) | Yes — one step at a time | Yes — H² parameter gradients per step |

- Full BPTT: exact gradients but O(T) memory and time; infeasible for T > a few hundred.
- Truncated BPTT: standard in practice; chunk sizes of 35–256 are common; gradient is biased for long lags.
- Gradient checkpointing: O(sqrt(T)) memory, 1.5x compute; useful when T is large but not extreme.
- RTRL: online learning with exact gradients but O(H^4) compute per step — only practical for tiny H.
- Gradient clipping (max_norm=1-5): prevents explosions; mandatory for stable RNN training.
- Orthogonal Whh init: spectral radius = 1 at initialisation; delays vanishing gradient onset.

---

