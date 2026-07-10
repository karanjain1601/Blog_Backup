---
title: "Multi-Layer RNNs — Depth in Sequence Models"
slug: "multi-layer-rnns"
description: "Stacking RNN layers creates hierarchical temporal representations: lower layers capture fine-grained local patterns, higher layers integrate them into abstract structures. Covers 2-layer LSTM from scratch, PyTorch num_layers with variational dropout, layer-wise gradient analysis, residual stacked LSTM, and depth vs width trade-offs."
tags: ["deep-learning", "rnns", "sequence-models"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"A single-layer RNN learns temporal patterns from raw input, but deep networks can learn hierarchical representations — low layers detect local structure (n-grams, phonemes, local syntax) while high layers integrate these into global patterns (semantics, long-range dependencies). Stacked RNNs apply this principle to sequences: the output sequence of layer l becomes the input sequence of layer l+1. Depth in sequence models provides the same inductive bias as depth in CNNs: hierarchical feature extraction at multiple scales."},{"type":"heading","level":2,"content":"Why Stack RNN Layers?"},{"type":"text","content":"In CNNs, depth enables hierarchical feature detection: edges → textures → parts → objects. The same principle applies to sequences: layer 1 might detect character n-grams or local dependency edges, layer 2 integrates these into phrase-level patterns, layer 3 captures sentence-level structure. Empirically, two-layer LSTMs consistently outperform single-layer LSTMs on language modeling and translation tasks, with diminishing returns beyond 4 layers. The key constraint is that each layer doubles the gradient path length, compounding the vanishing gradient problem across both time and depth."},{"type":"heading","level":2,"content":"Two-Layer LSTM from Scratch"},{"type":"text","content":"In a stacked LSTM, layer 1 receives the input sequence xt and produces output sequence out1t. Layer 2 receives out1t as its input and produces out2t. Between layers, dropout is applied to the output of layer 1 before feeding into layer 2 — this is standard inter-layer dropout. The hidden and cell states of each layer are maintained separately: [(h1, c1), (h2, c2)]."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\n\nclass StackedLSTM(nn.Module):\n    \"\"\"Two-layer LSTM: layer-1 output is layer-2 input, with inter-layer dropout.\"\"\"\n    def __init__(self, input_size, hidden_size, dropout_p=0.3):\n        super().__init__()\n        self.lstm1 = nn.LSTM(input_size, hidden_size, batch_first=True)\n        self.lstm2 = nn.LSTM(hidden_size, hidden_size, batch_first=True)\n        self.drop  = nn.Dropout(dropout_p)\n        self.hidden_size = hidden_size\n\n    def forward(self, x, states=None):\n        if states is None:\n            states = [None, None]\n        out1, (h1, c1) = self.lstm1(x, states[0])\n        out1_dropped = self.drop(out1)              # inter-layer dropout\n        out2, (h2, c2) = self.lstm2(out1_dropped, states[1])\n        return out2, [(h1, c1), (h2, c2)], out1\n\ntorch.manual_seed(42)\nB, T, I, H = 4, 20, 8, 32\nmodel = StackedLSTM(input_size=I, hidden_size=H)\nx = torch.randn(B, T, I)\nout2, states, out1 = model(x)\nh1, c1 = states[0]\nh2, c2 = states[1]\n\nprint(\u00272-layer stacked LSTM:\u0027)\nprint(\u0027  Input:    {}\u0027.format(tuple(x.shape)))\nprint(\u0027  L1 out:   {}  -\u003e dropout -\u003e L2 input\u0027.format(tuple(out1.shape)))\nprint(\u0027  L2 out:   {}\u0027.format(tuple(out2.shape)))\nprint(\u0027  h1: {}  h2: {}\u0027.format(tuple(h1.shape), tuple(h2.shape)))\nprint(\u0027  Params: {:,}\u0027.format(sum(p.numel() for p in model.parameters())))"},{"type":"heading","level":2,"content":"PyTorch num_layers with Variational Dropout"},{"type":"text","content":"nn.LSTM\u0027s num_layers parameter stacks layers automatically. Its dropout parameter applies between layers (not variational — a different mask at each timestep). Variational dropout (Gal \u0026 Ghahramani 2016) uses the same dropout mask across all T timesteps, which is more consistent with Bayesian inference and empirically performs better. Implementing variational dropout requires manually masking the input before passing it to the LSTM."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\n\nclass VarDropLSTM(nn.Module):\n    \"\"\"Multi-layer LSTM with variational dropout (same mask across all timesteps).\"\"\"\n    def __init__(self, input_size, hidden_size, num_layers, dropout_p=0.3):\n        super().__init__()\n        self.lstm = nn.LSTM(input_size, hidden_size, num_layers=num_layers,\n                            dropout=dropout_p if num_layers \u003e 1 else 0.0,\n                            batch_first=True)\n        self.dropout_p = dropout_p\n\n    def forward(self, x):\n        if self.training and self.dropout_p \u003e 0:\n            # Sample one mask; apply across all T timesteps (variational)\n            mask = (torch.rand(x.size(0), 1, x.size(2)) \u003e self.dropout_p).float()\n            mask = mask / (1.0 - self.dropout_p)   # rescale for expected value\n            x = x * mask\n        return self.lstm(x)\n\ntorch.manual_seed(0)\nB, T, I, H, L = 8, 25, 16, 64, 3\nmodel = VarDropLSTM(I, H, num_layers=L, dropout_p=0.3)\nmodel.train()\nx = torch.randn(B, T, I)\nout, (h, c) = model(x)\n\nprint(\u00273-layer LSTM with variational dropout (training mode):\u0027)\nprint(\u0027  Input:   {}\u0027.format(tuple(x.shape)))\nprint(\u0027  Output:  {}\u0027.format(tuple(out.shape)))\nprint(\u0027  h_n:     {}   \u003c- (num_layers, B, H)\u0027.format(tuple(h.shape)))\nprint(\u0027  Params:  {:,}\u0027.format(sum(p.numel() for p in model.parameters())))\nprint(\u0027  vs standard dropout: different mask each step (not variational)\u0027)"},{"type":"heading","level":2,"content":"Layer-Wise Gradient Analysis"},{"type":"text","content":"In a stacked LSTM, gradient must flow both backward through time (BPTT) and downward through layers. The bottom layer (closest to input, furthest from loss) receives the weakest gradient — it is compounded by both vanishing across timesteps and attenuation across layers. Measuring gradient norms per layer reveals this effect: top layers typically have 5–20x larger gradient norms than bottom layers in a 4-layer stack."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\n\ndef layer_gradient_norms(num_layers=4, I=8, H=32, T=20):\n    \"\"\"Measure weight gradient norm in each layer of a stacked LSTM.\"\"\"\n    torch.manual_seed(0)\n    lstm = nn.LSTM(I, H, num_layers=num_layers, batch_first=True)\n    x = torch.randn(4, T, I)\n    out, _ = lstm(x)\n    out[:, -1, :].sum().backward()\n\n    print(\u0027Gradient norms for {}-layer LSTM (loss at final timestep):\u0027.format(num_layers))\n    print(\u0027{:\u003e7} {:\u003e18} {:\u003e18}\u0027.format(\u0027Layer\u0027, \u0027weight_ih norm\u0027, \u0027weight_hh norm\u0027))\n    norms_hh = []\n    for l in range(num_layers):\n        wih = getattr(lstm, \u0027weight_ih_l{}\u0027.format(l))\n        whh = getattr(lstm, \u0027weight_hh_l{}\u0027.format(l))\n        g_ih = wih.grad.norm().item() if wih.grad is not None else 0.0\n        g_hh = whh.grad.norm().item() if whh.grad is not None else 0.0\n        norms_hh.append(g_hh)\n        tag = \u0027 \u003c- input layer\u0027 if l == 0 else (\u0027 \u003c- output layer\u0027 if l == num_layers-1 else \u0027\u0027)\n        print(\u0027{:\u003e7} {:\u003e18.4f} {:\u003e18.4f}{}\u0027.format(l, g_ih, g_hh, tag))\n    ratio = norms_hh[-1] / max(norms_hh[0], 1e-20)\n    print(\u0027Gradient ratio (top / bottom layer): {:.2f}x\u0027.format(ratio))\n\nlayer_gradient_norms(num_layers=4)"},{"type":"heading","level":2,"content":"Residual Connections in Stacked LSTMs"},{"type":"text","content":"Residual connections — adding the input of a layer to its output — are standard in deep CNNs (ResNets) and Transformers but less common in stacked LSTMs. They provide an additional gradient highway bypassing each layer\u0027s computation, helping with training 4+ layer stacks. For residual connections to work in stacked LSTMs, the input dimension and hidden size must match. A linear projection layer is used otherwise. Layer normalization is typically applied after the residual addition."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\n\nclass ResLSTMLayer(nn.Module):\n    \"\"\"Single LSTM layer with residual connection + layer norm (requires d_in == d_hidden).\"\"\"\n    def __init__(self, hidden_size, dropout_p=0.1):\n        super().__init__()\n        self.lstm = nn.LSTM(hidden_size, hidden_size, batch_first=True)\n        self.norm = nn.LayerNorm(hidden_size)\n        self.drop = nn.Dropout(dropout_p)\n\n    def forward(self, x):\n        out, state = self.lstm(x)\n        return self.norm(x + self.drop(out)), state   # residual + layer norm\n\nclass ResStackedLSTM(nn.Module):\n    \"\"\"N-layer residual stacked LSTM for language modeling.\"\"\"\n    def __init__(self, vocab_size, embed_dim, hidden_size, n_layers):\n        super().__init__()\n        self.embed   = nn.Embedding(vocab_size, embed_dim)\n        self.proj_in = nn.Linear(embed_dim, hidden_size)\n        self.layers  = nn.ModuleList([ResLSTMLayer(hidden_size) for _ in range(n_layers)])\n        self.fc      = nn.Linear(hidden_size, vocab_size)\n\n    def forward(self, tokens):\n        x = self.proj_in(self.embed(tokens))\n        for layer in self.layers:\n            x, _ = layer(x)\n        return self.fc(x)\n\ntorch.manual_seed(0)\nmodel = ResStackedLSTM(vocab_size=1000, embed_dim=64, hidden_size=64, n_layers=4)\ntokens = torch.randint(0, 1000, (4, 30))\nlogits = model(tokens)\nprint(\u00274-layer Residual Stacked LSTM:\u0027)\nprint(\u0027  Input tokens: {}\u0027.format(tuple(tokens.shape)))\nprint(\u0027  Output logits: {}  (per-position vocab scores)\u0027.format(tuple(logits.shape)))\nprint(\u0027  Params: {:,}\u0027.format(sum(p.numel() for p in model.parameters())))"},{"type":"callout","variant":"info","title":"2–4 Layers Usually Sufficient for Stacked LSTMs","content":"Unlike CNNs which may use 50–200 layers, stacked LSTMs rarely benefit beyond 4 layers. The compounding vanishing gradient (across both time and depth) makes very deep LSTMs hard to train without residual connections and careful initialization. Empirically, 2-layer LSTMs outperform 1-layer by 3–8 perplexity points on language modeling; 3-layer adds another 2–4 points; 4-layer marginal improvement with longer training time. Spend compute budget on wider hidden size or longer training before adding more layers."},{"type":"heading","level":2,"content":"Depth vs Width Trade-off"},{"type":"text","content":"For a fixed parameter budget, the choice between a single wider layer and multiple narrower layers affects both quality and training dynamics. Wider single-layer models have more direct connections between input and output, while deeper models learn hierarchical features. On language modeling benchmarks, 2-3 layer LSTMs consistently outperform equivalent-parameter 1-layer models, suggesting that depth provides a useful inductive bias beyond raw parameter count."},{"type":"table","headers":["Config","Params (I=256)","PTB Perplexity","Train time / epoch","Gradient (bottom layer)","Depth benefit"],"rows":[["1-layer H=512","~1.6M","~90","1x (baseline)","Strong — no depth decay","None — flat features"],["2-layer H=364","~1.6M","~78","~1.8x","Moderate — 1 extra hop","Local + mid-range patterns"],["3-layer H=297","~1.6M","~74","~2.5x","Weak — 2 extra hops","Hierarchical features"],["4-layer H=256","~1.6M","~73","~3.2x","Very weak — needs residual","Marginal over 3-layer"]]},{"type":"heading","level":2,"content":"Hierarchical Temporal Features"},{"type":"text","content":"The hierarchical feature hypothesis for stacked LSTMs: lower layers develop sensitivity to local, fine-grained patterns (characters, morphemes, short n-grams, local syntactic dependencies) while higher layers develop sensitivity to global, abstract patterns (phrases, clauses, semantic relationships). This has been empirically confirmed through probing tasks: layer 1 of a 3-layer LSTM best predicts part-of-speech tags; layer 3 best predicts semantic roles and long-range coreference."},{"type":"list","ordered":false,"items":["Layer 1 (closest to input): character trigrams, morphological suffixes, local POS patterns.","Layer 2 (middle): phrase boundaries, local dependency edges, named entity spans.","Layer 3 (closest to output): clause structure, semantic roles, coreference, topic.","Inter-layer dropout: prevents layer 2 from overfitting to raw layer-1 activations.","Residual connections: allow gradient to bypass layers — enables effective depth \u003e 4.","Practical recipe: 2 layers with H=512-1024 is the most reliable baseline for pre-Transformer NLP."]},{"type":"text","content":"Stacked LSTMs were the dominant architecture for NLP from 2015–2018, achieving state-of-the-art on language modeling (Penn Treebank), machine translation (WMT), and many classification tasks. The 2-layer BiLSTM with 650 hidden units from Merity et al. (AWD-LSTM, 2017) with weight dropout, embedding dropout, and DropConnect remained competitive with early Transformer models on language modeling benchmarks."},{"type":"divider"}]"
---
# Multi-Layer RNNs — Depth in Sequence Models

