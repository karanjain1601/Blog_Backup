---
title: "Bahdanau Attention — Additive Attention and Alignment"
slug: "bahdanau-attention"
description: "Deep dive into Bahdanau's additive attention mechanism — alignment scores, context vectors, and the interpretable alignment matrix that laid the groundwork for the Transformer."
tags: ["deep-learning", "rnns", "sequence-models", "state-space-models"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"In 2014–2015, Bahdanau, Cho, and Bengio identified a critical bottleneck in sequence-to-sequence models: the entire source sentence was compressed into a single fixed-size context vector before decoding began. For short sentences this works adequately, but for longer sequences the encoder struggles to pack all relevant information into one vector — and BLEU scores degrade sharply as input length grows. Their seminal paper introduced a mechanism that computes a fresh, decoder-step-specific context vector at each decoding step, drawn as a weighted sum of all encoder hidden states."},{"type":"heading","level":2,"content":"The Seq2Seq Bottleneck Problem"},{"type":"text","content":"A standard seq2seq model encodes the source sequence x₁,...,x_{Ts} into hidden states h₁,...,h_{Ts} using a bidirectional RNN, then passes only the final state to the decoder. The decoder produces output tokens y₁,...,y_{Tt} using a unidirectional RNN initialized with that single context. This forces the encoder to summarize arbitrarily long sequences into a fixed-dimensional vector — an information bottleneck that grows more severe as source length increases."},{"type":"list","ordered":false,"items":["Standard seq2seq BLEU degrades significantly for sentences longer than 30 tokens","A single context vector cannot represent all source positions simultaneously","Gradient must flow through every decoder step back to the encoder, causing vanishing gradients","Long-distance dependencies between source and target words are poorly captured"]},{"type":"heading","level":2,"content":"The Bahdanau Attention Mechanism"},{"type":"text","content":"Bahdanau attention breaks the bottleneck by allowing the decoder to look back at all encoder hidden states at each decoding step. The alignment score eᵢⱼ = vᵀ tanh(W₁sⱼ₋₁ + W₂hᵢ), where sⱼ₋₁ is the decoder state from the previous step and hᵢ is the i-th encoder hidden state. This additive (concat) formulation passes the sum through tanh and a learned vector v, computing an energy measuring compatibility between positions. The scores are normalized via softmax: αᵢⱼ = softmax(eᵢⱼ). The context vector for step j is the weighted sum cⱼ = Σᵢ αᵢⱼhᵢ."},{"type":"list","ordered":false,"items":["eᵢⱼ = vᵀ tanh(W₁sⱼ₋₁ + W₂hᵢ) — additive/concat alignment score","αᵢⱼ = softmax(eᵢⱼ) over all source positions i — probability distribution summing to 1","cⱼ = Σᵢ αᵢⱼhᵢ — weighted sum of encoder states, specific to decoder step j","O(Ts × Tt) alignment scores computed per sequence pair","Alignment matrix {αᵢⱼ} is interpretable: shows which source tokens decoder focuses on"]},{"type":"heading","level":2,"content":"Code 1 — Bahdanau Attention from Scratch"},{"type":"code","language":"python","content":"import numpy as np\nimport torch\nimport torch.nn as nn\nimport torch.nn.functional as F\n\nclass BahdanauAttention(nn.Module):\n    def __init__(self, enc_hidden_dim, dec_hidden_dim, attn_dim):\n        super().__init__()\n        self.W1 = nn.Linear(dec_hidden_dim, attn_dim, bias=False)\n        self.W2 = nn.Linear(enc_hidden_dim, attn_dim, bias=False)\n        self.v  = nn.Linear(attn_dim, 1, bias=False)\n\n    def forward(self, s_prev, encoder_outputs):\n        # s_prev: (batch, dec_hidden_dim)\n        # encoder_outputs: (batch, src_len, enc_hidden_dim)\n        s      = self.W1(s_prev).unsqueeze(1)           # (batch, 1, attn_dim)\n        h      = self.W2(encoder_outputs)                # (batch, src_len, attn_dim)\n        energy = self.v(torch.tanh(s + h)).squeeze(-1)  # (batch, src_len)\n        alpha  = F.softmax(energy, dim=-1)               # (batch, src_len)\n        # cj = sum_i alpha_ij * h_i\n        context = (alpha.unsqueeze(-1) * encoder_outputs).sum(dim=1)  # (batch, enc_h)\n        return context, alpha\n\n# Quick test\nbatch, src_len, enc_h, dec_h, attn_d = 2, 10, 256, 256, 128\nattn    = BahdanauAttention(enc_h, dec_h, attn_d)\nenc_out = torch.randn(batch, src_len, enc_h)\ns       = torch.randn(batch, dec_h)\nctx, weights = attn(s, enc_out)\nprint(f\"Context: {ctx.shape}, Weights: {weights.shape}, Sum: {weights.sum(-1)}\")"},{"type":"heading","level":2,"content":"Code 2 — Seq2Seq with Bahdanau Attention for Translation"},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.nn.functional as F\n\nclass Encoder(nn.Module):\n    def __init__(self, vocab_size, embed_dim, hidden_dim):\n        super().__init__()\n        self.embed = nn.Embedding(vocab_size, embed_dim, padding_idx=0)\n        self.rnn   = nn.GRU(embed_dim, hidden_dim, batch_first=True, bidirectional=True)\n        self.fc    = nn.Linear(hidden_dim * 2, hidden_dim)\n    def forward(self, src):\n        emb = self.embed(src)\n        out, hidden = self.rnn(emb)\n        hidden = torch.tanh(self.fc(torch.cat([hidden[-2], hidden[-1]], dim=-1)))\n        return out, hidden  # out: (B, T, 2H), hidden: (B, H)\n\nclass Decoder(nn.Module):\n    def __init__(self, vocab_size, embed_dim, enc_h, dec_h, attn_d):\n        super().__init__()\n        self.embed  = nn.Embedding(vocab_size, embed_dim)\n        self.attn_W1 = nn.Linear(dec_h, attn_d, bias=False)\n        self.attn_W2 = nn.Linear(enc_h * 2, attn_d, bias=False)\n        self.attn_v  = nn.Linear(attn_d, 1, bias=False)\n        self.rnn     = nn.GRUCell(embed_dim + enc_h * 2, dec_h)\n        self.fc_out  = nn.Linear(dec_h + enc_h * 2 + embed_dim, vocab_size)\n\n    def attention(self, s, enc_out):\n        e = self.attn_v(torch.tanh(self.attn_W1(s).unsqueeze(1) + self.attn_W2(enc_out))).squeeze(-1)\n        return F.softmax(e, dim=-1)\n\n    def forward(self, token, s, enc_out):\n        emb   = self.embed(token)\n        alpha = self.attention(s, enc_out)\n        ctx   = (alpha.unsqueeze(-1) * enc_out).sum(1)\n        s_new = self.rnn(torch.cat([emb, ctx], dim=-1), s)\n        logits = self.fc_out(torch.cat([s_new, ctx, emb], dim=-1))\n        return logits, s_new, alpha\n\nprint(\"Encoder and Bahdanau Decoder defined successfully.\")"},{"type":"heading","level":2,"content":"Code 3 — Alignment Matrix Visualization"},{"type":"text","content":"The alignment matrix {αᵢⱼ} is one of the most striking features of Bahdanau attention — it is directly interpretable as a soft alignment between source and target words. For well-trained translation models it reveals near-diagonal structure for language pairs with similar word order (French-English) and off-diagonal patterns for languages with different syntactic order (German verb-final). The heatmap below plots decoder steps on the y-axis and source positions on the x-axis."},{"type":"code","language":"python","content":"import numpy as np\nimport matplotlib.pyplot as plt\n\ndef plot_attention_heatmap(weights, src_tokens, tgt_tokens, title=\"Attention Alignment\"):\n    \"\"\"\n    weights: (tgt_len, src_len) numpy array of attention weights alpha_ij\n    src_tokens: list of source words\n    tgt_tokens: list of target/decoder words\n    \"\"\"\n    fig, ax = plt.subplots(figsize=(10, 8))\n    im = ax.imshow(weights, cmap=\u0027Blues\u0027, aspect=\u0027auto\u0027, vmin=0, vmax=1)\n    ax.set_xticks(range(len(src_tokens)))\n    ax.set_yticks(range(len(tgt_tokens)))\n    ax.set_xticklabels(src_tokens, rotation=45, ha=\u0027right\u0027, fontsize=11)\n    ax.set_yticklabels(tgt_tokens, fontsize=11)\n    ax.set_xlabel(\u0027Source (Encoder positions)\u0027, fontsize=12)\n    ax.set_ylabel(\u0027Target (Decoder steps)\u0027, fontsize=12)\n    ax.set_title(title, fontsize=14, fontweight=\u0027bold\u0027)\n    plt.colorbar(im, ax=ax, label=\u0027Alpha weight\u0027)\n    for i in range(len(tgt_tokens)):\n        for j in range(len(src_tokens)):\n            ax.text(j, i, f\u0027{weights[i,j]:.2f}\u0027, ha=\u0027center\u0027, va=\u0027center\u0027, fontsize=8)\n    plt.tight_layout()\n    plt.savefig(\u0027attention_alignment.png\u0027, dpi=150)\n    plt.show()\n\n# Simulated French -\u003e English alignment\nsrc = [\u0027Je\u0027, \u0027suis\u0027, \u0027etudiant\u0027, \u0027\u003ceos\u003e\u0027]\ntgt = [\u0027I\u0027, \u0027am\u0027, \u0027a\u0027, \u0027student\u0027, \u0027\u003ceos\u003e\u0027]\nweights = np.array([[0.85, 0.08, 0.04, 0.03],\n                    [0.10, 0.80, 0.06, 0.04],\n                    [0.05, 0.05, 0.85, 0.05],\n                    [0.04, 0.10, 0.82, 0.04],\n                    [0.02, 0.03, 0.05, 0.90]])\nplot_attention_heatmap(weights, src, tgt, \"Bahdanau Attention: French to English\")"},{"type":"heading","level":2,"content":"Code 4 — Attention vs No-Attention BLEU vs Length"},{"type":"code","language":"python","content":"import numpy as np\nimport matplotlib.pyplot as plt\n\ndef sim_bleu(base, decay, lengths, noise_std=0.5, seed=0):\n    \"\"\"Simulate BLEU scores that decay with sentence length.\"\"\"\n    np.random.seed(seed)\n    scores = []\n    for L in lengths:\n        s = base * np.exp(-decay * max(L - 10, 0)) + np.random.randn() * noise_std\n        scores.append(max(round(s, 2), 1.0))\n    return scores\n\nlengths = list(range(5, 55, 5))\nno_attn  = sim_bleu(28.0, 0.040, lengths, seed=1)\nbahdanau = sim_bleu(30.5, 0.012, lengths, seed=2)\n\nfig, ax = plt.subplots(figsize=(9, 5))\nax.plot(lengths, no_attn,  \u0027r--o\u0027, label=\u0027Seq2Seq (no attention)\u0027, linewidth=2)\nax.plot(lengths, bahdanau, \u0027b-s\u0027,  label=\u0027Seq2Seq + Bahdanau\u0027,    linewidth=2)\nax.fill_between(lengths, no_attn, bahdanau, alpha=0.15, color=\u0027blue\u0027)\nax.set_xlabel(\u0027Source Sentence Length (tokens)\u0027, fontsize=12)\nax.set_ylabel(\u0027BLEU Score\u0027, fontsize=12)\nax.set_title(\u0027BLEU vs Sentence Length: Attention vs No-Attention\u0027, fontsize=13)\nax.legend(fontsize=11)\nax.grid(True, alpha=0.3)\nax.annotate(\u0027attention gap widens\\nwith length\u0027, xy=(38, 15),\n            fontsize=10, color=\u0027blue\u0027, style=\u0027italic\u0027)\nplt.tight_layout()\nplt.savefig(\u0027bleu_vs_length.png\u0027, dpi=150)\nplt.show()\nprint(\"Attention advantage grows from ~2 BLEU at L=10 to ~8 BLEU at L=50.\")"},{"type":"heading","level":2,"content":"Hard Attention vs Soft Attention"},{"type":"text","content":"Bahdanau\u0027s original attention is soft attention: the context vector is a differentiable weighted sum over all encoder positions, enabling end-to-end backpropagation. Hard attention (Xu et al., 2015, for image captioning) samples a single position stochastically rather than computing a weighted average. Hard attention requires REINFORCE-style policy gradient training, is non-differentiable, and produces sparser — sometimes more interpretable — selections. Most subsequent work defaults to soft attention due to its training simplicity and better optimization landscape."},{"type":"callout","variant":"info","title":"Attention as Memory Retrieval","content":"Attention can be viewed as soft key-value retrieval: the decoder hidden state acts as a query Q, encoder hidden states act as keys K, and encoder outputs act as values V. The alignment score computes query-key compatibility, softmax normalizes into a probability, and the context vector is the weighted value sum. This query-key-value framing directly inspired the Transformer\u0027s scaled dot-product attention — replace the additive score with qᵀk / sqrt(d_k) and remove the RNN."},{"type":"heading","level":2,"content":"From Bahdanau to Transformer Attention"},{"type":"text","content":"Bahdanau attention established the conceptual template that scaled into the Transformer. Three key evolutions: (1) additive scoring replaced by scaled dot-product eᵢⱼ = qⱼᵀkᵢ / √d_k for computational efficiency on modern hardware; (2) the RNN backbone removed entirely — self-attention replaced recurrence, enabling O(1) depth for any pairwise interaction and full parallelism over the sequence; (3) multi-head attention applies multiple attention functions in parallel, each learning different aspects of alignment. The gradient-flow advantage — direct paths from any decoder position to any encoder position — is preserved across all variants."},{"type":"table","headers":["Variant","Score Formula","Complexity","Uses RNN","Original Paper"],"rows":[["Bahdanau (additive)","vᵀ tanh(W₁s + W₂h)","O(T²·d)","Yes (biGRU)","Bahdanau 2015"],["Luong dot","sᵀh","O(T²)","Yes (LSTM)","Luong 2015"],["Luong general","sᵀWh","O(T²·d)","Yes (LSTM)","Luong 2015"],["Luong concat","vᵀ tanh(W[s;h])","O(T²·d)","Yes (LSTM)","Luong 2015"],["Scaled dot-product","qᵀk / √d_k","O(T²)","No","Vaswani 2017"]]},{"type":"text","content":"Bahdanau attention has aged remarkably well. Its core intuition — that decoding should be conditioned on a content-specific weighted combination of encoder representations rather than a fixed summary — proved fundamental. Every modern sequence model inherits this idea: BERT\u0027s bidirectional self-attention, GPT\u0027s causal self-attention, cross-attention in diffusion and speech models. The alignment visualization also foreshadowed modern explainability: attention weight analysis remains a primary tool for understanding what sequence models have learned."},{"type":"list","ordered":false,"items":["O(Ts × Tt) cost is affordable for sentence-level sequences (T \u003c 200)","Bidirectional encoder hidden states hᵢ capture local context from both directions","Direct gradient path from loss to each encoder state — no bottleneck vanishing gradient","Alignment matrix is interpretable: near-diagonal for similar-order languages","Foundation for self-attention: when Q=K=V all come from the same sequence"]}]"
---
# Bahdanau Attention — Additive Attention and Alignment

