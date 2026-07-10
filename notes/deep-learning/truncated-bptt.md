---
title: "Truncated BPTT — Practical Approximation for Long Sequences"
slug: "truncated-bptt"
description: "Implement TBPTT(k1,k2), compare gradient quality across chunk sizes, train a character-level language model with TBPTT, and profile memory usage versus full BPTT."
tags: ["deep-learning", "rnns", "sequence-models"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"Full BPTT through T=1000 steps requires O(T·H) memory to store all activations and runs T sequential backward passes. Truncated BPTT (TBPTT) approximates this by limiting backpropagation to k₂ steps while the forward pass can run k₁ ≥ k₂ steps before each update. The most common form is TBPTT(k,k) where k is the chunk size — forward and backward both span k steps. The hidden state is carried between chunks (allowing long-range information to propagate forward) but the gradient is detached (preventing gradient flow beyond the current chunk). This is why TBPTT learns short-range gradients accurately but cannot directly update weights based on dependencies longer than k steps."},{"type":"heading","level":2,"content":"Full BPTT Memory Problem"},{"type":"text","content":"For a sequence of length T=1000, batch size B=32, hidden size H=512: full BPTT requires storing 1000×32×512×4 bytes ≈ 64 MB of hidden states per layer, plus matching buffers for tanh inputs. With multiple layers, the memory requirement grows proportionally. More critically, the backward graph contains T×H×H ≈ 262 million nodes, making each step of the backward pass slow. Gradient checkpointing can halve the memory requirement at 50% extra compute cost, but TBPTT remains the standard for RNN training because it is simpler and more predictable."},{"type":"heading","level":2,"content":"TBPTT(k₁,k₂) Formulation"},{"type":"text","content":"TBPTT(k₁,k₂) generalises the common chunked form: k₁ is the forward stride (how many steps to advance before each update) and k₂ is the backpropagation depth (k₂ ≤ k₁). When k₁ \u003e k₂, the first k₁-k₂ steps of each stride are run without gradient tracking, then gradient is tracked for the last k₂ steps. Most implementations use k₁ = k₂ = chunk_size (Penn Treebank uses 35, word-level models often 128–256). The detached hidden state h.detach() carries forward-pass information (letting the model condition on distant history) without creating gradient paths into those distant steps."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\n\ntorch.manual_seed(0)\nT, B, I, H, O = 200, 8, 16, 64, 8\nk1, k2 = 100, 20  # forward k1 steps, backprop through k2 steps (k2 \u003c k1)\n\nrnn = nn.RNN(I, H, batch_first=True)\nfc  = nn.Linear(H, O)\nopt = torch.optim.Adam(list(rnn.parameters()) + list(fc.parameters()), lr=3e-4)\nx   = torch.randn(B, T, I)\ny   = torch.randn(B, T, O)\n\nh = torch.zeros(1, B, H)\ntotal_loss, n_updates = 0.0, 0\n\nfor start in range(0, T - k2, k1):\n    # Run k1 - k2 steps forward without gradient to advance hidden state\n    no_grad_end = min(start + k1 - k2, T)\n    if no_grad_end \u003e start:\n        with torch.no_grad():\n            _, h = rnn(x[:, start:no_grad_end, :], h)\n        h = h.detach()\n    # Backprop through only the last k2 steps\n    bwd_start = min(start + k1 - k2, T - k2)\n    bwd_end   = min(bwd_start + k2, T)\n    opt.zero_grad()\n    out, h_new = rnn(x[:, bwd_start:bwd_end, :], h.detach())\n    loss = nn.functional.mse_loss(fc(out), y[:, bwd_start:bwd_end, :])\n    loss.backward()\n    torch.nn.utils.clip_grad_norm_(rnn.parameters(), 1.0)\n    opt.step()\n    h = h_new.detach()\n    total_loss += loss.item(); n_updates += 1\n\nprint(f\u0027TBPTT(k1={k1}, k2={k2}) over T={T}\u0027)\nprint(f\u0027Updates: {n_updates}, avg loss: {total_loss / max(n_updates, 1):.6f}\u0027)\nprint(f\u0027Gradient flows only through last k2={k2} steps per update.\u0027)"},{"type":"heading","level":2,"content":"Gradient Quality vs Chunk Size"},{"type":"text","content":"As chunk size k₂ increases, the TBPTT gradient becomes a better approximation of the full BPTT gradient. The cosine similarity between the truncated and full gradient vectors measures gradient direction quality. For dependencies that decay exponentially (as with a well-behaved RNN), k₂=20 may capture 90%+ of the useful gradient signal. For tasks with long-range dependencies (e.g., matching parentheses 50 steps apart), small k₂ will fail to learn the task. The practical rule: k₂ should be at least as large as the longest dependency you need to learn."},{"type":"code","language":"python","content":"import numpy as np\n\nnp.random.seed(7)\nT, I, H = 60, 4, 8\nWhh_scale = 0.5  # stable vanishing regime\n\nWxh = np.random.randn(H, I) * 0.1\nWhh = np.random.randn(H, H) * Whh_scale / np.sqrt(H)\nbh  = np.zeros((H, 1))\nxs  = [np.random.randn(I, 1) for _ in range(T)]\n\ndef forward_chunk(xs_list, h0):\n    hs = {-1: h0}\n    for t, x in enumerate(xs_list):\n        hs[t] = np.tanh(Wxh @ x + Whh @ hs[t-1] + bh)\n    return hs\n\ndef grad_Whh(xs_list, hs, Whh):\n    dh = np.ones((H, 1)) / H; dW = np.zeros_like(Whh)\n    for t in reversed(range(len(xs_list))):\n        dt = (1 - hs[t]**2) * dh\n        dW += dt @ hs[t-1].T; dh = Whh.T @ dt\n    return dW\n\n# Full BPTT reference gradient\nhs_full = forward_chunk(xs, np.zeros((H, 1)))\ndW_ref  = grad_Whh(xs, hs_full, Whh)\n\nprint(f\u0027Chunk  Cosine Similarity  dWhh Norm  Note\u0027)\nfor chunk in [5, 10, 20, 40, 60]:\n    dW_tbptt = np.zeros_like(Whh); h_carry = np.zeros((H, 1))\n    for s in range(0, T, chunk):\n        xc = xs[s:s + chunk]\n        hc = forward_chunk(xc, h_carry)\n        dW_tbptt += grad_Whh(xc, hc, Whh)\n        h_carry = hc[len(xc) - 1].copy()\n    cos = (np.dot(dW_ref.ravel(), dW_tbptt.ravel()) /\n           (np.linalg.norm(dW_ref) * np.linalg.norm(dW_tbptt) + 1e-9))\n    note = \u0027 (full BPTT)\u0027 if chunk == T else \u0027\u0027\n    print(f\u0027{chunk:\u003e5}  {cos:\u003e18.6f}  {np.linalg.norm(dW_tbptt):\u003e9.4f}{note}\u0027)"},{"type":"heading","level":2,"content":"Language Model Training with TBPTT"},{"type":"text","content":"Character-level language models are trained by predicting the next character given all previous characters. The standard TBPTT implementation: (1) tokenise text into integers, (2) chunk the token sequence into blocks of size k, (3) for each block run a forward pass and backward pass, (4) carry the hidden state between blocks with h.detach(). This is the exact setup used in Mikolov (2010) and Karpathy\u0027s char-rnn. Chunk size 35 matches the Penn Treebank benchmark; modern implementations often use 128–256. Loss is cross-entropy over the vocabulary; perplexity = exp(cross-entropy) is the standard evaluation metric."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\n\ntorch.manual_seed(42)\ntext  = \u0027the quick brown fox jumps over the lazy dog \u0027 * 40\nchars = sorted(set(text))\nc2i   = {c: i for i, c in enumerate(chars)}\nvocab = len(chars)\ndata  = torch.tensor([c2i[c] for c in text], dtype=torch.long)\nT_data, chunk, H, B = len(data) - 1, 35, 64, 1\n\nemb = nn.Embedding(vocab, H)\nrnn = nn.RNN(H, H, batch_first=True)\nfc  = nn.Linear(H, vocab)\nparams = list(emb.parameters()) + list(rnn.parameters()) + list(fc.parameters())\nopt    = torch.optim.Adam(params, lr=1e-3)\nh = torch.zeros(1, B, H)\ntotal_loss, n_steps = 0.0, 0\n\nfor start in range(0, T_data - chunk, chunk):\n    xc = data[start:start + chunk].unsqueeze(0)          # (1, chunk)\n    yc = data[start + 1:start + chunk + 1].unsqueeze(0)  # (1, chunk)\n    h  = h.detach()\n    embed_xc    = emb(xc)                                # (1, chunk, H)\n    hidden_out, h = rnn(embed_xc, h)                     # (1, chunk, H)\n    logits      = fc(hidden_out).view(-1, vocab)         # (chunk, vocab)\n    loss        = nn.functional.cross_entropy(logits, yc.view(-1))\n    opt.zero_grad(); loss.backward()\n    torch.nn.utils.clip_grad_norm_(rnn.parameters(), 5.0)\n    opt.step()\n    total_loss += loss.item(); n_steps += 1\n\navg_ce = total_loss / n_steps\nprint(f\u0027Char LM: vocab={vocab}, chunk={chunk} (PTB-style TBPTT)\u0027)\nprint(f\u0027Steps: {n_steps}, avg cross-entropy: {avg_ce:.4f}\u0027)\nprint(f\u0027Perplexity: {torch.exp(torch.tensor(avg_ce)).item():.2f}\u0027)"},{"type":"heading","level":2,"content":"Memory Profiling"},{"type":"text","content":"The memory advantage of TBPTT over full BPTT scales linearly with T/k. For T=1000 and k=35, TBPTT stores 28x fewer hidden state tensors. Profiling with torch.cuda.memory_allocated() or tracemalloc confirms this theoretical ratio. The autograd graph depth is also proportional to the chunk size, which affects backward pass time. Larger chunks give better gradient quality at the cost of more memory and slower backward passes — the fundamental trade-off in chunk size selection."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\n\ntorch.manual_seed(1)\nI, H, B = 16, 64, 4\nrnn = nn.RNN(I, H, batch_first=True)\n\ndef count_graph_nodes(loss_tensor):\n    visited, stack = set(), [loss_tensor.grad_fn]\n    while stack:\n        n = stack.pop()\n        if n is None or id(n) in visited:\n            continue\n        visited.add(id(n))\n        stack.extend(c for c, _ in (n.next_functions or []))\n    return len(visited)\n\nprint(f\u0027{\"T\":\u003e6} {\"Chunk\":\u003e7} {\"Method\":\u003c20} {\"Act. Mem MB\":\u003e12} {\"Graph nodes\":\u003e12}\u0027)\nbytes_per_float = 4\nfor T in [50, 100, 200]:\n    x = torch.randn(B, T, I)\n    out_full, _ = rnn(x, torch.zeros(1, B, H))\n    nodes_full  = count_graph_nodes(out_full.sum())\n    full_mb     = T * H * B * bytes_per_float / 1e6\n    print(f\u0027{T:\u003e6} {T:\u003e7} {\"Full BPTT\":\u003c20} {full_mb:\u003e12.4f} {nodes_full:\u003e12}\u0027)\n    for chunk in [10, 25]:\n        if chunk \u003e= T:\n            continue\n        out_c, _ = rnn(x[:, :chunk, :], torch.zeros(1, B, H))\n        nodes_c  = count_graph_nodes(out_c.sum())\n        mb_c     = chunk * H * B * bytes_per_float / 1e6\n        ratio    = full_mb / mb_c\n        print(f\u0027{T:\u003e6} {chunk:\u003e7} {f\"TBPTT k={chunk}\":\u003c20} {mb_c:\u003e12.4f} \u0027\n              f\u0027{nodes_c:\u003e12}  ({ratio:.1f}x less mem)\u0027)"},{"type":"heading","level":2,"content":"Practical Chunk Size Selection"},{"type":"table","headers":["Chunk Size","Gradient Quality","Memory per Chunk","Dependencies Captured","Typical Use Case"],"rows":[["10","Poor — very local gradient only","Very low — O(10·H·B)","Up to 10 steps","Simple pattern repetition, short-lag tasks"],["35","Moderate — PTB standard","Low — O(35·H·B)","Up to 35 steps","Character-level LM, Penn Treebank word-level LM"],["100","Good — captures medium-range patterns","Moderate — O(100·H·B)","Up to 100 steps","Word-level LM, machine translation sequences"],["256","Near-full BPTT quality","High — O(256·H·B)","Up to 256 steps","Long documents, modern LSTM/GRU training"]]},{"type":"heading","level":2,"content":"Trade-offs and Limitations"},{"type":"text","content":"TBPTT introduces a systematic bias: weights are updated based on local gradient signals only, so long-range patterns are learned indirectly (via the hidden state carrying information forward) rather than directly via gradient. For tasks with dependencies shorter than k, TBPTT is as good as full BPTT. For tasks where the critical signal arrives \u003ek steps before the output, TBPTT may fail to learn even if the hidden state contains the information — because the gradient cannot credit-assign back to where the information was encoded."},{"type":"callout","variant":"tip","title":"Rule of Thumb for Chunk Size","content":"Set chunk size to at least 2–3x the longest dependency you need to learn. If you\u0027re unsure, profile gradient cosine similarity between TBPTT and a short full-BPTT run on a small model. Use gradient checkpointing if you want full BPTT quality with acceptable memory: store every sqrt(T) hidden state and recompute the rest during backward."},{"type":"list","ordered":false,"items":["TBPTT(k,k): most common form — forward and backward both span k steps per chunk.","TBPTT(k1,k2) with k1\u003ek2: run k1 steps before each update; backprop only k2 steps back.","Carry h.detach() forward: hidden state carries long-range info; gradient is local only.","Chunk size 35: PTB language model benchmark standard since Mikolov (2010).","Gradient clipping (max_norm=1-5): mandatory alongside TBPTT to prevent explosions.","Gradient quality monitoring: measure cosine similarity of TBPTT vs full BPTT on a small held-out task."]},{"type":"divider"}]"
---
# Truncated BPTT — Practical Approximation for Long Sequences

Full BPTT through T=1000 steps requires O(T·H) memory to store all activations and runs T sequential backward passes. Truncated BPTT (TBPTT) approximates this by limiting backpropagation to k₂ steps while the forward pass can run k₁ ≥ k₂ steps before each update. The most common form is TBPTT(k,k) where k is the chunk size — forward and backward both span k steps. The hidden state is carried between chunks (allowing long-range information to propagate forward) but the gradient is detached (preventing gradient flow beyond the current chunk). This is why TBPTT learns short-range gradients accurately but cannot directly update weights based on dependencies longer than k steps.

## Full BPTT Memory Problem

For a sequence of length T=1000, batch size B=32, hidden size H=512: full BPTT requires storing 1000×32×512×4 bytes ≈ 64 MB of hidden states per layer, plus matching buffers for tanh inputs. With multiple layers, the memory requirement grows proportionally. More critically, the backward graph contains T×H×H ≈ 262 million nodes, making each step of the backward pass slow. Gradient checkpointing can halve the memory requirement at 50% extra compute cost, but TBPTT remains the standard for RNN training because it is simpler and more predictable.

## TBPTT(k₁,k₂) Formulation

TBPTT(k₁,k₂) generalises the common chunked form: k₁ is the forward stride (how many steps to advance before each update) and k₂ is the backpropagation depth (k₂ ≤ k₁). When k₁ > k₂, the first k₁-k₂ steps of each stride are run without gradient tracking, then gradient is tracked for the last k₂ steps. Most implementations use k₁ = k₂ = chunk_size (Penn Treebank uses 35, word-level models often 128–256). The detached hidden state h.detach() carries forward-pass information (letting the model condition on distant history) without creating gradient paths into those distant steps.

```python
import torch
import torch.nn as nn

torch.manual_seed(0)
T, B, I, H, O = 200, 8, 16, 64, 8
k1, k2 = 100, 20  # forward k1 steps, backprop through k2 steps (k2 < k1)

rnn = nn.RNN(I, H, batch_first=True)
fc  = nn.Linear(H, O)
opt = torch.optim.Adam(list(rnn.parameters()) + list(fc.parameters()), lr=3e-4)
x   = torch.randn(B, T, I)
y   = torch.randn(B, T, O)

h = torch.zeros(1, B, H)
total_loss, n_updates = 0.0, 0

for start in range(0, T - k2, k1):
    # Run k1 - k2 steps forward without gradient to advance hidden state
    no_grad_end = min(start + k1 - k2, T)
    if no_grad_end > start:
        with torch.no_grad():
            _, h = rnn(x[:, start:no_grad_end, :], h)
        h = h.detach()
    # Backprop through only the last k2 steps
    bwd_start = min(start + k1 - k2, T - k2)
    bwd_end   = min(bwd_start + k2, T)
    opt.zero_grad()
    out, h_new = rnn(x[:, bwd_start:bwd_end, :], h.detach())
    loss = nn.functional.mse_loss(fc(out), y[:, bwd_start:bwd_end, :])
    loss.backward()
    torch.nn.utils.clip_grad_norm_(rnn.parameters(), 1.0)
    opt.step()
    h = h_new.detach()
    total_loss += loss.item(); n_updates += 1

print(f'TBPTT(k1={k1}, k2={k2}) over T={T}')
print(f'Updates: {n_updates}, avg loss: {total_loss / max(n_updates, 1):.6f}')
print(f'Gradient flows only through last k2={k2} steps per update.')
```

## Gradient Quality vs Chunk Size

As chunk size k₂ increases, the TBPTT gradient becomes a better approximation of the full BPTT gradient. The cosine similarity between the truncated and full gradient vectors measures gradient direction quality. For dependencies that decay exponentially (as with a well-behaved RNN), k₂=20 may capture 90%+ of the useful gradient signal. For tasks with long-range dependencies (e.g., matching parentheses 50 steps apart), small k₂ will fail to learn the task. The practical rule: k₂ should be at least as large as the longest dependency you need to learn.

```python
import numpy as np

np.random.seed(7)
T, I, H = 60, 4, 8
Whh_scale = 0.5  # stable vanishing regime

Wxh = np.random.randn(H, I) * 0.1
Whh = np.random.randn(H, H) * Whh_scale / np.sqrt(H)
bh  = np.zeros((H, 1))
xs  = [np.random.randn(I, 1) for _ in range(T)]

def forward_chunk(xs_list, h0):
    hs = {-1: h0}
    for t, x in enumerate(xs_list):
        hs[t] = np.tanh(Wxh @ x + Whh @ hs[t-1] + bh)
    return hs

def grad_Whh(xs_list, hs, Whh):
    dh = np.ones((H, 1)) / H; dW = np.zeros_like(Whh)
    for t in reversed(range(len(xs_list))):
        dt = (1 - hs[t]**2) * dh
        dW += dt @ hs[t-1].T; dh = Whh.T @ dt
    return dW

# Full BPTT reference gradient
hs_full = forward_chunk(xs, np.zeros((H, 1)))
dW_ref  = grad_Whh(xs, hs_full, Whh)

print(f'Chunk  Cosine Similarity  dWhh Norm  Note')
for chunk in [5, 10, 20, 40, 60]:
    dW_tbptt = np.zeros_like(Whh); h_carry = np.zeros((H, 1))
    for s in range(0, T, chunk):
        xc = xs[s:s + chunk]
        hc = forward_chunk(xc, h_carry)
        dW_tbptt += grad_Whh(xc, hc, Whh)
        h_carry = hc[len(xc) - 1].copy()
    cos = (np.dot(dW_ref.ravel(), dW_tbptt.ravel()) /
           (np.linalg.norm(dW_ref) * np.linalg.norm(dW_tbptt) + 1e-9))
    note = ' (full BPTT)' if chunk == T else ''
    print(f'{chunk:>5}  {cos:>18.6f}  {np.linalg.norm(dW_tbptt):>9.4f}{note}')
```

## Language Model Training with TBPTT

Character-level language models are trained by predicting the next character given all previous characters. The standard TBPTT implementation: (1) tokenise text into integers, (2) chunk the token sequence into blocks of size k, (3) for each block run a forward pass and backward pass, (4) carry the hidden state between blocks with h.detach(). This is the exact setup used in Mikolov (2010) and Karpathy's char-rnn. Chunk size 35 matches the Penn Treebank benchmark; modern implementations often use 128–256. Loss is cross-entropy over the vocabulary; perplexity = exp(cross-entropy) is the standard evaluation metric.

```python
import torch
import torch.nn as nn

torch.manual_seed(42)
text  = 'the quick brown fox jumps over the lazy dog ' * 40
chars = sorted(set(text))
c2i   = {c: i for i, c in enumerate(chars)}
vocab = len(chars)
data  = torch.tensor([c2i[c] for c in text], dtype=torch.long)
T_data, chunk, H, B = len(data) - 1, 35, 64, 1

emb = nn.Embedding(vocab, H)
rnn = nn.RNN(H, H, batch_first=True)
fc  = nn.Linear(H, vocab)
params = list(emb.parameters()) + list(rnn.parameters()) + list(fc.parameters())
opt    = torch.optim.Adam(params, lr=1e-3)
h = torch.zeros(1, B, H)
total_loss, n_steps = 0.0, 0

for start in range(0, T_data - chunk, chunk):
    xc = data[start:start + chunk].unsqueeze(0)          # (1, chunk)
    yc = data[start + 1:start + chunk + 1].unsqueeze(0)  # (1, chunk)
    h  = h.detach()
    embed_xc    = emb(xc)                                # (1, chunk, H)
    hidden_out, h = rnn(embed_xc, h)                     # (1, chunk, H)
    logits      = fc(hidden_out).view(-1, vocab)         # (chunk, vocab)
    loss        = nn.functional.cross_entropy(logits, yc.view(-1))
    opt.zero_grad(); loss.backward()
    torch.nn.utils.clip_grad_norm_(rnn.parameters(), 5.0)
    opt.step()
    total_loss += loss.item(); n_steps += 1

avg_ce = total_loss / n_steps
print(f'Char LM: vocab={vocab}, chunk={chunk} (PTB-style TBPTT)')
print(f'Steps: {n_steps}, avg cross-entropy: {avg_ce:.4f}')
print(f'Perplexity: {torch.exp(torch.tensor(avg_ce)).item():.2f}')
```

## Memory Profiling

The memory advantage of TBPTT over full BPTT scales linearly with T/k. For T=1000 and k=35, TBPTT stores 28x fewer hidden state tensors. Profiling with torch.cuda.memory_allocated() or tracemalloc confirms this theoretical ratio. The autograd graph depth is also proportional to the chunk size, which affects backward pass time. Larger chunks give better gradient quality at the cost of more memory and slower backward passes — the fundamental trade-off in chunk size selection.

```python
import torch
import torch.nn as nn

torch.manual_seed(1)
I, H, B = 16, 64, 4
rnn = nn.RNN(I, H, batch_first=True)

def count_graph_nodes(loss_tensor):
    visited, stack = set(), [loss_tensor.grad_fn]
    while stack:
        n = stack.pop()
        if n is None or id(n) in visited:
            continue
        visited.add(id(n))
        stack.extend(c for c, _ in (n.next_functions or []))
    return len(visited)

print(f'{"T":>6} {"Chunk":>7} {"Method":<20} {"Act. Mem MB":>12} {"Graph nodes":>12}')
bytes_per_float = 4
for T in [50, 100, 200]:
    x = torch.randn(B, T, I)
    out_full, _ = rnn(x, torch.zeros(1, B, H))
    nodes_full  = count_graph_nodes(out_full.sum())
    full_mb     = T * H * B * bytes_per_float / 1e6
    print(f'{T:>6} {T:>7} {"Full BPTT":<20} {full_mb:>12.4f} {nodes_full:>12}')
    for chunk in [10, 25]:
        if chunk >= T:
            continue
        out_c, _ = rnn(x[:, :chunk, :], torch.zeros(1, B, H))
        nodes_c  = count_graph_nodes(out_c.sum())
        mb_c     = chunk * H * B * bytes_per_float / 1e6
        ratio    = full_mb / mb_c
        print(f'{T:>6} {chunk:>7} {f"TBPTT k={chunk}":<20} {mb_c:>12.4f} '
              f'{nodes_c:>12}  ({ratio:.1f}x less mem)')
```

## Practical Chunk Size Selection

| Chunk Size | Gradient Quality | Memory per Chunk | Dependencies Captured | Typical Use Case |
| --- | --- | --- | --- | --- |
| 10 | Poor — very local gradient only | Very low — O(10·H·B) | Up to 10 steps | Simple pattern repetition, short-lag tasks |
| 35 | Moderate — PTB standard | Low — O(35·H·B) | Up to 35 steps | Character-level LM, Penn Treebank word-level LM |
| 100 | Good — captures medium-range patterns | Moderate — O(100·H·B) | Up to 100 steps | Word-level LM, machine translation sequences |
| 256 | Near-full BPTT quality | High — O(256·H·B) | Up to 256 steps | Long documents, modern LSTM/GRU training |

## Trade-offs and Limitations

TBPTT introduces a systematic bias: weights are updated based on local gradient signals only, so long-range patterns are learned indirectly (via the hidden state carrying information forward) rather than directly via gradient. For tasks with dependencies shorter than k, TBPTT is as good as full BPTT. For tasks where the critical signal arrives >k steps before the output, TBPTT may fail to learn even if the hidden state contains the information — because the gradient cannot credit-assign back to where the information was encoded.

> **Rule of Thumb for Chunk Size**: Set chunk size to at least 2–3x the longest dependency you need to learn. If you're unsure, profile gradient cosine similarity between TBPTT and a short full-BPTT run on a small model. Use gradient checkpointing if you want full BPTT quality with acceptable memory: store every sqrt(T) hidden state and recompute the rest during backward.

- TBPTT(k,k): most common form — forward and backward both span k steps per chunk.
- TBPTT(k1,k2) with k1>k2: run k1 steps before each update; backprop only k2 steps back.
- Carry h.detach() forward: hidden state carries long-range info; gradient is local only.
- Chunk size 35: PTB language model benchmark standard since Mikolov (2010).
- Gradient clipping (max_norm=1-5): mandatory alongside TBPTT to prevent explosions.
- Gradient quality monitoring: measure cosine similarity of TBPTT vs full BPTT on a small held-out task.

---

