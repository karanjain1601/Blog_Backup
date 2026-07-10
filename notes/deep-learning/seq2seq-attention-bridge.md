---
title: "Seq2Seq — Encoder, Decoder, and the Attention Bottleneck"
slug: "seq2seq-attention-bridge"
description: "Seq2Seq (Sutskever et al. 2014) encodes a variable-length input into a fixed context vector c = hN then decodes output autoregressively. Covers encoder-decoder LSTM construction, information bottleneck problem, teacher forcing vs scheduled sampling, beam search decoding, BLEU degradation with source length, and coverage mechanism."
tags: ["deep-learning", "rnns", "sequence-models"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"Sequence-to-sequence (Seq2Seq, Sutskever et al. 2014) models map a variable-length input sequence x1...xN to a variable-length output sequence y1...yM, where N and M can differ. The encoder LSTM reads the source and compresses it into a fixed-size context vector c = hN (the final hidden state). The decoder LSTM generates the target autoregressively, conditioning each step on the context vector and all previously generated tokens. This framework unified machine translation, summarization, dialogue, and code generation under one architecture."},{"type":"heading","level":2,"content":"Encoder-Decoder Architecture"},{"type":"text","content":"The encoder processes the source sequence and produces a context vector: (h, c) = LSTM_enc(x1...xN). The decoder is initialized with this context — s0 = h, cell0 = c — and generates output tokens one at a time: at each step t, the decoder computes st = LSTM_dec(st-1, yt-1, context) and produces a distribution over the target vocabulary via a linear + softmax layer. The context vector threads through the entire decoder as the compressed representation of the source."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\n\nclass Encoder(nn.Module):\n    def __init__(self, vocab, emb, hid):\n        super().__init__()\n        self.embed = nn.Embedding(vocab, emb, padding_idx=0)\n        self.lstm  = nn.LSTM(emb, hid, batch_first=True)\n    def forward(self, src):\n        _, (h, c) = self.lstm(self.embed(src))\n        return h, c  # context: final hidden and cell state\n\nclass Decoder(nn.Module):\n    def __init__(self, vocab, emb, hid):\n        super().__init__()\n        self.embed = nn.Embedding(vocab, emb, padding_idx=0)\n        self.lstm  = nn.LSTM(emb, hid, batch_first=True)\n        self.fc    = nn.Linear(hid, vocab)\n    def step(self, tok, h, c):\n        out, (h, c) = self.lstm(self.embed(tok.unsqueeze(1)), (h, c))\n        return self.fc(out.squeeze(1)), h, c\n\nclass Seq2Seq(nn.Module):\n    def __init__(self, sv, tv, emb, hid):\n        super().__init__()\n        self.enc = Encoder(sv, emb, hid)\n        self.dec = Decoder(tv, emb, hid)\n    def forward(self, src, tgt, tf_ratio=0.5):\n        B, T = tgt.shape\n        V = self.dec.fc.out_features\n        outs = torch.zeros(B, T, V)\n        h, c = self.enc(src)\n        tok  = tgt[:, 0]\n        for t in range(1, T):\n            logit, h, c = self.dec.step(tok, h, c)\n            outs[:, t]  = logit\n            tok = tgt[:, t] if torch.rand(1).item() \u003c tf_ratio else logit.argmax(1)\n        return outs\n\ntorch.manual_seed(0)\nmodel = Seq2Seq(sv=500, tv=500, emb=32, hid=64)\nsrc = torch.randint(1, 500, (8, 15))\ntgt = torch.randint(1, 500, (8, 12))\nout = model(src, tgt)\nh_ctx, c_ctx = model.enc(src)\nprint(\u0027Seq2Seq encoder-decoder:\u0027)\nprint(\u0027  src: {}  -\u003e context h: {}  c: {}\u0027.format(tuple(src.shape), tuple(h_ctx.shape), tuple(c_ctx.shape)))\nprint(\u0027  tgt: {}  -\u003e output logits: {}\u0027.format(tuple(tgt.shape), tuple(out.shape)))\nprint(\u0027  Params: {:,}\u0027.format(sum(p.numel() for p in model.parameters())))"},{"type":"heading","level":2,"content":"The Information Bottleneck"},{"type":"text","content":"The context vector c = hN is a fixed-size representation of H floats regardless of the source length N. For short sequences (N \u003c 15), a well-trained LSTM can pack sufficient information into c. For long sequences (N \u003e 30–50), critical information is inevitably lost — the model must choose what to compress and what to drop. This bottleneck causes BLEU score to degrade significantly with source length for attention-free seq2seq models. Bahdanau attention (2015) was introduced specifically to address this bottleneck by allowing the decoder to directly access encoder hidden states at each decoding step."},{"type":"heading","level":2,"content":"Teacher Forcing and Scheduled Sampling"},{"type":"text","content":"During training, teacher forcing feeds the gold target token yt-1 as input at each decoder step — even if the model would have predicted a different token. This provides clean gradients and fast convergence, but creates a train-inference mismatch: at inference, the model receives its own (potentially wrong) previous predictions. This exposure bias causes compounding errors: a wrong prediction at step t causes worse input at step t+1. Scheduled sampling (Bengio et al. 2015) bridges this gap by gradually mixing teacher-forced and free-running inputs during training."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.optim as optim\n\ndef train_strategy(strategy=\u0027teacher_forcing\u0027, epochs=25, T=12, V=20, H=32, N=128):\n    torch.manual_seed(42)\n    emb  = nn.Embedding(V, H)\n    lstm = nn.LSTM(H, H, batch_first=True)\n    fc   = nn.Linear(H, V)\n    params = list(emb.parameters()) + list(lstm.parameters()) + list(fc.parameters())\n    opt = optim.Adam(params, lr=1e-3)\n    x = torch.randint(0, V, (N, T))\n    y = torch.randint(0, V, (N, T))\n    for ep in range(epochs):\n        tf = (1.0 if strategy == \u0027teacher_forcing\u0027 else\n              max(0.0, 1.0 - ep / epochs) if strategy == \u0027scheduled_sampling\u0027 else 0.0)\n        h = c = torch.zeros(1, N, H)\n        total_loss = 0.0\n        inp = emb(x[:, 0])\n        for t in range(T - 1):\n            out, (h, c) = lstm(inp.unsqueeze(1), (h, c))\n            logit = fc(out.squeeze(1))\n            total_loss += nn.CrossEntropyLoss()(logit, y[:, t+1])\n            inp = emb(y[:, t+1] if torch.rand(1) \u003c tf else logit.argmax(1).detach())\n        loss = total_loss / (T - 1)\n        opt.zero_grad(); loss.backward(); h = h.detach(); c = c.detach(); opt.step()\n    return loss.item()\n\nprint(\u0027Decoding strategy comparison (final training loss):\u0027)\nfor s in [\u0027teacher_forcing\u0027, \u0027scheduled_sampling\u0027, \u0027free_running\u0027]:\n    print(\u0027  {}: {:.4f}\u0027.format(s, train_strategy(s)))"},{"type":"heading","level":2,"content":"Beam Search Decoding"},{"type":"text","content":"Greedy decoding picks the highest-probability token at each step. This is myopic — a high-probability token at step t may lead to low-probability tokens at later steps. Beam search maintains beam_width complete hypotheses at each step, expanding each and keeping the top-k by cumulative log-probability. This approximates the globally most probable sequence without the exponential cost of exact search. Typical beam widths are 4–10 for translation. Length normalization — dividing score by sequence length — prevents short sequences from being unfairly preferred."},{"type":"code","language":"python","content":"import torch\n\ndef beam_search(score_fn, start_tok, end_tok, beam_width=3, max_steps=15):\n    \"\"\"Beam search: maintain top-k hypotheses at each decoding step.\n\n    score_fn(sequence) -\u003e log-probability tensor over vocabulary.\n    Returns (best_log_prob, best_token_sequence).\n    \"\"\"\n    beams = [(0.0, [start_tok])]\n    completed = []\n\n    for step in range(max_steps):\n        candidates = []\n        for log_prob, seq in beams:\n            if seq[-1] == end_tok:\n                completed.append((log_prob, seq))\n                continue\n            next_lps = score_fn(seq)                        # (vocab_size,) log-probs\n            topk_vals, topk_ids = torch.topk(next_lps, beam_width)\n            for lp, tok in zip(topk_vals.tolist(), topk_ids.tolist()):\n                candidates.append((log_prob + lp, seq + [tok]))\n        if not candidates:\n            break\n        candidates.sort(key=lambda x: x[0], reverse=True)\n        beams = candidates[:beam_width]\n\n    all_hyps = completed + beams\n    # Length-normalize: divide accumulated score by sequence length\n    all_hyps.sort(key=lambda x: x[0] / max(len(x[1]), 1), reverse=True)\n    return all_hyps[0]\n\ntorch.manual_seed(0)\ndef mock_scorer(seq):\n    return torch.log_softmax(torch.randn(10), dim=0)\n\nbest_score, best_seq = beam_search(mock_scorer, start_tok=1, end_tok=2, beam_width=3)\nprint(\u0027Beam search (width=3, max_steps=15):\u0027)\nprint(\u0027  Best sequence: {}\u0027.format(best_seq))\nprint(\u0027  Log-prob: {:.3f}  length-norm score: {:.3f}\u0027.format(\n    best_score, best_score / max(len(best_seq), 1)))"},{"type":"heading","level":2,"content":"BLEU Score vs Source Length Analysis"},{"type":"text","content":"The information bottleneck manifests empirically as a degradation in BLEU score as source length increases. For short source sequences (\u003c 15 tokens) the fixed context vector captures the source adequately; for longer sequences (\u003e 30 tokens) critical information is lost during compression, and BLEU drops sharply. Bahdanau attention eliminates the fixed bottleneck — BLEU degrades much more slowly with source length because the decoder can directly query encoder states at any position."},{"type":"code","language":"python","content":"import numpy as np\n\ndef simulate_bleu_vs_length(n_buckets=8, seed=42):\n    \"\"\"Simulate BLEU degradation with source length for attention-free vs attention seq2seq.\"\"\"\n    rng = np.random.default_rng(seed)\n    lengths = np.linspace(5, 80, n_buckets).astype(int)\n    no_attn_scores = []\n    with_attn_scores = []\n\n    print(\u0027Source length vs BLEU score (simulated bottleneck effect):\u0027)\n    print(\u0027{:\u003e9} {:\u003e16} {:\u003e16} {:\u003e10}\u0027.format(\u0027Src len\u0027, \u0027No Attention\u0027, \u0027With Attention\u0027, \u0027Attn Gain\u0027))\n    for src_len in lengths:\n        no_attn   = max(0.03, 0.45 - 0.005 * src_len + rng.normal(0, 0.02))\n        with_attn = max(0.20, 0.45 - 0.001 * src_len + rng.normal(0, 0.02))\n        no_attn_scores.append(no_attn)\n        with_attn_scores.append(with_attn)\n        print(\u0027{:\u003e9} {:\u003e16.3f} {:\u003e16.3f} {:\u003e+10.3f}\u0027.format(\n            src_len, no_attn, with_attn, with_attn - no_attn))\n\n    short_avg = np.mean(no_attn_scores[:3])\n    long_avg  = np.mean(no_attn_scores[-3:])\n    print(\u0027\\nNo-attn: short={:.3f} long={:.3f}  degradation={:.2f}x\u0027.format(\n        short_avg, long_avg, short_avg / max(long_avg, 0.001)))\n\nsimulate_bleu_vs_length()"},{"type":"callout","variant":"info","title":"Coverage Mechanism Prevents Over-Attention","content":"Basic attention can attend repeatedly to the same source positions while ignoring others — a problem called over-attention or under-coverage. The coverage mechanism (Tu et al. 2016) adds a coverage vector that accumulates attention weights across all previous decoder steps and penalizes re-attending to already-covered positions. This produces more uniform attention distributions and is especially important for long documents where every source position should contribute to the output."},{"type":"heading","level":2,"content":"Seq2Seq Variants Comparison"},{"type":"text","content":"The original seq2seq model (Sutskever 2014) used 4-layer LSTM encoders and decoders with fixed context vectors. Bahdanau attention (2015) added dynamic context vectors computed at each decoder step — the first major improvement. Luong attention (2015) simplified the attention computation with dot-product scoring. The Transformer (2017) replaced recurrence entirely with self-attention, enabling full parallelization and better long-range modeling. T5 (2020) unified all text tasks under a text-to-text seq2seq framework."},{"type":"table","headers":["Model","Context","Long Sequence","Parallelizable","Typical Use"],"rows":[["Basic Seq2Seq (2014)","Fixed vector c=hN","Poor — bottleneck degrades BLEU sharply","No — sequential","Short translation, proof of concept"],["Bahdanau Attention (2015)","Dynamic — query encoder at each step","Good — no fixed bottleneck","No — sequential decoder","NMT, summarization, TTS"],["Luong Attention (2015)","Dot-product attention over encoder","Good — simpler computation","No — sequential decoder","NMT baseline, faster than Bahdanau"],["Transformer (2017)","Self-attention over all positions","Very good — O(n²) attention","Yes — fully parallel","All seq2seq tasks, standard since 2018"],["T5 / BART (2020)","Full encoder-decoder Transformer","Very good with position encoding","Yes — parallel encoder, serial decoder","Unified text-to-text, summarization, QA"]]},{"type":"heading","level":2,"content":"Exposure Bias and Coverage"},{"type":"text","content":"Exposure bias — the mismatch between teacher-forced training and free-running inference — remains an unsolved problem even in modern seq2seq systems. Scheduled sampling mitigates but does not eliminate it. Sequence-level training objectives (REINFORCE with BLEU reward, minimum risk training) directly optimize for inference-time quality but suffer from high variance. In practice, teacher forcing with beam search at inference remains the standard recipe despite the bias."},{"type":"list","ordered":false,"items":["Teacher forcing: fast convergence but exposure bias — model sees gold history, not its own errors.","Scheduled sampling: curriculum from TF to free-running — reduces bias but introduces instability.","REINFORCE: optimize BLEU directly — unbiased but high variance, requires careful baselines.","Beam search: width 4-10 is standard; wider beams occasionally hurt due to label bias.","Length penalty: alpha=0.6-0.8 in length normalization is standard for translation.","Coverage penalty: add negative log sum of attention weights below threshold to beam score."]},{"type":"text","content":"The seq2seq framework established the encoder-decoder paradigm that underlies modern large language models. The key engineering insight — encode into a latent representation, decode autoregressively conditioned on that representation — appears in GPT (decoder only), BERT (encoder only), T5 and BART (full encoder-decoder). Understanding the fixed-vector bottleneck and how attention resolves it is essential background for understanding why self-attention became the dominant architectural primitive."},{"type":"divider"}]"
---
# Seq2Seq — Encoder, Decoder, and the Attention Bottleneck

Sequence-to-sequence (Seq2Seq, Sutskever et al. 2014) models map a variable-length input sequence x1...xN to a variable-length output sequence y1...yM, where N and M can differ. The encoder LSTM reads the source and compresses it into a fixed-size context vector c = hN (the final hidden state). The decoder LSTM generates the target autoregressively, conditioning each step on the context vector and all previously generated tokens. This framework unified machine translation, summarization, dialogue, and code generation under one architecture.

## Encoder-Decoder Architecture

The encoder processes the source sequence and produces a context vector: (h, c) = LSTM_enc(x1...xN). The decoder is initialized with this context — s0 = h, cell0 = c — and generates output tokens one at a time: at each step t, the decoder computes st = LSTM_dec(st-1, yt-1, context) and produces a distribution over the target vocabulary via a linear + softmax layer. The context vector threads through the entire decoder as the compressed representation of the source.

```python
import torch
import torch.nn as nn

class Encoder(nn.Module):
    def __init__(self, vocab, emb, hid):
        super().__init__()
        self.embed = nn.Embedding(vocab, emb, padding_idx=0)
        self.lstm  = nn.LSTM(emb, hid, batch_first=True)
    def forward(self, src):
        _, (h, c) = self.lstm(self.embed(src))
        return h, c  # context: final hidden and cell state

class Decoder(nn.Module):
    def __init__(self, vocab, emb, hid):
        super().__init__()
        self.embed = nn.Embedding(vocab, emb, padding_idx=0)
        self.lstm  = nn.LSTM(emb, hid, batch_first=True)
        self.fc    = nn.Linear(hid, vocab)
    def step(self, tok, h, c):
        out, (h, c) = self.lstm(self.embed(tok.unsqueeze(1)), (h, c))
        return self.fc(out.squeeze(1)), h, c

class Seq2Seq(nn.Module):
    def __init__(self, sv, tv, emb, hid):
        super().__init__()
        self.enc = Encoder(sv, emb, hid)
        self.dec = Decoder(tv, emb, hid)
    def forward(self, src, tgt, tf_ratio=0.5):
        B, T = tgt.shape
        V = self.dec.fc.out_features
        outs = torch.zeros(B, T, V)
        h, c = self.enc(src)
        tok  = tgt[:, 0]
        for t in range(1, T):
            logit, h, c = self.dec.step(tok, h, c)
            outs[:, t]  = logit
            tok = tgt[:, t] if torch.rand(1).item() < tf_ratio else logit.argmax(1)
        return outs

torch.manual_seed(0)
model = Seq2Seq(sv=500, tv=500, emb=32, hid=64)
src = torch.randint(1, 500, (8, 15))
tgt = torch.randint(1, 500, (8, 12))
out = model(src, tgt)
h_ctx, c_ctx = model.enc(src)
print('Seq2Seq encoder-decoder:')
print('  src: {}  -> context h: {}  c: {}'.format(tuple(src.shape), tuple(h_ctx.shape), tuple(c_ctx.shape)))
print('  tgt: {}  -> output logits: {}'.format(tuple(tgt.shape), tuple(out.shape)))
print('  Params: {:,}'.format(sum(p.numel() for p in model.parameters())))
```

## The Information Bottleneck

The context vector c = hN is a fixed-size representation of H floats regardless of the source length N. For short sequences (N < 15), a well-trained LSTM can pack sufficient information into c. For long sequences (N > 30–50), critical information is inevitably lost — the model must choose what to compress and what to drop. This bottleneck causes BLEU score to degrade significantly with source length for attention-free seq2seq models. Bahdanau attention (2015) was introduced specifically to address this bottleneck by allowing the decoder to directly access encoder hidden states at each decoding step.

## Teacher Forcing and Scheduled Sampling

During training, teacher forcing feeds the gold target token yt-1 as input at each decoder step — even if the model would have predicted a different token. This provides clean gradients and fast convergence, but creates a train-inference mismatch: at inference, the model receives its own (potentially wrong) previous predictions. This exposure bias causes compounding errors: a wrong prediction at step t causes worse input at step t+1. Scheduled sampling (Bengio et al. 2015) bridges this gap by gradually mixing teacher-forced and free-running inputs during training.

```python
import torch
import torch.nn as nn
import torch.optim as optim

def train_strategy(strategy='teacher_forcing', epochs=25, T=12, V=20, H=32, N=128):
    torch.manual_seed(42)
    emb  = nn.Embedding(V, H)
    lstm = nn.LSTM(H, H, batch_first=True)
    fc   = nn.Linear(H, V)
    params = list(emb.parameters()) + list(lstm.parameters()) + list(fc.parameters())
    opt = optim.Adam(params, lr=1e-3)
    x = torch.randint(0, V, (N, T))
    y = torch.randint(0, V, (N, T))
    for ep in range(epochs):
        tf = (1.0 if strategy == 'teacher_forcing' else
              max(0.0, 1.0 - ep / epochs) if strategy == 'scheduled_sampling' else 0.0)
        h = c = torch.zeros(1, N, H)
        total_loss = 0.0
        inp = emb(x[:, 0])
        for t in range(T - 1):
            out, (h, c) = lstm(inp.unsqueeze(1), (h, c))
            logit = fc(out.squeeze(1))
            total_loss += nn.CrossEntropyLoss()(logit, y[:, t+1])
            inp = emb(y[:, t+1] if torch.rand(1) < tf else logit.argmax(1).detach())
        loss = total_loss / (T - 1)
        opt.zero_grad(); loss.backward(); h = h.detach(); c = c.detach(); opt.step()
    return loss.item()

print('Decoding strategy comparison (final training loss):')
for s in ['teacher_forcing', 'scheduled_sampling', 'free_running']:
    print('  {}: {:.4f}'.format(s, train_strategy(s)))
```

## Beam Search Decoding

Greedy decoding picks the highest-probability token at each step. This is myopic — a high-probability token at step t may lead to low-probability tokens at later steps. Beam search maintains beam_width complete hypotheses at each step, expanding each and keeping the top-k by cumulative log-probability. This approximates the globally most probable sequence without the exponential cost of exact search. Typical beam widths are 4–10 for translation. Length normalization — dividing score by sequence length — prevents short sequences from being unfairly preferred.

```python
import torch

def beam_search(score_fn, start_tok, end_tok, beam_width=3, max_steps=15):
    """Beam search: maintain top-k hypotheses at each decoding step.

    score_fn(sequence) -> log-probability tensor over vocabulary.
    Returns (best_log_prob, best_token_sequence).
    """
    beams = [(0.0, [start_tok])]
    completed = []

    for step in range(max_steps):
        candidates = []
        for log_prob, seq in beams:
            if seq[-1] == end_tok:
                completed.append((log_prob, seq))
                continue
            next_lps = score_fn(seq)                        # (vocab_size,) log-probs
            topk_vals, topk_ids = torch.topk(next_lps, beam_width)
            for lp, tok in zip(topk_vals.tolist(), topk_ids.tolist()):
                candidates.append((log_prob + lp, seq + [tok]))
        if not candidates:
            break
        candidates.sort(key=lambda x: x[0], reverse=True)
        beams = candidates[:beam_width]

    all_hyps = completed + beams
    # Length-normalize: divide accumulated score by sequence length
    all_hyps.sort(key=lambda x: x[0] / max(len(x[1]), 1), reverse=True)
    return all_hyps[0]

torch.manual_seed(0)
def mock_scorer(seq):
    return torch.log_softmax(torch.randn(10), dim=0)

best_score, best_seq = beam_search(mock_scorer, start_tok=1, end_tok=2, beam_width=3)
print('Beam search (width=3, max_steps=15):')
print('  Best sequence: {}'.format(best_seq))
print('  Log-prob: {:.3f}  length-norm score: {:.3f}'.format(
    best_score, best_score / max(len(best_seq), 1)))
```

## BLEU Score vs Source Length Analysis

The information bottleneck manifests empirically as a degradation in BLEU score as source length increases. For short source sequences (< 15 tokens) the fixed context vector captures the source adequately; for longer sequences (> 30 tokens) critical information is lost during compression, and BLEU drops sharply. Bahdanau attention eliminates the fixed bottleneck — BLEU degrades much more slowly with source length because the decoder can directly query encoder states at any position.

```python
import numpy as np

def simulate_bleu_vs_length(n_buckets=8, seed=42):
    """Simulate BLEU degradation with source length for attention-free vs attention seq2seq."""
    rng = np.random.default_rng(seed)
    lengths = np.linspace(5, 80, n_buckets).astype(int)
    no_attn_scores = []
    with_attn_scores = []

    print('Source length vs BLEU score (simulated bottleneck effect):')
    print('{:>9} {:>16} {:>16} {:>10}'.format('Src len', 'No Attention', 'With Attention', 'Attn Gain'))
    for src_len in lengths:
        no_attn   = max(0.03, 0.45 - 0.005 * src_len + rng.normal(0, 0.02))
        with_attn = max(0.20, 0.45 - 0.001 * src_len + rng.normal(0, 0.02))
        no_attn_scores.append(no_attn)
        with_attn_scores.append(with_attn)
        print('{:>9} {:>16.3f} {:>16.3f} {:>+10.3f}'.format(
            src_len, no_attn, with_attn, with_attn - no_attn))

    short_avg = np.mean(no_attn_scores[:3])
    long_avg  = np.mean(no_attn_scores[-3:])
    print('\nNo-attn: short={:.3f} long={:.3f}  degradation={:.2f}x'.format(
        short_avg, long_avg, short_avg / max(long_avg, 0.001)))

simulate_bleu_vs_length()
```

> **Coverage Mechanism Prevents Over-Attention**: Basic attention can attend repeatedly to the same source positions while ignoring others — a problem called over-attention or under-coverage. The coverage mechanism (Tu et al. 2016) adds a coverage vector that accumulates attention weights across all previous decoder steps and penalizes re-attending to already-covered positions. This produces more uniform attention distributions and is especially important for long documents where every source position should contribute to the output.

## Seq2Seq Variants Comparison

The original seq2seq model (Sutskever 2014) used 4-layer LSTM encoders and decoders with fixed context vectors. Bahdanau attention (2015) added dynamic context vectors computed at each decoder step — the first major improvement. Luong attention (2015) simplified the attention computation with dot-product scoring. The Transformer (2017) replaced recurrence entirely with self-attention, enabling full parallelization and better long-range modeling. T5 (2020) unified all text tasks under a text-to-text seq2seq framework.

| Model | Context | Long Sequence | Parallelizable | Typical Use |
| --- | --- | --- | --- | --- |
| Basic Seq2Seq (2014) | Fixed vector c=hN | Poor — bottleneck degrades BLEU sharply | No — sequential | Short translation, proof of concept |
| Bahdanau Attention (2015) | Dynamic — query encoder at each step | Good — no fixed bottleneck | No — sequential decoder | NMT, summarization, TTS |
| Luong Attention (2015) | Dot-product attention over encoder | Good — simpler computation | No — sequential decoder | NMT baseline, faster than Bahdanau |
| Transformer (2017) | Self-attention over all positions | Very good — O(n²) attention | Yes — fully parallel | All seq2seq tasks, standard since 2018 |
| T5 / BART (2020) | Full encoder-decoder Transformer | Very good with position encoding | Yes — parallel encoder, serial decoder | Unified text-to-text, summarization, QA |

## Exposure Bias and Coverage

Exposure bias — the mismatch between teacher-forced training and free-running inference — remains an unsolved problem even in modern seq2seq systems. Scheduled sampling mitigates but does not eliminate it. Sequence-level training objectives (REINFORCE with BLEU reward, minimum risk training) directly optimize for inference-time quality but suffer from high variance. In practice, teacher forcing with beam search at inference remains the standard recipe despite the bias.

- Teacher forcing: fast convergence but exposure bias — model sees gold history, not its own errors.
- Scheduled sampling: curriculum from TF to free-running — reduces bias but introduces instability.
- REINFORCE: optimize BLEU directly — unbiased but high variance, requires careful baselines.
- Beam search: width 4-10 is standard; wider beams occasionally hurt due to label bias.
- Length penalty: alpha=0.6-0.8 in length normalization is standard for translation.
- Coverage penalty: add negative log sum of attention weights below threshold to beam score.

The seq2seq framework established the encoder-decoder paradigm that underlies modern large language models. The key engineering insight — encode into a latent representation, decode autoregressively conditioned on that representation — appears in GPT (decoder only), BERT (encoder only), T5 and BART (full encoder-decoder). Understanding the fixed-vector bottleneck and how attention resolves it is essential background for understanding why self-attention became the dominant architectural primitive.

---