A single-layer RNN learns temporal patterns from raw input, but deep networks can learn hierarchical representations — low layers detect local structure (n-grams, phonemes, local syntax) while high layers integrate these into global patterns (semantics, long-range dependencies). Stacked RNNs apply this principle to sequences: the output sequence of layer l becomes the input sequence of layer l+1. Depth in sequence models provides the same inductive bias as depth in CNNs: hierarchical feature extraction at multiple scales.

## Why Stack RNN Layers?

In CNNs, depth enables hierarchical feature detection: edges → textures → parts → objects. The same principle applies to sequences: layer 1 might detect character n-grams or local dependency edges, layer 2 integrates these into phrase-level patterns, layer 3 captures sentence-level structure. Empirically, two-layer LSTMs consistently outperform single-layer LSTMs on language modeling and translation tasks, with diminishing returns beyond 4 layers. The key constraint is that each layer doubles the gradient path length, compounding the vanishing gradient problem across both time and depth.

## Two-Layer LSTM from Scratch

In a stacked LSTM, layer 1 receives the input sequence xt and produces output sequence out1t. Layer 2 receives out1t as its input and produces out2t. Between layers, dropout is applied to the output of layer 1 before feeding into layer 2 — this is standard inter-layer dropout. The hidden and cell states of each layer are maintained separately: [(h1, c1), (h2, c2)].

