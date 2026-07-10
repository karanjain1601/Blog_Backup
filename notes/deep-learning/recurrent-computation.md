---
title: "Recurrent Computation — Hidden State and Weight Sharing"
slug: "recurrent-computation"
description: "Derive the RNN recurrence equation, explore weight sharing across time, understand many-to-one/many-to-many architectures, implement stateful inference for long sequences, and compare RNN vs Transformer training speed."
tags: ["deep-learning", "rnns", "sequence-models"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"A Recurrent Neural Network (RNN) processes sequences by maintaining a hidden state hₜ that summarises all information seen up to time t. At each step the same weight matrices are applied: hₜ = tanh(Wₕₓxₜ + Wₕₕhₜ₋₁ + b), yₜ = Wₒhₜ. This weight sharing across time is the defining property of RNNs — unlike a feedforward network with separate parameters per position, the RNN uses identical Wₕₕ at every step, giving it O(H²) recurrent parameters regardless of sequence length T. The same mechanism that enables variable-length processing also introduces the vanishing gradient problem and prevents parallelisation over the time axis."},{"type":"heading","level":2,"content":"The RNN Recurrence Equation"},{"type":"text","content":"The core recurrence hₜ = tanh(Wₕₓxₜ + Wₕₕhₜ₋₁ + b) composes three operations: a linear projection of the input xₜ ∈ ℝᴵ via Wₕₓ ∈ ℝᴴˣᴵ, a linear projection of the previous hidden state hₜ₋₁ ∈ ℝᴴ via Wₕₕ ∈ ℝᴴˣᴴ, and a tanh nonlinearity that squashes the result to (-1, 1). The output yₜ = Wₒhₜ is a linear readout from the hidden state via Wₒ ∈ ℝᴼˣᴴ. Total parameters: H×I (Wₕₓ) + H×H (Wₕₕ) + H×O (Wₒ) + H (bias). Computational cost per step is O(H²) for the Wₕₕhₜ₋₁ product, giving O(T·H²) total for a sequence of length T."},{"type":"heading","level":2,"content":"Weight Sharing Across Time"},{"type":"text","content":"Weight sharing means the same Wₕₕ is multiplied at every time step. This is analogous to a convolutional filter being applied at every spatial position — it allows the model to generalise temporal patterns regardless of when they occur. Theoretically, RNNs with sufficient hidden size are Turing complete: they can simulate any computable function on sequences. Practically, learning long-range dependencies is limited by the vanishing gradient problem. The hidden state hₜ must compress the entire history into H numbers, creating an information bottleneck for very long sequences."},{"type":"code","language":"python","content":"import numpy as np\n\nclass VanillaRNN:\n    def __init__(self, input_size, hidden_size, output_size):\n        scale = 0.01\n        self.Wxh = np.random.randn(hidden_size, input_size) * scale\n        self.Whh = np.random.randn(hidden_size, hidden_size) * scale\n        self.Why = np.random.randn(output_size, hidden_size) * scale\n        self.bh  = np.zeros((hidden_size, 1))\n        self.by  = np.zeros((output_size, 1))\n\n    def forward(self, inputs, h_prev):\n        self.hs = {-1: h_prev}\n        self.ys = {}\n        for t, x in enumerate(inputs):\n            self.hs[t] = np.tanh(\n                self.Wxh @ x + self.Whh @ self.hs[t - 1] + self.bh\n            )\n            self.ys[t] = self.Why @ self.hs[t] + self.by\n        return self.ys, self.hs\n\nnp.random.seed(42)\nT, I, H, O = 5, 4, 8, 3\nrnn = VanillaRNN(I, H, O)\ninputs = [np.random.randn(I, 1) for _ in range(T)]\nh0 = np.zeros((H, 1))\nys, hs = rnn.forward(inputs, h0)\nprint(f\u0027Sequence length T={T}, hidden size H={H}\u0027)\nfor t in range(T):\n    print(f\u0027  t={t}: h shape={hs[t].shape}, y shape={ys[t].shape}\u0027)\nprint(f\u0027h_T norm = {np.linalg.norm(hs[T-1]):.4f}\u0027)\nprint(\u0027Same Whh applied at every step -- weight sharing across time.\u0027)"},{"type":"heading","level":2,"content":"PyTorch nn.RNN — Many-to-One and Many-to-Many"},{"type":"text","content":"PyTorch\u0027s nn.RNN wraps the recurrence in an optimised CUDA kernel. The output tensor contains hidden states at all T steps; h_n is the final hidden state. For many-to-one tasks (classification), use h_n directly. For many-to-many (tagging, translation), use the full output sequence. One-to-many (generation) repeats a seed input for T steps. Bidirectional RNNs run one forward and one backward pass, concatenating hidden states — doubling the parameter count and output dimension."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\n\ntorch.manual_seed(42)\nT, B, I, H = 10, 4, 8, 16  # seq_len, batch, input_dim, hidden_dim\n\nrnn = nn.RNN(input_size=I, hidden_size=H, batch_first=True)\nx = torch.randn(B, T, I)\n\n# Many-to-many: use all time-step outputs\nout, h_n = rnn(x)\nprint(f\u0027Many-to-many: out.shape={out.shape}, h_n.shape={h_n.shape}\u0027)\n\n# Many-to-one: last hidden state only\nlast_hidden = h_n.squeeze(0)  # (B, H)\nprint(f\u0027Many-to-one: last_hidden.shape={last_hidden.shape}\u0027)\n\n# One-to-many: repeat single input for T steps\nsingle_input = torch.randn(B, 1, I).repeat(1, T, 1)\nout_otm, _ = rnn(single_input)\nprint(f\u0027One-to-many: out.shape={out_otm.shape}\u0027)\n\n# Bidirectional RNN\nrnn_bi = nn.RNN(input_size=I, hidden_size=H, batch_first=True, bidirectional=True)\nout_bi, h_bi = rnn_bi(x)\nprint(f\u0027Bidirectional: out.shape={out_bi.shape}, h_n.shape={h_bi.shape}\u0027)\n\ntotal_params = sum(p.numel() for p in rnn.parameters())\nprint(f\u0027Unidirectional RNN params: {total_params}\u0027)\nprint(f\u0027  Wxh: {I}x{H}={I*H}, Whh: {H}x{H}={H*H}, bh: {H}\u0027)"},{"type":"heading","level":2,"content":"Stateful Inference for Long Sequences"},{"type":"text","content":"For sequences longer than the training context (e.g., streaming audio or very long documents), the hidden state must be carried between batches. The key is to pass h_state from the previous chunk as the initial state for the next chunk. Gradients are not tracked across chunks during inference. During training, the hidden state is detached (h.detach()) to stop gradient flow into earlier chunks — this is the truncated BPTT pattern. Carrying state allows the model to use information from the entire sequence history at inference time, even if gradients only flow within chunks at training time."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\n\ntorch.manual_seed(0)\nI, H, O, B = 8, 32, 4, 2\nTOTAL_LEN = 500\nCHUNK_SIZE = 50\n\nrnn = nn.RNN(input_size=I, hidden_size=H, batch_first=True)\nfc  = nn.Linear(H, O)\nrnn.eval(); fc.eval()\n\nlong_seq = torch.randn(B, TOTAL_LEN, I)\nh_state  = torch.zeros(1, B, H)  # (num_layers, batch, hidden)\n\noutputs = []\nwith torch.no_grad():\n    for start in range(0, TOTAL_LEN, CHUNK_SIZE):\n        chunk = long_seq[:, start:start + CHUNK_SIZE, :]\n        out, h_state = rnn(chunk, h_state)\n        # h_state carries to next chunk — stateful inference\n        logits = fc(out)\n        outputs.append(logits)\n\nall_out = torch.cat(outputs, dim=1)\nprint(f\u0027Input length: {TOTAL_LEN}, chunk size: {CHUNK_SIZE}\u0027)\nprint(f\u0027Number of chunks: {TOTAL_LEN // CHUNK_SIZE}\u0027)\nprint(f\u0027Final output shape: {all_out.shape}\u0027)\nprint(f\u0027Final hidden state norm: {h_state.norm().item():.4f}\u0027)\nprint(\u0027Hidden state carried across chunks -- full-sequence context at inference.\u0027)"},{"type":"heading","level":2,"content":"RNN Architectures"},{"type":"table","headers":["Architecture","Use Case","Hidden State Handling","Batch Processing","Example Task"],"rows":[["Many-to-many (aligned)","Output at every input step","h_t used at each t","Pad to max length; mask output loss","POS tagging, NER, frame-level prediction"],["Many-to-one","Single output for whole sequence","Only final h_T used","Pad + pack sequences for efficiency","Sentiment analysis, sequence classification"],["One-to-many","Generate sequence from single input","Decoded step-by-step from h_0","Replicate input for T steps","Image captioning, music generation"],["Encoder-decoder","Map sequence to sequence of different length","Encoder h_T initialises decoder","Fixed-length bottleneck; attention needed for long seqs","Machine translation, summarization"]]},{"type":"heading","level":2,"content":"Sequential Computation and GPU Limitations"},{"type":"text","content":"The recurrence hₜ = f(hₜ₋₁, xₜ) creates a strict sequential dependency: step t cannot begin until step t-1 is complete. This prevents parallelisation over the time axis. On a GPU with thousands of cores, only the matrix multiplications Wₕₓxₜ and Wₕₕhₜ₋₁ at each single step are parallelisable — but these are small compared to what a Transformer can parallelise (all T positions simultaneously). For T=512 and H=512, an RNN requires 512 sequential matrix multiplications of size 512×512, while a Transformer computes all attention in a single batched operation."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport time\n\ntorch.manual_seed(42)\ndevice = torch.device(\u0027cuda\u0027 if torch.cuda.is_available() else \u0027cpu\u0027)\nB, T, I, H = 16, 64, 32, 64\n\nrnn = nn.RNN(input_size=I, hidden_size=H, batch_first=True).to(device)\ntf_layer = nn.TransformerEncoderLayer(\n    d_model=I, nhead=4, dim_feedforward=128, batch_first=True\n).to(device)\n\nx = torch.randn(B, T, I, device=device)\nn_iters = 50\n\n# RNN: sequential over T steps\nstart = time.perf_counter()\nfor _ in range(n_iters):\n    out_rnn, _ = rnn(x)\n    out_rnn.sum().backward()\nrnn_ms = (time.perf_counter() - start) / n_iters * 1000\n\n# Transformer: parallel over all T positions\nstart = time.perf_counter()\nfor _ in range(n_iters):\n    out_tf = tf_layer(x)\n    out_tf.sum().backward()\ntf_ms = (time.perf_counter() - start) / n_iters * 1000\n\nprint(f\u0027Device: {device}, T={T}, B={B}\u0027)\nprint(f\u0027RNN avg fwd+bwd:         {rnn_ms:.2f} ms\u0027)\nprint(f\u0027Transformer avg fwd+bwd: {tf_ms:.2f} ms\u0027)\nprint(\u0027RNN is sequential over T; Transformer parallelises all T positions.\u0027)\nprint(\u0027GPU utilisation is much lower for RNN -- T steps must be serial.\u0027)"},{"type":"heading","level":2,"content":"Computational Cost and Complexity"},{"type":"text","content":"The dominant cost per RNN step is the Wₕₕhₜ₋₁ product: O(H²) FLOPs. Over T steps, total cost is O(T·H²) for the recurrent part, plus O(T·H·I) for input projections. Memory scales as O(T·H) to store all hidden states for backpropagation. In contrast, Transformers use O(T²·D) attention (quadratic in sequence length) but O(D²) per token for feed-forward layers. For short sequences (T\u003c200), RNNs can be competitive; for T\u003e1000, the Transformer\u0027s parallelism advantage dominates on modern hardware despite its quadratic attention cost."},{"type":"callout","variant":"warning","title":"Sequential Computation Bottleneck","content":"The RNN\u0027s recurrence prevents GPU parallelisation over time. For H=512, T=256, a single forward pass requires 256 sequential matrix multiplications. This is why RNNs train 10–50x slower than Transformers on the same sequence length using modern GPUs. Transformers trade O(T²) attention memory for O(1/T) sequential steps — a worthwhile trade for T up to several thousand."},{"type":"heading","level":2,"content":"Why Transformers Replaced RNNs for Long Sequences"},{"type":"text","content":"Transformers (Vaswani et al. 2017) solve two fundamental RNN limitations: (1) sequential computation by using self-attention that connects all positions in O(1) sequential steps, and (2) the vanishing gradient problem by providing direct gradient paths from every output position to every input position. RNNs remain relevant for streaming inference (constant memory, no sequence-length limit), edge deployment (small parameter count), and tasks where causality is required without future context. However, for pre-training on long text, audio, or video, Transformers (or their linear-attention variants) are the dominant architecture."},{"type":"list","ordered":false,"items":["RNN strength: O(H) memory at inference — no KV cache needed; ideal for streaming and embedded systems.","RNN weakness: O(T) sequential steps prevent GPU parallelism; vanishing gradients limit effective memory to ~100 steps.","Transformer strength: O(1) sequential steps; direct gradient paths; scales with data and compute.","Transformer weakness: O(T²) attention memory; fixed context window; no native streaming.","LSTM/GRU mitigate vanishing gradients with gating but preserve sequential computation bottleneck.","Mamba/S4/linear RNNs aim to recover parallelisable training while retaining RNN-style inference efficiency."]},{"type":"divider"}]"
---
# Recurrent Computation — Hidden State and Weight Sharing

A Recurrent Neural Network (RNN) processes sequences by maintaining a hidden state hₜ that summarises all information seen up to time t. At each step the same weight matrices are applied: hₜ = tanh(Wₕₓxₜ + Wₕₕhₜ₋₁ + b), yₜ = Wₒhₜ. This weight sharing across time is the defining property of RNNs — unlike a feedforward network with separate parameters per position, the RNN uses identical Wₕₕ at every step, giving it O(H²) recurrent parameters regardless of sequence length T. The same mechanism that enables variable-length processing also introduces the vanishing gradient problem and prevents parallelisation over the time axis.

## The RNN Recurrence Equation

The core recurrence hₜ = tanh(Wₕₓxₜ + Wₕₕhₜ₋₁ + b) composes three operations: a linear projection of the input xₜ ∈ ℝᴵ via Wₕₓ ∈ ℝᴴˣᴵ, a linear projection of the previous hidden state hₜ₋₁ ∈ ℝᴴ via Wₕₕ ∈ ℝᴴˣᴴ, and a tanh nonlinearity that squashes the result to (-1, 1). The output yₜ = Wₒhₜ is a linear readout from the hidden state via Wₒ ∈ ℝᴼˣᴴ. Total parameters: H×I (Wₕₓ) + H×H (Wₕₕ) + H×O (Wₒ) + H (bias). Computational cost per step is O(H²) for the Wₕₕhₜ₋₁ product, giving O(T·H²) total for a sequence of length T.

## Weight Sharing Across Time

Weight sharing means the same Wₕₕ is multiplied at every time step. This is analogous to a convolutional filter being applied at every spatial position — it allows the model to generalise temporal patterns regardless of when they occur. Theoretically, RNNs with sufficient hidden size are Turing complete: they can simulate any computable function on sequences. Practically, learning long-range dependencies is limited by the vanishing gradient problem. The hidden state hₜ must compress the entire history into H numbers, creating an information bottleneck for very long sequences.

```python
import numpy as np

class VanillaRNN:
    def __init__(self, input_size, hidden_size, output_size):
        scale = 0.01
        self.Wxh = np.random.randn(hidden_size, input_size) * scale
        self.Whh = np.random.randn(hidden_size, hidden_size) * scale
        self.Why = np.random.randn(output_size, hidden_size) * scale
        self.bh  = np.zeros((hidden_size, 1))
        self.by  = np.zeros((output_size, 1))

    def forward(self, inputs, h_prev):
        self.hs = {-1: h_prev}
        self.ys = {}
        for t, x in enumerate(inputs):
            self.hs[t] = np.tanh(
                self.Wxh @ x + self.Whh @ self.hs[t - 1] + self.bh
            )
            self.ys[t] = self.Why @ self.hs[t] + self.by
        return self.ys, self.hs

np.random.seed(42)
T, I, H, O = 5, 4, 8, 3
rnn = VanillaRNN(I, H, O)
inputs = [np.random.randn(I, 1) for _ in range(T)]
h0 = np.zeros((H, 1))
ys, hs = rnn.forward(inputs, h0)
print(f'Sequence length T={T}, hidden size H={H}')
for t in range(T):
    print(f'  t={t}: h shape={hs[t].shape}, y shape={ys[t].shape}')
print(f'h_T norm = {np.linalg.norm(hs[T-1]):.4f}')
print('Same Whh applied at every step -- weight sharing across time.')
```

## PyTorch nn.RNN — Many-to-One and Many-to-Many

PyTorch's nn.RNN wraps the recurrence in an optimised CUDA kernel. The output tensor contains hidden states at all T steps; h_n is the final hidden state. For many-to-one tasks (classification), use h_n directly. For many-to-many (tagging, translation), use the full output sequence. One-to-many (generation) repeats a seed input for T steps. Bidirectional RNNs run one forward and one backward pass, concatenating hidden states — doubling the parameter count and output dimension.

```python
import torch
import torch.nn as nn

torch.manual_seed(42)
T, B, I, H = 10, 4, 8, 16  # seq_len, batch, input_dim, hidden_dim

rnn = nn.RNN(input_size=I, hidden_size=H, batch_first=True)
x = torch.randn(B, T, I)

# Many-to-many: use all time-step outputs
out, h_n = rnn(x)
print(f'Many-to-many: out.shape={out.shape}, h_n.shape={h_n.shape}')

# Many-to-one: last hidden state only
last_hidden = h_n.squeeze(0)  # (B, H)
print(f'Many-to-one: last_hidden.shape={last_hidden.shape}')

# One-to-many: repeat single input for T steps
single_input = torch.randn(B, 1, I).repeat(1, T, 1)
out_otm, _ = rnn(single_input)
print(f'One-to-many: out.shape={out_otm.shape}')

# Bidirectional RNN
rnn_bi = nn.RNN(input_size=I, hidden_size=H, batch_first=True, bidirectional=True)
out_bi, h_bi = rnn_bi(x)
print(f'Bidirectional: out.shape={out_bi.shape}, h_n.shape={h_bi.shape}')

total_params = sum(p.numel() for p in rnn.parameters())
print(f'Unidirectional RNN params: {total_params}')
print(f'  Wxh: {I}x{H}={I*H}, Whh: {H}x{H}={H*H}, bh: {H}')
```

## Stateful Inference for Long Sequences

For sequences longer than the training context (e.g., streaming audio or very long documents), the hidden state must be carried between batches. The key is to pass h_state from the previous chunk as the initial state for the next chunk. Gradients are not tracked across chunks during inference. During training, the hidden state is detached (h.detach()) to stop gradient flow into earlier chunks — this is the truncated BPTT pattern. Carrying state allows the model to use information from the entire sequence history at inference time, even if gradients only flow within chunks at training time.

```python
import torch
import torch.nn as nn

torch.manual_seed(0)
I, H, O, B = 8, 32, 4, 2
TOTAL_LEN = 500
CHUNK_SIZE = 50

rnn = nn.RNN(input_size=I, hidden_size=H, batch_first=True)
fc  = nn.Linear(H, O)
rnn.eval(); fc.eval()

long_seq = torch.randn(B, TOTAL_LEN, I)
h_state  = torch.zeros(1, B, H)  # (num_layers, batch, hidden)

outputs = []
with torch.no_grad():
    for start in range(0, TOTAL_LEN, CHUNK_SIZE):
        chunk = long_seq[:, start:start + CHUNK_SIZE, :]
        out, h_state = rnn(chunk, h_state)
        # h_state carries to next chunk — stateful inference
        logits = fc(out)
        outputs.append(logits)

all_out = torch.cat(outputs, dim=1)
print(f'Input length: {TOTAL_LEN}, chunk size: {CHUNK_SIZE}')
print(f'Number of chunks: {TOTAL_LEN // CHUNK_SIZE}')
print(f'Final output shape: {all_out.shape}')
print(f'Final hidden state norm: {h_state.norm().item():.4f}')
print('Hidden state carried across chunks -- full-sequence context at inference.')
```

## RNN Architectures

| Architecture | Use Case | Hidden State Handling | Batch Processing | Example Task |
| --- | --- | --- | --- | --- |
| Many-to-many (aligned) | Output at every input step | h_t used at each t | Pad to max length; mask output loss | POS tagging, NER, frame-level prediction |
| Many-to-one | Single output for whole sequence | Only final h_T used | Pad + pack sequences for efficiency | Sentiment analysis, sequence classification |
| One-to-many | Generate sequence from single input | Decoded step-by-step from h_0 | Replicate input for T steps | Image captioning, music generation |
| Encoder-decoder | Map sequence to sequence of different length | Encoder h_T initialises decoder | Fixed-length bottleneck; attention needed for long seqs | Machine translation, summarization |

## Sequential Computation and GPU Limitations

The recurrence hₜ = f(hₜ₋₁, xₜ) creates a strict sequential dependency: step t cannot begin until step t-1 is complete. This prevents parallelisation over the time axis. On a GPU with thousands of cores, only the matrix multiplications Wₕₓxₜ and Wₕₕhₜ₋₁ at each single step are parallelisable — but these are small compared to what a Transformer can parallelise (all T positions simultaneously). For T=512 and H=512, an RNN requires 512 sequential matrix multiplications of size 512×512, while a Transformer computes all attention in a single batched operation.

```python
import torch
import torch.nn as nn
import time

torch.manual_seed(42)
device = torch.device('cuda' if torch.cuda.is_available() else 'cpu')
B, T, I, H = 16, 64, 32, 64

rnn = nn.RNN(input_size=I, hidden_size=H, batch_first=True).to(device)
tf_layer = nn.TransformerEncoderLayer(
    d_model=I, nhead=4, dim_feedforward=128, batch_first=True
).to(device)

x = torch.randn(B, T, I, device=device)
n_iters = 50

# RNN: sequential over T steps
start = time.perf_counter()
for _ in range(n_iters):
    out_rnn, _ = rnn(x)
    out_rnn.sum().backward()
rnn_ms = (time.perf_counter() - start) / n_iters * 1000

# Transformer: parallel over all T positions
start = time.perf_counter()
for _ in range(n_iters):
    out_tf = tf_layer(x)
    out_tf.sum().backward()
tf_ms = (time.perf_counter() - start) / n_iters * 1000

print(f'Device: {device}, T={T}, B={B}')
print(f'RNN avg fwd+bwd:         {rnn_ms:.2f} ms')
print(f'Transformer avg fwd+bwd: {tf_ms:.2f} ms')
print('RNN is sequential over T; Transformer parallelises all T positions.')
print('GPU utilisation is much lower for RNN -- T steps must be serial.')
```

## Computational Cost and Complexity

The dominant cost per RNN step is the Wₕₕhₜ₋₁ product: O(H²) FLOPs. Over T steps, total cost is O(T·H²) for the recurrent part, plus O(T·H·I) for input projections. Memory scales as O(T·H) to store all hidden states for backpropagation. In contrast, Transformers use O(T²·D) attention (quadratic in sequence length) but O(D²) per token for feed-forward layers. For short sequences (T<200), RNNs can be competitive; for T>1000, the Transformer's parallelism advantage dominates on modern hardware despite its quadratic attention cost.

> **Sequential Computation Bottleneck**: The RNN's recurrence prevents GPU parallelisation over time. For H=512, T=256, a single forward pass requires 256 sequential matrix multiplications. This is why RNNs train 10–50x slower than Transformers on the same sequence length using modern GPUs. Transformers trade O(T²) attention memory for O(1/T) sequential steps — a worthwhile trade for T up to several thousand.

## Why Transformers Replaced RNNs for Long Sequences

Transformers (Vaswani et al. 2017) solve two fundamental RNN limitations: (1) sequential computation by using self-attention that connects all positions in O(1) sequential steps, and (2) the vanishing gradient problem by providing direct gradient paths from every output position to every input position. RNNs remain relevant for streaming inference (constant memory, no sequence-length limit), edge deployment (small parameter count), and tasks where causality is required without future context. However, for pre-training on long text, audio, or video, Transformers (or their linear-attention variants) are the dominant architecture.

- RNN strength: O(H) memory at inference — no KV cache needed; ideal for streaming and embedded systems.
- RNN weakness: O(T) sequential steps prevent GPU parallelism; vanishing gradients limit effective memory to ~100 steps.
- Transformer strength: O(1) sequential steps; direct gradient paths; scales with data and compute.
- Transformer weakness: O(T²) attention memory; fixed context window; no native streaming.
- LSTM/GRU mitigate vanishing gradients with gating but preserve sequential computation bottleneck.
- Mamba/S4/linear RNNs aim to recover parallelisable training while retaining RNN-style inference efficiency.

---