In 2014–2015, Bahdanau, Cho, and Bengio identified a critical bottleneck in sequence-to-sequence models: the entire source sentence was compressed into a single fixed-size context vector before decoding began. For short sentences this works adequately, but for longer sequences the encoder struggles to pack all relevant information into one vector — and BLEU scores degrade sharply as input length grows. Their seminal paper introduced a mechanism that computes a fresh, decoder-step-specific context vector at each decoding step, drawn as a weighted sum of all encoder hidden states.

## The Seq2Seq Bottleneck Problem

A standard seq2seq model encodes the source sequence x₁,...,x_{Ts} into hidden states h₁,...,h_{Ts} using a bidirectional RNN, then passes only the final state to the decoder. The decoder produces output tokens y₁,...,y_{Tt} using a unidirectional RNN initialized with that single context. This forces the encoder to summarize arbitrarily long sequences into a fixed-dimensional vector — an information bottleneck that grows more severe as source length increases.

- Standard seq2seq BLEU degrades significantly for sentences longer than 30 tokens
- A single context vector cannot represent all source positions simultaneously
- Gradient must flow through every decoder step back to the encoder, causing vanishing gradients
- Long-distance dependencies between source and target words are poorly captured

## The Bahdanau Attention Mechanism

Bahdanau attention breaks the bottleneck by allowing the decoder to look back at all encoder hidden states at each decoding step. The alignment score eᵢⱼ = vᵀ tanh(W₁sⱼ₋₁ + W₂hᵢ), where sⱼ₋₁ is the decoder state from the previous step and hᵢ is the i-th encoder hidden state. This additive (concat) formulation passes the sum through tanh and a learned vector v, computing an energy measuring compatibility between positions. The scores are normalized via softmax: αᵢⱼ = softmax(eᵢⱼ). The context vector for step j is the weighted sum cⱼ = Σᵢ αᵢⱼhᵢ.