```python
import torch
import torch.nn as nn

class StackedLSTM(nn.Module):
    """Two-layer LSTM: layer-1 output is layer-2 input, with inter-layer dropout."""
    def __init__(self, input_size, hidden_size, dropout_p=0.3):
        super().__init__()
        self.lstm1 = nn.LSTM(input_size, hidden_size, batch_first=True)
        self.lstm2 = nn.LSTM(hidden_size, hidden_size, batch_first=True)
        self.drop  = nn.Dropout(dropout_p)
        self.hidden_size = hidden_size

    def forward(self, x, states=None):
        if states is None:
            states = [None, None]
        out1, (h1, c1) = self.lstm1(x, states[0])
        out1_dropped = self.drop(out1)              # inter-layer dropout
        out2, (h2, c2) = self.lstm2(out1_dropped, states[1])
        return out2, [(h1, c1), (h2, c2)], out1

torch.manual_seed(42)
B, T, I, H = 4, 20, 8, 32
model = StackedLSTM(input_size=I, hidden_size=H)
x = torch.randn(B, T, I)
out2, states, out1 = model(x)
h1, c1 = states[0]
h2, c2 = states[1]

print('2-layer stacked LSTM:')
print('  Input:    {}'.format(tuple(x.shape)))
print('  L1 out:   {}  -> dropout -> L2 input'.format(tuple(out1.shape)))
print('  L2 out:   {}'.format(tuple(out2.shape)))
print('  h1: {}  h2: {}'.format(tuple(h1.shape), tuple(h2.shape)))
print('  Params: {:,}'.format(sum(p.numel() for p in model.parameters())))
```

