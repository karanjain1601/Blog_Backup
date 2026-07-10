---
title: "Bidirectional RNNs — Forward and Backward Pass Concatenation"
slug: "bidirectional-rnns"
description: "Bidirectional LSTMs run a forward RNN left-to-right and a backward RNN right-to-left, concatenating hidden states at each position to give full-sequence context. Covers manual BiLSTM construction, PyTorch shape handling, pack_padded_sequence for variable-length batching, and BiLSTM for NER token classification."
tags: ["deep-learning", "rnns", "sequence-models"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"A unidirectional RNN computes ht from x1, x2, ..., xt — each position sees only past context. Many tasks (named entity recognition, machine translation encoding, sentiment analysis) benefit from knowing the full sequence at every position. Bidirectional RNNs run two RNNs on the same sequence: one processes left to right (forward), one right to left (backward). Their hidden states are concatenated at each step, giving [h→t, h←t] — a representation that has seen both past and future context."},{"type":"heading","level":2,"content":"Unidirectional vs Bidirectional Context"},{"type":"text","content":"In the forward direction h→t depends on x1...xt; in the backward direction h←t depends on xT...xt. Concatenating them at each position gives access to the full context x1...xT from both ends. This is crucial for tasks where the meaning of a word depends on what comes after it: in \u0027I went to the bank to withdraw cash\u0027 vs \u0027I sat by the river bank\u0027, the word \u0027bank\u0027 cannot be classified without seeing downstream context. Bidirectional processing makes this information available at every position simultaneously."},{"type":"heading","level":2,"content":"Manual BiLSTM — Forward and Backward Concatenation"},{"type":"text","content":"Implementing BiLSTM manually clarifies exactly what concatenation happens where. The forward LSTM processes the sequence normally. The backward LSTM processes the time-reversed sequence, then its outputs are re-aligned to the original time axis by reversing again. At each position t, the output is [fwd_outt, bwd_outt] ∈ ℝ²ᴴ. The final hidden state for a classifier is typically [h→T, h←1] — the forward final step and the backward final step (which processed x1)."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\n\ndef manual_bilstm(x, input_size, hidden_size, seed=0):\n    \"\"\"Run forward + backward LSTMs and concatenate outputs at each step.\"\"\"\n    torch.manual_seed(seed)\n    fwd = nn.LSTM(input_size, hidden_size, batch_first=True)\n    bwd = nn.LSTM(input_size, hidden_size, batch_first=True)\n\n    fwd_out, (fwd_h, _) = fwd(x)                       # (B, T, H) left-to-right\n    x_rev = torch.flip(x, dims=[1])                    # reverse sequence\n    bwd_out_rev, (bwd_h, _) = bwd(x_rev)               # (B, T, H) right-to-left\n    bwd_out = torch.flip(bwd_out_rev, dims=[1])         # re-align to original time axis\n\n    combined = torch.cat([fwd_out, bwd_out], dim=2)    # (B, T, 2H)\n    final_h  = torch.cat([fwd_h, bwd_h], dim=2)        # (1, B, 2H)\n    return combined, final_h\n\nB, T, I, H = 4, 10, 8, 16\ntorch.manual_seed(99)\nx = torch.randn(B, T, I)\nout, h = manual_bilstm(x, I, H)\n\nprint(\u0027Manual BiLSTM:\u0027)\nprint(\u0027  Input:        {}\u0027.format(tuple(x.shape)))\nprint(\u0027  Output:       {}  (fwd+bwd context at each position)\u0027.format(tuple(out.shape)))\nprint(\u0027  Final hidden: {}\u0027.format(tuple(h.shape)))\nprint()\nprint(\u0027  t=0:   forward has seen x[0] only; backward has seen full sequence\u0027)\nprint(\u0027  t=T/2: both directions have partial context -- richest representation\u0027)\nprint(\u0027  t=T-1: forward has seen full sequence; backward has seen x[T-1] only\u0027)"},{"type":"heading","level":2,"content":"PyTorch Built-in — Shape Guide"},{"type":"text","content":"PyTorch\u0027s nn.LSTM with bidirectional=True handles the forward and backward passes internally. The output tensor has shape (B, T, 2*H) and h_n has shape (2*num_layers, B, H) where directions are interleaved: h_n[0] is the forward final hidden, h_n[1] is the backward final hidden. Understanding these shape conventions prevents the common bug of accidentally using only the forward or only the backward hidden for downstream tasks."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\n\ntorch.manual_seed(0)\nB, T, I, H = 4, 15, 8, 16\n\nbilstm = nn.LSTM(input_size=I, hidden_size=H, num_layers=1,\n                 bidirectional=True, batch_first=True)\n\nx = torch.randn(B, T, I)\nout, (h_n, c_n) = bilstm(x)\n\nprint(\u0027Shape guide for nn.LSTM(bidirectional=True, batch_first=True):\u0027)\nprint(\u0027  x   {}\u0027.format(tuple(x.shape)))\nprint(\u0027  out {}  \u003c- 2*H per position\u0027.format(tuple(out.shape)))\nprint(\u0027  h_n {}  \u003c- [fwd_last, bwd_last] stacked on dim 0\u0027.format(tuple(h_n.shape)))\nprint(\u0027  c_n {}\u0027.format(tuple(c_n.shape)))\nprint()\nh_fwd = h_n[0]                              # (B, H) last forward hidden\nh_bwd = h_n[1]                              # (B, H) last backward hidden\nh_cat = torch.cat([h_fwd, h_bwd], dim=1)   # (B, 2H) for classifier\nprint(\u0027  h_fwd {}  \u003c- final forward hidden (reads from x[T-1])\u0027.format(tuple(h_fwd.shape)))\nprint(\u0027  h_bwd {}  \u003c- final backward hidden (reads from x[0])\u0027.format(tuple(h_bwd.shape)))\nprint(\u0027  h_cat {}   \u003c- concatenated for sentence-level classifier\u0027.format(tuple(h_cat.shape)))\nout_fwd = out[:, :, :H]\nout_bwd = out[:, :, H:]\nprint(\u0027  out_fwd {}  per-step forward outputs\u0027.format(tuple(out_fwd.shape)))\nprint(\u0027  out_bwd {}  per-step backward outputs\u0027.format(tuple(out_bwd.shape)))"},{"type":"heading","level":2,"content":"Efficient Batching with pack_padded_sequence"},{"type":"text","content":"Variable-length sequences in a batch must be padded to the same length, creating wasted computation on padding tokens. PyTorch\u0027s pack_padded_sequence removes padding before the LSTM, passing only real tokens through the recurrent computation. The LSTM processes a compressed representation and pad_packed_sequence restores the padded form afterward. For bidirectional LSTMs with variable-length sequences, this optimization is especially important since both directions process the same padding."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nfrom torch.nn.utils.rnn import pack_padded_sequence, pad_packed_sequence, pad_sequence\n\ndef batch_variable_length(lengths, input_size=4, hidden_size=16):\n    torch.manual_seed(1)\n    seqs = [torch.randn(l, input_size) for l in lengths]\n    bilstm = nn.LSTM(input_size, hidden_size, bidirectional=True, batch_first=True)\n\n    seqs_sorted = sorted(seqs, key=len, reverse=True)\n    len_sorted  = sorted(lengths, reverse=True)\n    len_tensor  = torch.tensor(len_sorted)\n\n    padded = pad_sequence(seqs_sorted, batch_first=True, padding_value=0.0)\n    wasted = padded.numel() - sum(l * input_size for l in len_sorted)\n    print(\u0027Padded batch: {}  ({} wasted elements)\u0027.format(tuple(padded.shape), wasted))\n\n    packed = pack_padded_sequence(padded, len_tensor, batch_first=True)\n    out_packed, (h_n, _) = bilstm(packed)\n    print(\u0027Packed data:  {}  (no wasted computation)\u0027.format(tuple(packed.data.shape)))\n\n    out_pad, out_lens = pad_packed_sequence(out_packed, batch_first=True)\n    print(\u0027Unpacked out: {}  actual lengths: {}\u0027.format(\n        tuple(out_pad.shape), out_lens.tolist()))\n    print(\u0027h_n shape:    {}  \u003c- [fwd_final, bwd_final] x batch\u0027.format(tuple(h_n.shape)))\n\nbatch_variable_length(lengths=[12, 8, 5, 3])"},{"type":"heading","level":2,"content":"Sequence Labeling — BiLSTM for NER"},{"type":"text","content":"Named entity recognition (NER) requires tagging each token with a label (e.g. B-PER, I-ORG, O using BIO notation). BiLSTM is the canonical pre-Transformer architecture for NER: each token\u0027s representation benefits from both left and right context. Two stacked BiLSTM layers are standard — the first captures local syntactic patterns, the second integrates them into higher-level entity representations. A linear classifier on top of each BiLSTM output position produces per-token logits."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\n\nclass BiLSTMNER(nn.Module):\n    \"\"\"Bidirectional 2-layer LSTM for token-level NER (sequence labeling).\"\"\"\n    def __init__(self, vocab_size, embed_dim, hidden_size, n_tags, pad_idx=0):\n        super().__init__()\n        self.embed  = nn.Embedding(vocab_size, embed_dim, padding_idx=pad_idx)\n        self.bilstm = nn.LSTM(embed_dim, hidden_size, num_layers=2,\n                              bidirectional=True, batch_first=True, dropout=0.3)\n        self.drop   = nn.Dropout(0.5)\n        self.fc     = nn.Linear(2 * hidden_size, n_tags)\n\n    def forward(self, token_ids):\n        emb    = self.drop(self.embed(token_ids))    # (B, T, E)\n        out, _ = self.bilstm(emb)                    # (B, T, 2H)\n        out    = self.drop(out)\n        return self.fc(out)                           # (B, T, n_tags)\n\ntorch.manual_seed(42)\nV, E, H, TAGS = 5000, 64, 128, 9   # 9 BIO tags: O + B/I for 4 entity types\nmodel = BiLSTMNER(V, E, H, TAGS)\ntokens = torch.randint(1, V, (8, 20))      # batch=8, seq_len=20\nlabels = torch.randint(0, TAGS, (8, 20))\n\nlogits = model(tokens)\nloss = nn.CrossEntropyLoss()(logits.view(-1, TAGS), labels.view(-1))\nprint(\u0027BiLSTM-NER (2-layer, bidirectional):\u0027)\nprint(\u0027  Input tokens: {}\u0027.format(tuple(tokens.shape)))\nprint(\u0027  Output logits: {}  (per-token tag scores)\u0027.format(tuple(logits.shape)))\nprint(\u0027  Loss: {:.4f}\u0027.format(loss.item()))\nprint(\u0027  Params: {:,}\u0027.format(sum(p.numel() for p in model.parameters())))"},{"type":"callout","variant":"warning","title":"BiRNN Cannot Be Used Autoregressively","content":"Bidirectional RNNs require the full input sequence to be available before processing — they cannot generate output tokens one at a time because the backward pass has not run yet. This makes them unsuitable for autoregressive generation (language modeling, machine translation decoding). They are appropriate only for encoding tasks where the full input is known: classification, tagging, named entity recognition, or as the encoder in encoder-decoder architectures."},{"type":"heading","level":2,"content":"Unidirectional vs Bidirectional Comparison"},{"type":"text","content":"The choice between unidirectional and bidirectional depends primarily on whether future context is available at inference time. For sequence encoding tasks (classification, tagging, translation encoding) bidirectional is almost always better. For generation tasks it is impossible. Memory doubles because there are two sets of hidden states, and training is slower but generally produces significantly better representations for fixed-input tasks."},{"type":"table","headers":["Property","Unidirectional","Bidirectional"],"rows":[["Context at t","x1...xt (causal only)","x1...xT (full sequence)"],["Autoregressive generation","Yes — outputs token by token","No — needs full input first"],["Memory (H=128)","128 per step","256 per step (2x)"],["Training speed","Faster (1 LSTM pass)","~2x slower (2 LSTM passes)"],["NER / tagging","Weaker — no right context","Standard choice — both contexts"],["Language model","Standard — causal constraint","Not applicable for generation"],["Encoder in seq2seq","Common","Preferred — richer source repr"]]},{"type":"heading","level":2,"content":"Applications and Common Patterns"},{"type":"text","content":"BiLSTM is used as the encoder in many NLP architectures: BiLSTM-CRF for NER (add a Conditional Random Field on top of BiLSTM logits to enforce label consistency), BiLSTM + attention for text classification, and BiLSTM encoder + unidirectional LSTM decoder for sequence-to-sequence tasks (machine translation before Transformers). BERT pre-trains bidirectional Transformer encoders rather than BiLSTMs, but the core idea — full context at every position — is the same."},{"type":"list","ordered":false,"items":["BiLSTM-CRF: gold standard pre-Transformer NER — BiLSTM features + Viterbi decoding.","BiLSTM encoder + unidirectional decoder: standard seq2seq for translation (Bahdanau 2015).","DeepSpeech: stacked BiLSTMs for acoustic modeling in speech recognition.","ELMo: deep BiLSTM language model used as contextual word embeddings (Peters et al. 2018).","Sentiment analysis: BiLSTM over sentence with max-pool or attention over all positions.","Document encoding: hierarchical BiLSTM — word-level then sentence-level."]},{"type":"text","content":"Bidirectional processing is one of the most reliable improvements available for any fixed-input sequence task. The engineering cost is minimal (one flag in PyTorch, careful shape handling for h_n) while the accuracy gain from full context can be substantial. Modern Transformer encoders are also bidirectional by nature — BERT\u0027s self-attention attends to all positions simultaneously — making BiLSTM understanding directly relevant to interpreting why encoder-only Transformers work so well."},{"type":"divider"}]"
---
# Bidirectional RNNs — Forward and Backward Pass Concatenation

A unidirectional RNN computes ht from x1, x2, ..., xt — each position sees only past context. Many tasks (named entity recognition, machine translation encoding, sentiment analysis) benefit from knowing the full sequence at every position. Bidirectional RNNs run two RNNs on the same sequence: one processes left to right (forward), one right to left (backward). Their hidden states are concatenated at each step, giving [h→t, h←t] — a representation that has seen both past and future context.

## Unidirectional vs Bidirectional Context

In the forward direction h→t depends on x1...xt; in the backward direction h←t depends on xT...xt. Concatenating them at each position gives access to the full context x1...xT from both ends. This is crucial for tasks where the meaning of a word depends on what comes after it: in 'I went to the bank to withdraw cash' vs 'I sat by the river bank', the word 'bank' cannot be classified without seeing downstream context. Bidirectional processing makes this information available at every position simultaneously.

## Manual BiLSTM — Forward and Backward Concatenation

Implementing BiLSTM manually clarifies exactly what concatenation happens where. The forward LSTM processes the sequence normally. The backward LSTM processes the time-reversed sequence, then its outputs are re-aligned to the original time axis by reversing again. At each position t, the output is [fwd_outt, bwd_outt] ∈ ℝ²ᴴ. The final hidden state for a classifier is typically [h→T, h←1] — the forward final step and the backward final step (which processed x1).

```python
import torch
import torch.nn as nn

def manual_bilstm(x, input_size, hidden_size, seed=0):
    """Run forward + backward LSTMs and concatenate outputs at each step."""
    torch.manual_seed(seed)
    fwd = nn.LSTM(input_size, hidden_size, batch_first=True)
    bwd = nn.LSTM(input_size, hidden_size, batch_first=True)

    fwd_out, (fwd_h, _) = fwd(x)                       # (B, T, H) left-to-right
    x_rev = torch.flip(x, dims=[1])                    # reverse sequence
    bwd_out_rev, (bwd_h, _) = bwd(x_rev)               # (B, T, H) right-to-left
    bwd_out = torch.flip(bwd_out_rev, dims=[1])         # re-align to original time axis

    combined = torch.cat([fwd_out, bwd_out], dim=2)    # (B, T, 2H)
    final_h  = torch.cat([fwd_h, bwd_h], dim=2)        # (1, B, 2H)
    return combined, final_h

B, T, I, H = 4, 10, 8, 16
torch.manual_seed(99)
x = torch.randn(B, T, I)
out, h = manual_bilstm(x, I, H)

print('Manual BiLSTM:')
print('  Input:        {}'.format(tuple(x.shape)))
print('  Output:       {}  (fwd+bwd context at each position)'.format(tuple(out.shape)))
print('  Final hidden: {}'.format(tuple(h.shape)))
print()
print('  t=0:   forward has seen x[0] only; backward has seen full sequence')
print('  t=T/2: both directions have partial context -- richest representation')
print('  t=T-1: forward has seen full sequence; backward has seen x[T-1] only')
```

## PyTorch Built-in — Shape Guide

PyTorch's nn.LSTM with bidirectional=True handles the forward and backward passes internally. The output tensor has shape (B, T, 2*H) and h_n has shape (2*num_layers, B, H) where directions are interleaved: h_n[0] is the forward final hidden, h_n[1] is the backward final hidden. Understanding these shape conventions prevents the common bug of accidentally using only the forward or only the backward hidden for downstream tasks.

```python
import torch
import torch.nn as nn

torch.manual_seed(0)
B, T, I, H = 4, 15, 8, 16

bilstm = nn.LSTM(input_size=I, hidden_size=H, num_layers=1,
                 bidirectional=True, batch_first=True)

x = torch.randn(B, T, I)
out, (h_n, c_n) = bilstm(x)

print('Shape guide for nn.LSTM(bidirectional=True, batch_first=True):')
print('  x   {}'.format(tuple(x.shape)))
print('  out {}  <- 2*H per position'.format(tuple(out.shape)))
print('  h_n {}  <- [fwd_last, bwd_last] stacked on dim 0'.format(tuple(h_n.shape)))
print('  c_n {}'.format(tuple(c_n.shape)))
print()
h_fwd = h_n[0]                              # (B, H) last forward hidden
h_bwd = h_n[1]                              # (B, H) last backward hidden
h_cat = torch.cat([h_fwd, h_bwd], dim=1)   # (B, 2H) for classifier
print('  h_fwd {}  <- final forward hidden (reads from x[T-1])'.format(tuple(h_fwd.shape)))
print('  h_bwd {}  <- final backward hidden (reads from x[0])'.format(tuple(h_bwd.shape)))
print('  h_cat {}   <- concatenated for sentence-level classifier'.format(tuple(h_cat.shape)))
out_fwd = out[:, :, :H]
out_bwd = out[:, :, H:]
print('  out_fwd {}  per-step forward outputs'.format(tuple(out_fwd.shape)))
print('  out_bwd {}  per-step backward outputs'.format(tuple(out_bwd.shape)))
```

## Efficient Batching with pack_padded_sequence

Variable-length sequences in a batch must be padded to the same length, creating wasted computation on padding tokens. PyTorch's pack_padded_sequence removes padding before the LSTM, passing only real tokens through the recurrent computation. The LSTM processes a compressed representation and pad_packed_sequence restores the padded form afterward. For bidirectional LSTMs with variable-length sequences, this optimization is especially important since both directions process the same padding.

```python
import torch
import torch.nn as nn
from torch.nn.utils.rnn import pack_padded_sequence, pad_packed_sequence, pad_sequence

def batch_variable_length(lengths, input_size=4, hidden_size=16):
    torch.manual_seed(1)
    seqs = [torch.randn(l, input_size) for l in lengths]
    bilstm = nn.LSTM(input_size, hidden_size, bidirectional=True, batch_first=True)

    seqs_sorted = sorted(seqs, key=len, reverse=True)
    len_sorted  = sorted(lengths, reverse=True)
    len_tensor  = torch.tensor(len_sorted)

    padded = pad_sequence(seqs_sorted, batch_first=True, padding_value=0.0)
    wasted = padded.numel() - sum(l * input_size for l in len_sorted)
    print('Padded batch: {}  ({} wasted elements)'.format(tuple(padded.shape), wasted))

    packed = pack_padded_sequence(padded, len_tensor, batch_first=True)
    out_packed, (h_n, _) = bilstm(packed)
    print('Packed data:  {}  (no wasted computation)'.format(tuple(packed.data.shape)))

    out_pad, out_lens = pad_packed_sequence(out_packed, batch_first=True)
    print('Unpacked out: {}  actual lengths: {}'.format(
        tuple(out_pad.shape), out_lens.tolist()))
    print('h_n shape:    {}  <- [fwd_final, bwd_final] x batch'.format(tuple(h_n.shape)))

batch_variable_length(lengths=[12, 8, 5, 3])
```

## Sequence Labeling — BiLSTM for NER

Named entity recognition (NER) requires tagging each token with a label (e.g. B-PER, I-ORG, O using BIO notation). BiLSTM is the canonical pre-Transformer architecture for NER: each token's representation benefits from both left and right context. Two stacked BiLSTM layers are standard — the first captures local syntactic patterns, the second integrates them into higher-level entity representations. A linear classifier on top of each BiLSTM output position produces per-token logits.

```python
import torch
import torch.nn as nn

class BiLSTMNER(nn.Module):
    """Bidirectional 2-layer LSTM for token-level NER (sequence labeling)."""
    def __init__(self, vocab_size, embed_dim, hidden_size, n_tags, pad_idx=0):
        super().__init__()
        self.embed  = nn.Embedding(vocab_size, embed_dim, padding_idx=pad_idx)
        self.bilstm = nn.LSTM(embed_dim, hidden_size, num_layers=2,
                              bidirectional=True, batch_first=True, dropout=0.3)
        self.drop   = nn.Dropout(0.5)
        self.fc     = nn.Linear(2 * hidden_size, n_tags)

    def forward(self, token_ids):
        emb    = self.drop(self.embed(token_ids))    # (B, T, E)
        out, _ = self.bilstm(emb)                    # (B, T, 2H)
        out    = self.drop(out)
        return self.fc(out)                           # (B, T, n_tags)

torch.manual_seed(42)
V, E, H, TAGS = 5000, 64, 128, 9   # 9 BIO tags: O + B/I for 4 entity types
model = BiLSTMNER(V, E, H, TAGS)
tokens = torch.randint(1, V, (8, 20))      # batch=8, seq_len=20
labels = torch.randint(0, TAGS, (8, 20))

logits = model(tokens)
loss = nn.CrossEntropyLoss()(logits.view(-1, TAGS), labels.view(-1))
print('BiLSTM-NER (2-layer, bidirectional):')
print('  Input tokens: {}'.format(tuple(tokens.shape)))
print('  Output logits: {}  (per-token tag scores)'.format(tuple(logits.shape)))
print('  Loss: {:.4f}'.format(loss.item()))
print('  Params: {:,}'.format(sum(p.numel() for p in model.parameters())))
```

> **BiRNN Cannot Be Used Autoregressively**: Bidirectional RNNs require the full input sequence to be available before processing — they cannot generate output tokens one at a time because the backward pass has not run yet. This makes them unsuitable for autoregressive generation (language modeling, machine translation decoding). They are appropriate only for encoding tasks where the full input is known: classification, tagging, named entity recognition, or as the encoder in encoder-decoder architectures.

## Unidirectional vs Bidirectional Comparison

The choice between unidirectional and bidirectional depends primarily on whether future context is available at inference time. For sequence encoding tasks (classification, tagging, translation encoding) bidirectional is almost always better. For generation tasks it is impossible. Memory doubles because there are two sets of hidden states, and training is slower but generally produces significantly better representations for fixed-input tasks.

| Property | Unidirectional | Bidirectional |
| --- | --- | --- |
| Context at t | x1...xt (causal only) | x1...xT (full sequence) |
| Autoregressive generation | Yes — outputs token by token | No — needs full input first |
| Memory (H=128) | 128 per step | 256 per step (2x) |
| Training speed | Faster (1 LSTM pass) | ~2x slower (2 LSTM passes) |
| NER / tagging | Weaker — no right context | Standard choice — both contexts |
| Language model | Standard — causal constraint | Not applicable for generation |
| Encoder in seq2seq | Common | Preferred — richer source repr |

## Applications and Common Patterns

BiLSTM is used as the encoder in many NLP architectures: BiLSTM-CRF for NER (add a Conditional Random Field on top of BiLSTM logits to enforce label consistency), BiLSTM + attention for text classification, and BiLSTM encoder + unidirectional LSTM decoder for sequence-to-sequence tasks (machine translation before Transformers). BERT pre-trains bidirectional Transformer encoders rather than BiLSTMs, but the core idea — full context at every position — is the same.

- BiLSTM-CRF: gold standard pre-Transformer NER — BiLSTM features + Viterbi decoding.
- BiLSTM encoder + unidirectional decoder: standard seq2seq for translation (Bahdanau 2015).
- DeepSpeech: stacked BiLSTMs for acoustic modeling in speech recognition.
- ELMo: deep BiLSTM language model used as contextual word embeddings (Peters et al. 2018).
- Sentiment analysis: BiLSTM over sentence with max-pool or attention over all positions.
- Document encoding: hierarchical BiLSTM — word-level then sentence-level.

Bidirectional processing is one of the most reliable improvements available for any fixed-input sequence task. The engineering cost is minimal (one flag in PyTorch, careful shape handling for h_n) while the accuracy gain from full context can be substantial. Modern Transformer encoders are also bidirectional by nature — BERT's self-attention attends to all positions simultaneously — making BiLSTM understanding directly relevant to interpreting why encoder-only Transformers work so well.

---