- eᵢⱼ = vᵀ tanh(W₁sⱼ₋₁ + W₂hᵢ) — additive/concat alignment score
- αᵢⱼ = softmax(eᵢⱼ) over all source positions i — probability distribution summing to 1
- cⱼ = Σᵢ αᵢⱼhᵢ — weighted sum of encoder states, specific to decoder step j
- O(Ts × Tt) alignment scores computed per sequence pair
- Alignment matrix {αᵢⱼ} is interpretable: shows which source tokens decoder focuses on

## Code 1 — Bahdanau Attention from Scratch

```python
import numpy as np
import torch
import torch.nn as nn
import torch.nn.functional as F

class BahdanauAttention(nn.Module):
    def __init__(self, enc_hidden_dim, dec_hidden_dim, attn_dim):
        super().__init__()
        self.W1 = nn.Linear(dec_hidden_dim, attn_dim, bias=False)
        self.W2 = nn.Linear(enc_hidden_dim, attn_dim, bias=False)
        self.v  = nn.Linear(attn_dim, 1, bias=False)

    def forward(self, s_prev, encoder_outputs):
        # s_prev: (batch, dec_hidden_dim)
        # encoder_outputs: (batch, src_len, enc_hidden_dim)
        s      = self.W1(s_prev).unsqueeze(1)           # (batch, 1, attn_dim)
        h      = self.W2(encoder_outputs)                # (batch, src_len, attn_dim)
        energy = self.v(torch.tanh(s + h)).squeeze(-1)  # (batch, src_len)
        alpha  = F.softmax(energy, dim=-1)               # (batch, src_len)
        # cj = sum_i alpha_ij * h_i
        context = (alpha.unsqueeze(-1) * encoder_outputs).sum(dim=1)  # (batch, enc_h)
        return context, alpha

# Quick test
batch, src_len, enc_h, dec_h, attn_d = 2, 10, 256, 256, 128
attn    = BahdanauAttention(enc_h, dec_h, attn_d)
enc_out = torch.randn(batch, src_len, enc_h)
s       = torch.randn(batch, dec_h)
ctx, weights = attn(s, enc_out)
print(f"Context: {ctx.shape}, Weights: {weights.shape}, Sum: {weights.sum(-1)}")
```