## PyTorch num_layers with Variational Dropout

nn.LSTM's num_layers parameter stacks layers automatically. Its dropout parameter applies between layers (not variational — a different mask at each timestep). Variational dropout (Gal & Ghahramani 2016) uses the same dropout mask across all T timesteps, which is more consistent with Bayesian inference and empirically performs better. Implementing variational dropout requires manually masking the input before passing it to the LSTM.

```python
import torch
import torch.nn as nn

class VarDropLSTM(nn.Module):
    """Multi-layer LSTM with variational dropout (same mask across all timesteps)."""
    def __init__(self, input_size, hidden_size, num_layers, dropout_p=0.3):
        super().__init__()
        self.lstm = nn.LSTM(input_size, hidden_size, num_layers=num_layers,
                            dropout=dropout_p if num_layers > 1 else 0.0,
                            batch_first=True)
        self.dropout_p = dropout_p

    def forward(self, x):
        if self.training and self.dropout_p > 0:
            # Sample one mask; apply across all T timesteps (variational)
            mask = (torch.rand(x.size(0), 1, x.size(2)) > self.dropout_p).float()
            mask = mask / (1.0 - self.dropout_p)   # rescale for expected value
            x = x * mask
        return self.lstm(x)

torch.manual_seed(0)
B, T, I, H, L = 8, 25, 16, 64, 3
model = VarDropLSTM(I, H, num_layers=L, dropout_p=0.3)
model.train()
x = torch.randn(B, T, I)
out, (h, c) = model(x)

print('3-layer LSTM with variational dropout (training mode):')
print('  Input:   {}'.format(tuple(x.shape)))
print('  Output:  {}'.format(tuple(out.shape)))
print('  h_n:     {}   <- (num_layers, B, H)'.format(tuple(h.shape)))
print('  Params:  {:,}'.format(sum(p.numel() for p in model.parameters())))
print('  vs standard dropout: different mask each step (not variational)')
```

