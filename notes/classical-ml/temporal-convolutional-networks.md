---
title: "Temporal Convolutional Networks (TCN) — Dilated Causal Convolutions"
slug: "temporal-convolutional-networks"
description: "Build TCN architectures using causal and dilated convolutions to achieve exponentially growing receptive fields without sequential computation, and compare training dynamics and accuracy against LSTM baselines."
tags: ["time-series", "forecasting", "classical-ml"]
topic: "classical-ml"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"Temporal Convolutional Networks (TCN) achieve long-range temporal modelling through two key modifications to standard convolutions: causal padding (ensuring output at time t depends only on inputs at t, t-1, ...) and dilation (expanding the receptive field exponentially by skipping positions in the input). Combined with residual connections and weight normalisation, TCNs match or outperform LSTMs on many sequence modelling benchmarks while being fully parallelisable across time — a key training-efficiency advantage."},{"type":"text","content":"The three design requirements for sequence models used in forecasting are: (1) causality — no information from future timesteps should influence the output at time t; (2) long receptive field — the model must be able to attend to patterns that happened many steps in the past, such as seasonal cycles; (3) stable gradient flow — very deep networks should not suffer from vanishing or exploding gradients that prevent convergence. TCN satisfies all three through causal padding, exponentially growing dilation, and residual shortcuts respectively."},{"type":"heading","level":2,"content":"Causal Convolutions"},{"type":"text","content":"A standard 1D convolution with kernel size k and padding (k-1)/2 is not causal — it uses future inputs at position t+(k-1)/2. Causal convolution pads (k-1) zeros to the left of the input (past side) and zero to the right, so the output at position t uses only inputs at positions t, t-1, ..., t-(k-1). With stride 1, input and output length are equal. Causal convolutions are a prerequisite for autoregressive forecasting: the model cannot peek at the future during training or inference."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\n\nclass CausalConv1d(nn.Module):\n    \"\"\"\n    Causal 1D convolution: pads (kernel_size-1)*dilation zeros on the left.\n    Output at position t depends only on inputs at t, t-1, ...\n    \"\"\"\n    def __init__(self, in_channels, out_channels, kernel_size, dilation=1):\n        super().__init__()\n        self.padding = (kernel_size - 1) * dilation\n        self.conv = nn.Conv1d(\n            in_channels, out_channels, kernel_size,\n            dilation=dilation, padding=self.padding\n        )\n\n    def forward(self, x):\n        # x: (batch, channels, time)\n        out = self.conv(x)\n        # Remove right padding to restore original time dimension\n        return out[:, :, :-self.padding] if self.padding \u003e 0 else out\n\n# Verify causality: output at t should not depend on future inputs\nbatch, C, T = 2, 1, 20\nx = torch.randn(batch, C, T)\ncausal = CausalConv1d(1, 1, kernel_size=3, dilation=2)\nout = causal(x)\nprint(f\u0027Input  shape: {x.shape}\u0027)\nprint(f\u0027Output shape: {out.shape}  (must match input time dim)\u0027)\nassert out.shape[2] == T, \u0027Causal conv must preserve sequence length\u0027\nprint(\u0027Causality check passed.\u0027)"},{"type":"heading","level":2,"content":"Dilated Convolutions and Receptive Field"},{"type":"text","content":"Dilated convolution applies the kernel with a step of d (dilation rate) between kernel positions. A kernel of size k with dilation d has an effective receptive field of d·(k-1)+1 per layer. Stacking L layers with doubling dilations d=1,2,4,...,2^(L-1) and kernel size k gives total receptive field: (k-1)·(2^L - 1) + 1. With k=3, L=8, the receptive field is 511 time steps — enough for most practical series — using only 8·2=16 convolutional operations. This exponential growth is the key advantage over vanilla convolutions that need L layers for receptive field L·(k-1)."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\n\ndef receptive_field(kernel_size, dilations):\n    \"\"\"Compute TCN receptive field for a stack of dilated causal convs.\"\"\"\n    rf = 1\n    for d in dilations:\n        rf += (kernel_size - 1) * d\n    return rf\n\n# Example: 3 blocks, each with dilations [1,2,4,8]\nkernel_size = 3\ndilations = [1, 2, 4, 8] * 3  # 3 repeated blocks\nrf = receptive_field(kernel_size, dilations)\nprint(f\u0027Kernel size: {kernel_size}\u0027)\nprint(f\u0027Dilations:   {dilations}\u0027)\nprint(f\u0027Receptive field: {rf} time steps\u0027)\n\n# Show RF growth per block\nfor n_layers in [1, 2, 4, 8, 12]:\n    d_list = dilations[:n_layers]\n    print(f\u0027  {n_layers:2d} layers → RF = {receptive_field(kernel_size, d_list):4d}\u0027)"},{"type":"heading","level":2,"content":"TCN Residual Block Architecture"},{"type":"text","content":"Each TCN residual block consists of two causal dilated convolutions with weight normalisation and dropout, followed by a skip connection: output = activation(WeightNorm(CausalConv) → ReLU → Dropout → WeightNorm(CausalConv) → ReLU → Dropout) + skip. The skip connection uses a 1×1 convolution if the channel dimension changes, otherwise an identity map. Residual connections prevent vanishing gradients in deep networks (up to 30+ layers) and allow the network to learn small incremental refinements over each block. Multiple blocks with increasing dilation rates are stacked to achieve the desired receptive field."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\n\nclass TCNBlock(nn.Module):\n    def __init__(self, in_ch, out_ch, kernel_size, dilation, dropout=0.1):\n        super().__init__()\n        pad = (kernel_size - 1) * dilation\n        self.conv1 = nn.utils.weight_norm(nn.Conv1d(\n            in_ch, out_ch, kernel_size, dilation=dilation, padding=pad))\n        self.conv2 = nn.utils.weight_norm(nn.Conv1d(\n            out_ch, out_ch, kernel_size, dilation=dilation, padding=pad))\n        self.relu    = nn.ReLU()\n        self.dropout = nn.Dropout(dropout)\n        self.skip    = nn.Conv1d(in_ch, out_ch, 1) if in_ch != out_ch else nn.Identity()\n        self.pad     = pad\n\n    def _causal_trim(self, x):\n        return x[:, :, :-self.pad] if self.pad \u003e 0 else x\n\n    def forward(self, x):\n        out = self.dropout(self.relu(self._causal_trim(self.conv1(x))))\n        out = self.dropout(self.relu(self._causal_trim(self.conv2(out))))\n        return self.relu(out + self.skip(x))\n\nclass TCN(nn.Module):\n    def __init__(self, in_ch, n_filters, kernel_size, n_blocks, dropout=0.1):\n        super().__init__()\n        layers = []\n        for i in range(n_blocks):\n            dilation = 2 ** i\n            c_in  = in_ch if i == 0 else n_filters\n            layers.append(TCNBlock(c_in, n_filters, kernel_size, dilation, dropout))\n        self.net    = nn.Sequential(*layers)\n        self.linear = nn.Linear(n_filters, 1)\n\n    def forward(self, x):\n        # x: (batch, features, time)\n        out = self.net(x)   # (batch, n_filters, time)\n        return self.linear(out.transpose(1, 2))  # (batch, time, 1)\n\nmodel = TCN(in_ch=1, n_filters=32, kernel_size=3, n_blocks=6)\nprint(model)\ntotal_params = sum(p.numel() for p in model.parameters())\nprint(f\u0027Total parameters: {total_params:,}\u0027)"},{"type":"heading","level":2,"content":"Receptive Field Calculation"},{"type":"text","content":"Before building a TCN, determine the minimum receptive field needed to capture the series\u0027 longest relevant dependency. For hourly data with weekly seasonality, the receptive field must cover 168 time steps (7 days × 24 hours). For daily data with annual seasonality, it must cover 365 steps. Choose the minimum number of blocks that achieves this RF with your chosen kernel size. Over-provisioning the RF wastes parameters and may require more data; under-provisioning prevents the model from capturing long-range seasonal patterns."},{"type":"code","language":"python","content":"import numpy as np\nimport pandas as pd\n\ndef tcn_receptive_field(kernel_size, n_blocks, n_layers_per_block=1):\n    \"\"\"Receptive field for TCN with doubling dilations over n_blocks.\"\"\"\n    dilations = [2**i for b in range(n_blocks) for i in range(n_layers_per_block)]\n    rf = 1 + sum((kernel_size - 1) * d for d in dilations)\n    return rf, dilations\n\nrows = []\nfor k in [2, 3, 4]:\n    for nb in [4, 6, 8, 10]:\n        rf, _ = tcn_receptive_field(k, nb)\n        rows.append({\u0027kernel\u0027: k, \u0027blocks\u0027: nb, \u0027RF\u0027: rf, \u0027RF_k\u0027: rf // 1000})\n\ndf = pd.DataFrame(rows)\nprint(df.pivot_table(values=\u0027RF\u0027, index=\u0027kernel\u0027, columns=\u0027blocks\u0027).to_string())\n\n# Practical recommendation\ntarget_rf = 168  # e.g., weekly hourly pattern\nfor k in [2, 3]:\n    for nb in range(1, 15):\n        rf, _ = tcn_receptive_field(k, nb)\n        if rf \u003e= target_rf:\n            print(f\u0027kernel={k}, blocks={nb} → RF={rf} \u003e= {target_rf}\u0027); break"},{"type":"callout","variant":"tip","title":"TCN vs LSTM: When to Prefer Each","content":"TCN is preferred when: (1) training data is large (parallel training over time is a significant speedup), (2) the required receptive field is known and fixed (dilations give explicit control), (3) gradient flow needs to be stable (no LSTM gating issues). LSTM is preferred when: (1) variable-length sequences without padding, (2) strong sequential inductive bias is desired, (3) the model must produce a hidden state for downstream tasks."},{"type":"text","content":"Training a TCN on time-series data follows a sliding-window approach: create input-output pairs (xₜ₋L:t, yₜ₊₁:t₊H) where L = input window length ≥ receptive field and H = forecast horizon. For multi-step output, the TCN head maps the last time step\u0027s feature vector to H values (MIMO). Use Adam with learning rate 1e-3 and cosine annealing. Dropout rate 0.1–0.2 between the two convolutions per block. Weight normalisation is preferred over batch normalisation because it is compatible with variable sequence lengths and small batch sizes."},{"type":"heading","level":2,"content":"Architecture Comparison"},{"type":"table","headers":["Property","TCN","LSTM","Transformer"],"rows":[["Parallelisable over time","Yes — fully parallel","No — sequential hidden state","Yes — attention is parallel"],["Receptive field","Exponential in depth (explicit)","Theoretically infinite (practical ~50-200)","Full sequence (O(L²) memory)"],["Gradient path length","Short — residual shortcuts","Gated — vanishing gradient mitigated","Constant — attention shortcuts"],["Memory per sequence","O(L) — no hidden state","O(L·d) — hidden states for all t","O(L²) — attention matrix"],["Positional information","Implicit via causal padding order","Implicit via recurrence","Explicit positional encoding needed"],["Parameter count (equal RF)","Moderate — convolutional weights","Moderate — gate weights","High — Q,K,V projections per layer"]]},{"type":"list","ordered":false,"items":["Use dilation rates [1, 2, 4, 8, 16, 32] (doubling) for exponential receptive field growth with minimal layers.","Weight normalisation (not batch normalisation) is standard for TCN because it is compatible with variable-length sequences.","Dropout between the two convolutions in each block (not after residual addition) is the standard TCN regularisation.","For multi-step forecasting with TCN, use a MIMO output head: linear layer mapping the last time step\u0027s features to H future values.","TCN outperforms LSTM on tasks requiring very long context (hours of audio, months of hourly sensor data) due to explicit receptive field control."]},{"type":"text","content":"TCN has been successfully applied to load forecasting (electricity demand), anomaly detection in industrial sensor data, and financial volatility prediction. The Temporal Fusion Transformer (Lim et al., 2021) combines ideas from TCN (gating, skip connections) with attention mechanisms and variable selection networks for interpretable multi-horizon forecasting on tabular time series — a practical architecture that bridges TCN and Transformer paradigms."},{"type":"text","content":"When porting an LSTM baseline to a TCN: (1) replace the LSTM cell with a stack of TCNBlocks; (2) set the receptive field to at least 4× the longest seasonal period; (3) replace the LSTM hidden state output with the TCN\u0027s last time-step feature vector for the prediction head; (4) tune dropout in [0.05, 0.2] and number of filters in [32, 128]. Usually, 6–8 blocks with doubling dilations and kernel size 3 or 4 are sufficient for daily or hourly series up to 1 year of context."},{"type":"divider"}]"
---
# Temporal Convolutional Networks (TCN) — Dilated Causal Convolutions

Temporal Convolutional Networks (TCN) achieve long-range temporal modelling through two key modifications to standard convolutions: causal padding (ensuring output at time t depends only on inputs at t, t-1, ...) and dilation (expanding the receptive field exponentially by skipping positions in the input). Combined with residual connections and weight normalisation, TCNs match or outperform LSTMs on many sequence modelling benchmarks while being fully parallelisable across time — a key training-efficiency advantage.

The three design requirements for sequence models used in forecasting are: (1) causality — no information from future timesteps should influence the output at time t; (2) long receptive field — the model must be able to attend to patterns that happened many steps in the past, such as seasonal cycles; (3) stable gradient flow — very deep networks should not suffer from vanishing or exploding gradients that prevent convergence. TCN satisfies all three through causal padding, exponentially growing dilation, and residual shortcuts respectively.

## Causal Convolutions

A standard 1D convolution with kernel size k and padding (k-1)/2 is not causal — it uses future inputs at position t+(k-1)/2. Causal convolution pads (k-1) zeros to the left of the input (past side) and zero to the right, so the output at position t uses only inputs at positions t, t-1, ..., t-(k-1). With stride 1, input and output length are equal. Causal convolutions are a prerequisite for autoregressive forecasting: the model cannot peek at the future during training or inference.

```python
import torch
import torch.nn as nn

class CausalConv1d(nn.Module):
    """
    Causal 1D convolution: pads (kernel_size-1)*dilation zeros on the left.
    Output at position t depends only on inputs at t, t-1, ...
    """
    def __init__(self, in_channels, out_channels, kernel_size, dilation=1):
        super().__init__()
        self.padding = (kernel_size - 1) * dilation
        self.conv = nn.Conv1d(
            in_channels, out_channels, kernel_size,
            dilation=dilation, padding=self.padding
        )

    def forward(self, x):
        # x: (batch, channels, time)
        out = self.conv(x)
        # Remove right padding to restore original time dimension
        return out[:, :, :-self.padding] if self.padding > 0 else out

# Verify causality: output at t should not depend on future inputs
batch, C, T = 2, 1, 20
x = torch.randn(batch, C, T)
causal = CausalConv1d(1, 1, kernel_size=3, dilation=2)
out = causal(x)
print(f'Input  shape: {x.shape}')
print(f'Output shape: {out.shape}  (must match input time dim)')
assert out.shape[2] == T, 'Causal conv must preserve sequence length'
print('Causality check passed.')
```

## Dilated Convolutions and Receptive Field

Dilated convolution applies the kernel with a step of d (dilation rate) between kernel positions. A kernel of size k with dilation d has an effective receptive field of d·(k-1)+1 per layer. Stacking L layers with doubling dilations d=1,2,4,...,2^(L-1) and kernel size k gives total receptive field: (k-1)·(2^L - 1) + 1. With k=3, L=8, the receptive field is 511 time steps — enough for most practical series — using only 8·2=16 convolutional operations. This exponential growth is the key advantage over vanilla convolutions that need L layers for receptive field L·(k-1).

```python
import torch
import torch.nn as nn

def receptive_field(kernel_size, dilations):
    """Compute TCN receptive field for a stack of dilated causal convs."""
    rf = 1
    for d in dilations:
        rf += (kernel_size - 1) * d
    return rf

# Example: 3 blocks, each with dilations [1,2,4,8]
kernel_size = 3
dilations = [1, 2, 4, 8] * 3  # 3 repeated blocks
rf = receptive_field(kernel_size, dilations)
print(f'Kernel size: {kernel_size}')
print(f'Dilations:   {dilations}')
print(f'Receptive field: {rf} time steps')

# Show RF growth per block
for n_layers in [1, 2, 4, 8, 12]:
    d_list = dilations[:n_layers]
    print(f'  {n_layers:2d} layers → RF = {receptive_field(kernel_size, d_list):4d}')
```

## TCN Residual Block Architecture

Each TCN residual block consists of two causal dilated convolutions with weight normalisation and dropout, followed by a skip connection: output = activation(WeightNorm(CausalConv) → ReLU → Dropout → WeightNorm(CausalConv) → ReLU → Dropout) + skip. The skip connection uses a 1×1 convolution if the channel dimension changes, otherwise an identity map. Residual connections prevent vanishing gradients in deep networks (up to 30+ layers) and allow the network to learn small incremental refinements over each block. Multiple blocks with increasing dilation rates are stacked to achieve the desired receptive field.

```python
import torch
import torch.nn as nn

class TCNBlock(nn.Module):
    def __init__(self, in_ch, out_ch, kernel_size, dilation, dropout=0.1):
        super().__init__()
        pad = (kernel_size - 1) * dilation
        self.conv1 = nn.utils.weight_norm(nn.Conv1d(
            in_ch, out_ch, kernel_size, dilation=dilation, padding=pad))
        self.conv2 = nn.utils.weight_norm(nn.Conv1d(
            out_ch, out_ch, kernel_size, dilation=dilation, padding=pad))
        self.relu    = nn.ReLU()
        self.dropout = nn.Dropout(dropout)
        self.skip    = nn.Conv1d(in_ch, out_ch, 1) if in_ch != out_ch else nn.Identity()
        self.pad     = pad

    def _causal_trim(self, x):
        return x[:, :, :-self.pad] if self.pad > 0 else x

    def forward(self, x):
        out = self.dropout(self.relu(self._causal_trim(self.conv1(x))))
        out = self.dropout(self.relu(self._causal_trim(self.conv2(out))))
        return self.relu(out + self.skip(x))

class TCN(nn.Module):
    def __init__(self, in_ch, n_filters, kernel_size, n_blocks, dropout=0.1):
        super().__init__()
        layers = []
        for i in range(n_blocks):
            dilation = 2 ** i
            c_in  = in_ch if i == 0 else n_filters
            layers.append(TCNBlock(c_in, n_filters, kernel_size, dilation, dropout))
        self.net    = nn.Sequential(*layers)
        self.linear = nn.Linear(n_filters, 1)

    def forward(self, x):
        # x: (batch, features, time)
        out = self.net(x)   # (batch, n_filters, time)
        return self.linear(out.transpose(1, 2))  # (batch, time, 1)

model = TCN(in_ch=1, n_filters=32, kernel_size=3, n_blocks=6)
print(model)
total_params = sum(p.numel() for p in model.parameters())
print(f'Total parameters: {total_params:,}')
```

## Receptive Field Calculation

Before building a TCN, determine the minimum receptive field needed to capture the series' longest relevant dependency. For hourly data with weekly seasonality, the receptive field must cover 168 time steps (7 days × 24 hours). For daily data with annual seasonality, it must cover 365 steps. Choose the minimum number of blocks that achieves this RF with your chosen kernel size. Over-provisioning the RF wastes parameters and may require more data; under-provisioning prevents the model from capturing long-range seasonal patterns.

```python
import numpy as np
import pandas as pd

def tcn_receptive_field(kernel_size, n_blocks, n_layers_per_block=1):
    """Receptive field for TCN with doubling dilations over n_blocks."""
    dilations = [2**i for b in range(n_blocks) for i in range(n_layers_per_block)]
    rf = 1 + sum((kernel_size - 1) * d for d in dilations)
    return rf, dilations

rows = []
for k in [2, 3, 4]:
    for nb in [4, 6, 8, 10]:
        rf, _ = tcn_receptive_field(k, nb)
        rows.append({'kernel': k, 'blocks': nb, 'RF': rf, 'RF_k': rf // 1000})

df = pd.DataFrame(rows)
print(df.pivot_table(values='RF', index='kernel', columns='blocks').to_string())

# Practical recommendation
target_rf = 168  # e.g., weekly hourly pattern
for k in [2, 3]:
    for nb in range(1, 15):
        rf, _ = tcn_receptive_field(k, nb)
        if rf >= target_rf:
            print(f'kernel={k}, blocks={nb} → RF={rf} >= {target_rf}'); break
```

> **TCN vs LSTM: When to Prefer Each**: TCN is preferred when: (1) training data is large (parallel training over time is a significant speedup), (2) the required receptive field is known and fixed (dilations give explicit control), (3) gradient flow needs to be stable (no LSTM gating issues). LSTM is preferred when: (1) variable-length sequences without padding, (2) strong sequential inductive bias is desired, (3) the model must produce a hidden state for downstream tasks.

Training a TCN on time-series data follows a sliding-window approach: create input-output pairs (xₜ₋L:t, yₜ₊₁:t₊H) where L = input window length ≥ receptive field and H = forecast horizon. For multi-step output, the TCN head maps the last time step's feature vector to H values (MIMO). Use Adam with learning rate 1e-3 and cosine annealing. Dropout rate 0.1–0.2 between the two convolutions per block. Weight normalisation is preferred over batch normalisation because it is compatible with variable sequence lengths and small batch sizes.

## Architecture Comparison

| Property | TCN | LSTM | Transformer |
| --- | --- | --- | --- |
| Parallelisable over time | Yes — fully parallel | No — sequential hidden state | Yes — attention is parallel |
| Receptive field | Exponential in depth (explicit) | Theoretically infinite (practical ~50-200) | Full sequence (O(L²) memory) |
| Gradient path length | Short — residual shortcuts | Gated — vanishing gradient mitigated | Constant — attention shortcuts |
| Memory per sequence | O(L) — no hidden state | O(L·d) — hidden states for all t | O(L²) — attention matrix |
| Positional information | Implicit via causal padding order | Implicit via recurrence | Explicit positional encoding needed |
| Parameter count (equal RF) | Moderate — convolutional weights | Moderate — gate weights | High — Q,K,V projections per layer |

- Use dilation rates [1, 2, 4, 8, 16, 32] (doubling) for exponential receptive field growth with minimal layers.
- Weight normalisation (not batch normalisation) is standard for TCN because it is compatible with variable-length sequences.
- Dropout between the two convolutions in each block (not after residual addition) is the standard TCN regularisation.
- For multi-step forecasting with TCN, use a MIMO output head: linear layer mapping the last time step's features to H future values.
- TCN outperforms LSTM on tasks requiring very long context (hours of audio, months of hourly sensor data) due to explicit receptive field control.

TCN has been successfully applied to load forecasting (electricity demand), anomaly detection in industrial sensor data, and financial volatility prediction. The Temporal Fusion Transformer (Lim et al., 2021) combines ideas from TCN (gating, skip connections) with attention mechanisms and variable selection networks for interpretable multi-horizon forecasting on tabular time series — a practical architecture that bridges TCN and Transformer paradigms.

When porting an LSTM baseline to a TCN: (1) replace the LSTM cell with a stack of TCNBlocks; (2) set the receptive field to at least 4× the longest seasonal period; (3) replace the LSTM hidden state output with the TCN's last time-step feature vector for the prediction head; (4) tune dropout in [0.05, 0.2] and number of filters in [32, 128]. Usually, 6–8 blocks with doubling dilations and kernel size 3 or 4 are sufficient for daily or hourly series up to 1 year of context.

---