## Code 2 — Seq2Seq with Bahdanau Attention for Translation

```python
import torch
import torch.nn as nn
import torch.nn.functional as F

class Encoder(nn.Module):
    def __init__(self, vocab_size, embed_dim, hidden_dim):
        super().__init__()
        self.embed = nn.Embedding(vocab_size, embed_dim, padding_idx=0)
        self.rnn   = nn.GRU(embed_dim, hidden_dim, batch_first=True, bidirectional=True)
        self.fc    = nn.Linear(hidden_dim * 2, hidden_dim)
    def forward(self, src):
        emb = self.embed(src)
        out, hidden = self.rnn(emb)
        hidden = torch.tanh(self.fc(torch.cat([hidden[-2], hidden[-1]], dim=-1)))
        return out, hidden  # out: (B, T, 2H), hidden: (B, H)

class Decoder(nn.Module):
    def __init__(self, vocab_size, embed_dim, enc_h, dec_h, attn_d):
        super().__init__()
        self.embed  = nn.Embedding(vocab_size, embed_dim)
        self.attn_W1 = nn.Linear(dec_h, attn_d, bias=False)
        self.attn_W2 = nn.Linear(enc_h * 2, attn_d, bias=False)
        self.attn_v  = nn.Linear(attn_d, 1, bias=False)
        self.rnn     = nn.GRUCell(embed_dim + enc_h * 2, dec_h)
        self.fc_out  = nn.Linear(dec_h + enc_h * 2 + embed_dim, vocab_size)

    def attention(self, s, enc_out):
        e = self.attn_v(torch.tanh(self.attn_W1(s).unsqueeze(1) + self.attn_W2(enc_out))).squeeze(-1)
        return F.softmax(e, dim=-1)

    def forward(self, token, s, enc_out):
        emb   = self.embed(token)
        alpha = self.attention(s, enc_out)
        ctx   = (alpha.unsqueeze(-1) * enc_out).sum(1)
        s_new = self.rnn(torch.cat([emb, ctx], dim=-1), s)
        logits = self.fc_out(torch.cat([s_new, ctx, emb], dim=-1))
        return logits, s_new, alpha

print("Encoder and Bahdanau Decoder defined successfully.")
```