## Layer-Wise Gradient Analysis

In a stacked LSTM, gradient must flow both backward through time (BPTT) and downward through layers. The bottom layer (closest to input, furthest from loss) receives the weakest gradient — it is compounded by both vanishing across timesteps and attenuation across layers. Measuring gradient norms per layer reveals this effect: top layers typically have 5–20x larger gradient norms than bottom layers in a 4-layer stack.

```python
import torch
import torch.nn as nn

def layer_gradient_norms(num_layers=4, I=8, H=32, T=20):
    """Measure weight gradient norm in each layer of a stacked LSTM."""
    torch.manual_seed(0)
    lstm = nn.LSTM(I, H, num_layers=num_layers, batch_first=True)
    x = torch.randn(4, T, I)
    out, _ = lstm(x)
    out[:, -1, :].sum().backward()

    print('Gradient norms for {}-layer LSTM (loss at final timestep):'.format(num_layers))
    print('{:>7} {:>18} {:>18}'.format('Layer', 'weight_ih norm', 'weight_hh norm'))
    norms_hh = []
    for l in range(num_layers):
        wih = getattr(lstm, 'weight_ih_l{}'.format(l))
        whh = getattr(lstm, 'weight_hh_l{}'.format(l))
        g_ih = wih.grad.norm().item() if wih.grad is not None else 0.0
        g_hh = whh.grad.norm().item() if whh.grad is not None else 0.0
        norms_hh.append(g_hh)
        tag = ' <- input layer' if l == 0 else (' <- output layer' if l == num_layers-1 else '')
        print('{:>7} {:>18.4f} {:>18.4f}{}'.format(l, g_ih, g_hh, tag))
    ratio = norms_hh[-1] / max(norms_hh[0], 1e-20)
    print('Gradient ratio (top / bottom layer): {:.2f}x'.format(ratio))

layer_gradient_norms(num_layers=4)
```

## Residual Connections in Stacked LSTMs

Residual connections — adding the input of a layer to its output — are standard in deep CNNs (ResNets) and Transformers but less common in stacked LSTMs. They provide an additional gradient highway bypassing each layer's computation, helping with training 4+ layer stacks. For residual connections to work in stacked LSTMs, the input dimension and hidden size must match. A linear projection layer is used otherwise. Layer normalization is typically applied after the residual addition.

```python
import torch
import torch.nn as nn

class ResLSTMLayer(nn.Module):
    """Single LSTM layer with residual connection + layer norm (requires d_in == d_hidden)."""
    def __init__(self, hidden_size, dropout_p=0.1):
        super().__init__()
        self.lstm = nn.LSTM(hidden_size, hidden_size, batch_first=True)
        self.norm = nn.LayerNorm(hidden_size)
        self.drop = nn.Dropout(dropout_p)

    def forward(self, x):
        out, state = self.lstm(x)
        return self.norm(x + self.drop(out)), state   # residual + layer norm

class ResStackedLSTM(nn.Module):
    """N-layer residual stacked LSTM for language modeling."""
    def __init__(self, vocab_size, embed_dim, hidden_size, n_layers):
        super().__init__()
        self.embed   = nn.Embedding(vocab_size, embed_dim)
        self.proj_in = nn.Linear(embed_dim, hidden_size)
        self.layers  = nn.ModuleList([ResLSTMLayer(hidden_size) for _ in range(n_layers)])
        self.fc      = nn.Linear(hidden_size, vocab_size)

    def forward(self, tokens):
        x = self.proj_in(self.embed(tokens))
        for layer in self.layers:
            x, _ = layer(x)
        return self.fc(x)

torch.manual_seed(0)
model = ResStackedLSTM(vocab_size=1000, embed_dim=64, hidden_size=64, n_layers=4)
tokens = torch.randint(0, 1000, (4, 30))
logits = model(tokens)
print('4-layer Residual Stacked LSTM:')
print('  Input tokens: {}'.format(tuple(tokens.shape)))
print('  Output logits: {}  (per-position vocab scores)'.format(tuple(logits.shape)))
print('  Params: {:,}'.format(sum(p.numel() for p in model.parameters())))
```

> **2–4 Layers Usually Sufficient for Stacked LSTMs**: Unlike CNNs which may use 50–200 layers, stacked LSTMs rarely benefit beyond 4 layers. The compounding vanishing gradient (across both time and depth) makes very deep LSTMs hard to train without residual connections and careful initialization. Empirically, 2-layer LSTMs outperform 1-layer by 3–8 perplexity points on language modeling; 3-layer adds another 2–4 points; 4-layer marginal improvement with longer training time. Spend compute budget on wider hidden size or longer training before adding more layers.

## Depth vs Width Trade-off

For a fixed parameter budget, the choice between a single wider layer and multiple narrower layers affects both quality and training dynamics. Wider single-layer models have more direct connections between input and output, while deeper models learn hierarchical features. On language modeling benchmarks, 2-3 layer LSTMs consistently outperform equivalent-parameter 1-layer models, suggesting that depth provides a useful inductive bias beyond raw parameter count.

| Config | Params (I=256) | PTB Perplexity | Train time / epoch | Gradient (bottom layer) | Depth benefit |
| --- | --- | --- | --- | --- | --- |
| 1-layer H=512 | ~1.6M | ~90 | 1x (baseline) | Strong — no depth decay | None — flat features |
| 2-layer H=364 | ~1.6M | ~78 | ~1.8x | Moderate — 1 extra hop | Local + mid-range patterns |
| 3-layer H=297 | ~1.6M | ~74 | ~2.5x | Weak — 2 extra hops | Hierarchical features |
| 4-layer H=256 | ~1.6M | ~73 | ~3.2x | Very weak — needs residual | Marginal over 3-layer |

## Hierarchical Temporal Features

The hierarchical feature hypothesis for stacked LSTMs: lower layers develop sensitivity to local, fine-grained patterns (characters, morphemes, short n-grams, local syntactic dependencies) while higher layers develop sensitivity to global, abstract patterns (phrases, clauses, semantic relationships). This has been empirically confirmed through probing tasks: layer 1 of a 3-layer LSTM best predicts part-of-speech tags; layer 3 best predicts semantic roles and long-range coreference.

- Layer 1 (closest to input): character trigrams, morphological suffixes, local POS patterns.
- Layer 2 (middle): phrase boundaries, local dependency edges, named entity spans.
- Layer 3 (closest to output): clause structure, semantic roles, coreference, topic.
- Inter-layer dropout: prevents layer 2 from overfitting to raw layer-1 activations.
- Residual connections: allow gradient to bypass layers — enables effective depth > 4.
- Practical recipe: 2 layers with H=512-1024 is the most reliable baseline for pre-Transformer NLP.

Stacked LSTMs were the dominant architecture for NLP from 2015–2018, achieving state-of-the-art on language modeling (Penn Treebank), machine translation (WMT), and many classification tasks. The 2-layer BiLSTM with 650 hidden units from Merity et al. (AWD-LSTM, 2017) with weight dropout, embedding dropout, and DropConnect remained competitive with early Transformer models on language modeling benchmarks.

---