## Code 3 — Alignment Matrix Visualization

The alignment matrix {αᵢⱼ} is one of the most striking features of Bahdanau attention — it is directly interpretable as a soft alignment between source and target words. For well-trained translation models it reveals near-diagonal structure for language pairs with similar word order (French-English) and off-diagonal patterns for languages with different syntactic order (German verb-final). The heatmap below plots decoder steps on the y-axis and source positions on the x-axis.

```python
import numpy as np
import matplotlib.pyplot as plt

def plot_attention_heatmap(weights, src_tokens, tgt_tokens, title="Attention Alignment"):
    """
    weights: (tgt_len, src_len) numpy array of attention weights alpha_ij
    src_tokens: list of source words
    tgt_tokens: list of target/decoder words
    """
    fig, ax = plt.subplots(figsize=(10, 8))
    im = ax.imshow(weights, cmap='Blues', aspect='auto', vmin=0, vmax=1)
    ax.set_xticks(range(len(src_tokens)))
    ax.set_yticks(range(len(tgt_tokens)))
    ax.set_xticklabels(src_tokens, rotation=45, ha='right', fontsize=11)
    ax.set_yticklabels(tgt_tokens, fontsize=11)
    ax.set_xlabel('Source (Encoder positions)', fontsize=12)
    ax.set_ylabel('Target (Decoder steps)', fontsize=12)
    ax.set_title(title, fontsize=14, fontweight='bold')
    plt.colorbar(im, ax=ax, label='Alpha weight')
    for i in range(len(tgt_tokens)):
        for j in range(len(src_tokens)):
            ax.text(j, i, f'{weights[i,j]:.2f}', ha='center', va='center', fontsize=8)
    plt.tight_layout()
    plt.savefig('attention_alignment.png', dpi=150)
    plt.show()

# Simulated French -> English alignment
src = ['Je', 'suis', 'etudiant', '<eos>']
tgt = ['I', 'am', 'a', 'student', '<eos>']
weights = np.array([[0.85, 0.08, 0.04, 0.03],
                    [0.10, 0.80, 0.06, 0.04],
                    [0.05, 0.05, 0.85, 0.05],
                    [0.04, 0.10, 0.82, 0.04],
                    [0.02, 0.03, 0.05, 0.90]])
plot_attention_heatmap(weights, src, tgt, "Bahdanau Attention: French to English")
```

## Code 4 — Attention vs No-Attention BLEU vs Length

```python
import numpy as np
import matplotlib.pyplot as plt

def sim_bleu(base, decay, lengths, noise_std=0.5, seed=0):
    """Simulate BLEU scores that decay with sentence length."""
    np.random.seed(seed)
    scores = []
    for L in lengths:
        s = base * np.exp(-decay * max(L - 10, 0)) + np.random.randn() * noise_std
        scores.append(max(round(s, 2), 1.0))
    return scores

lengths = list(range(5, 55, 5))
no_attn  = sim_bleu(28.0, 0.040, lengths, seed=1)
bahdanau = sim_bleu(30.5, 0.012, lengths, seed=2)

fig, ax = plt.subplots(figsize=(9, 5))
ax.plot(lengths, no_attn,  'r--o', label='Seq2Seq (no attention)', linewidth=2)
ax.plot(lengths, bahdanau, 'b-s',  label='Seq2Seq + Bahdanau',    linewidth=2)
ax.fill_between(lengths, no_attn, bahdanau, alpha=0.15, color='blue')
ax.set_xlabel('Source Sentence Length (tokens)', fontsize=12)
ax.set_ylabel('BLEU Score', fontsize=12)
ax.set_title('BLEU vs Sentence Length: Attention vs No-Attention', fontsize=13)
ax.legend(fontsize=11)
ax.grid(True, alpha=0.3)
ax.annotate('attention gap widens\nwith length', xy=(38, 15),
            fontsize=10, color='blue', style='italic')
plt.tight_layout()
plt.savefig('bleu_vs_length.png', dpi=150)
plt.show()
print("Attention advantage grows from ~2 BLEU at L=10 to ~8 BLEU at L=50.")
```

## Hard Attention vs Soft Attention

Bahdanau's original attention is soft attention: the context vector is a differentiable weighted sum over all encoder positions, enabling end-to-end backpropagation. Hard attention (Xu et al., 2015, for image captioning) samples a single position stochastically rather than computing a weighted average. Hard attention requires REINFORCE-style policy gradient training, is non-differentiable, and produces sparser — sometimes more interpretable — selections. Most subsequent work defaults to soft attention due to its training simplicity and better optimization landscape.

> **Attention as Memory Retrieval**: Attention can be viewed as soft key-value retrieval: the decoder hidden state acts as a query Q, encoder hidden states act as keys K, and encoder outputs act as values V. The alignment score computes query-key compatibility, softmax normalizes into a probability, and the context vector is the weighted value sum. This query-key-value framing directly inspired the Transformer's scaled dot-product attention — replace the additive score with qᵀk / sqrt(d_k) and remove the RNN.

## From Bahdanau to Transformer Attention

Bahdanau attention established the conceptual template that scaled into the Transformer. Three key evolutions: (1) additive scoring replaced by scaled dot-product eᵢⱼ = qⱼᵀkᵢ / √d_k for computational efficiency on modern hardware; (2) the RNN backbone removed entirely — self-attention replaced recurrence, enabling O(1) depth for any pairwise interaction and full parallelism over the sequence; (3) multi-head attention applies multiple attention functions in parallel, each learning different aspects of alignment. The gradient-flow advantage — direct paths from any decoder position to any encoder position — is preserved across all variants.

| Variant | Score Formula | Complexity | Uses RNN | Original Paper |
| --- | --- | --- | --- | --- |
| Bahdanau (additive) | vᵀ tanh(W₁s + W₂h) | O(T²·d) | Yes (biGRU) | Bahdanau 2015 |
| Luong dot | sᵀh | O(T²) | Yes (LSTM) | Luong 2015 |
| Luong general | sᵀWh | O(T²·d) | Yes (LSTM) | Luong 2015 |
| Luong concat | vᵀ tanh(W[s;h]) | O(T²·d) | Yes (LSTM) | Luong 2015 |
| Scaled dot-product | qᵀk / √d_k | O(T²) | No | Vaswani 2017 |

Bahdanau attention has aged remarkably well. Its core intuition — that decoding should be conditioned on a content-specific weighted combination of encoder representations rather than a fixed summary — proved fundamental. Every modern sequence model inherits this idea: BERT's bidirectional self-attention, GPT's causal self-attention, cross-attention in diffusion and speech models. The alignment visualization also foreshadowed modern explainability: attention weight analysis remains a primary tool for understanding what sequence models have learned.

- O(Ts × Tt) cost is affordable for sentence-level sequences (T < 200)
- Bidirectional encoder hidden states hᵢ capture local context from both directions
- Direct gradient path from loss to each encoder state — no bottleneck vanishing gradient
- Alignment matrix is interpretable: near-diagonal for similar-order languages
- Foundation for self-attention: when Q=K=V all come from the same sequence

