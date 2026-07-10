---
title: "Encoder-Only Transformers — BERT, RoBERTa, and DeBERTa"
slug: "encoder-only-bert"
description: "Encoder-only Transformers with bidirectional attention — BERT's masked language modelling, fine-tuning for classification, and the improvements in RoBERTa, ELECTRA, and DeBERTa."
tags: ["deep-learning", "transformers"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"Encoder-only Transformers use bidirectional self-attention: every token can attend to every other token in both directions simultaneously. There is no causal mask. This makes encoder models ideal for tasks that require understanding the full context of an input — classification, named entity recognition, question answering, and natural language inference — but they cannot generate text autoregressively. BERT (Devlin et al. 2018) established the encoder-only paradigm and set off a wave of improvements: RoBERTa, ELECTRA, DeBERTa, and many others."},{"type":"heading","level":2,"content":"Bidirectional Attention — Seeing All Tokens"},{"type":"text","content":"In a standard encoder self-attention layer, the attention score matrix S = QKᵀ / √d_k has no mask applied — all L×L entries are used. This means every position can draw information from every other position, including future tokens. The attention weights form a dense L×L matrix after softmax. Bidirectionality is what makes encoders powerful for understanding tasks: the representation of the word \u0027bank\u0027 can simultaneously look left at \u0027river\u0027 and right at \u0027deposit\u0027 to resolve its meaning."},{"type":"list","ordered":false,"items":["Encoder: all positions attend to all others — full L×L attention matrix","Decoder (causal): position i attends only to j ≤ i — lower-triangular matrix","Encoder input: [CLS] token + real tokens + [SEP] token (WordPiece tokenised)","[CLS] representation aggregates the whole-sequence meaning — used for classification","Padding mask still applied: PAD tokens blocked from receiving attention (key_padding_mask)"]},{"type":"callout","variant":"info","title":"Why Encoders Cannot Generate Text","content":"During inference, an autoregressive generator must predict token t given tokens 0 through t-1 without seeing t+1, t+2, … Encoder-only models have no such constraint — they always see the entire input sequence. This makes them excellent understanders but incapable of sequential generation without modification (e.g., adding a causal decoder or using masked-token prediction iteratively)."},{"type":"heading","level":2,"content":"Masked Language Modelling — BERT\u0027s Pretraining Objective"},{"type":"text","content":"BERT is pretrained with Masked Language Modelling (MLM): 15% of input tokens are randomly selected. Of those, 80% are replaced with the special [MASK] token, 10% are replaced with a random token from the vocabulary, and 10% are left unchanged. The model is trained to predict the original token at each masked position using cross-entropy loss. This forces the model to build rich contextual representations because predicting a masked word requires understanding its left and right context simultaneously."},{"type":"heading","level":2,"content":"BERT Architecture and Fine-Tuning"},{"type":"text","content":"BERT-base: 12 layers, 12 attention heads, d_model=768, d_ff=3072, 110M parameters. BERT-large: 24 layers, 16 heads, d_model=1024, d_ff=4096, 340M parameters. Fine-tuning adds a task-specific head on top of the pretrained encoder. For sentence classification, a linear layer maps the [CLS] token representation (shape d_model) to the number of classes. For token-level tasks (NER, POS tagging), a linear head is applied to every token\u0027s representation. BERT popularised the pretrain-then-finetune paradigm that now dominates NLP."},{"type":"heading","level":2,"content":"Code 1 — Encoder-Only Transformer Block from Scratch"},{"type":"text","content":"A bidirectional (no causal mask) Transformer encoder block, showing that all L×L attention weight entries are non-zero."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\n\nclass EncoderBlock(nn.Module):\n    \"\"\"Encoder-only Transformer block: bidirectional self-attention, no causal mask.\n    Pre-norm layout (modern variant).\n    \"\"\"\n    def __init__(self, d_model: int, n_heads: int, d_ff: int,\n                 dropout: float = 0.1):\n        super().__init__()\n        self.norm1 = nn.LayerNorm(d_model)\n        self.norm2 = nn.LayerNorm(d_model)\n        self.attn  = nn.MultiheadAttention(d_model, n_heads,\n                                            dropout=dropout, batch_first=True)\n        self.ff1   = nn.Linear(d_model, d_ff)\n        self.ff2   = nn.Linear(d_ff, d_model)\n        self.act   = nn.GELU()\n        self.drop  = nn.Dropout(dropout)\n\n    def forward(self, x: torch.Tensor,\n                key_padding_mask: torch.Tensor = None):\n        # No attn_mask passed -\u003e bidirectional (all positions attend to all)\n        n = self.norm1(x)\n        a, weights = self.attn(n, n, n, key_padding_mask=key_padding_mask)\n        x = x + self.drop(a)\n        x = x + self.drop(self.ff2(self.act(self.ff1(self.norm2(x)))))\n        return x, weights\n\n# BERT-base dimensions\nblock = EncoderBlock(d_model=768, n_heads=12, d_ff=3072)\nx = torch.randn(2, 12, 768)\nout, attn = block(x)\nprint(\u0027Encoder output:\u0027, out.shape)          # (2, 12, 768)\nprint(\u0027Attention weights:\u0027, attn.shape)      # (2, 12, 12)\nprint(\u0027Non-zero weights:\u0027, (attn \u003e 1e-6).sum().item(), \u0027(all positions attend all)\u0027)"},{"type":"heading","level":2,"content":"Code 2 — MLM Data Preparation"},{"type":"text","content":"Implementing the BERT masking strategy: 15% of tokens selected, 80% replaced with [MASK], 10% random, 10% unchanged. Labels of -100 at non-masked positions are ignored by CrossEntropyLoss."},{"type":"code","language":"python","content":"import torch\nimport random\n\ndef prepare_mlm_batch(token_ids: list, vocab_size: int,\n                       mask_token_id: int, mask_prob: float = 0.15,\n                       pad_id: int = 0):\n    \"\"\"BERT-style MLM masking.\n    Of selected positions: 80% -\u003e [MASK], 10% -\u003e random, 10% -\u003e unchanged.\n    Returns (input_ids, labels, attention_mask) as tensors.\n    labels[b, pos] = -100 (ignored) for non-masked positions.\n    \"\"\"\n    max_len = max(len(s) for s in token_ids)\n    inputs, labels, att_masks = [], [], []\n    for seq in token_ids:\n        ids   = list(seq)\n        label = [-100] * max_len\n        am    = [1] * len(seq) + [0] * (max_len - len(seq))\n        ids  += [pad_id] * (max_len - len(seq))\n        for pos in range(len(seq)):\n            if random.random() \u003c mask_prob:\n                label[pos] = ids[pos]          # store original token as target\n                r = random.random()\n                if r \u003c 0.80:                   # 80%: replace with [MASK]\n                    ids[pos] = mask_token_id\n                elif r \u003c 0.90:                 # 10%: replace with random token\n                    ids[pos] = random.randint(5, vocab_size - 1)\n                # 10%: leave unchanged\n        inputs.append(ids); labels.append(label); att_masks.append(am)\n    return torch.tensor(inputs), torch.tensor(labels), torch.tensor(att_masks)\n\nrandom.seed(42)\nseqs   = [[101, 2054, 2003, 1996, 3007, 102], [101, 4067, 2024, 4658, 102]]\ninp, lbl, am = prepare_mlm_batch(seqs, vocab_size=30000, mask_token_id=103)\nprint(\u0027Input IDs:\u0027)\nprint(inp)\nprint(\u0027Labels (-100 = not masked):\u0027)\nprint(lbl)"},{"type":"heading","level":2,"content":"Code 3 — BERT Fine-Tuning for Classification"},{"type":"text","content":"Using HuggingFace transformers to fine-tune BERT for binary classification: a linear head on the [CLS] token representation with AdamW optimiser."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nfrom transformers import BertModel, BertTokenizer\nfrom torch.optim import AdamW\n\nclass BertForSentiment(nn.Module):\n    \"\"\"BERT encoder + linear classification head on the [CLS] token.\"\"\"\n    def __init__(self, n_classes: int = 2, dropout: float = 0.1):\n        super().__init__()\n        self.bert       = BertModel.from_pretrained(\u0027bert-base-uncased\u0027)\n        self.dropout    = nn.Dropout(dropout)\n        self.classifier = nn.Linear(768, n_classes)\n\n    def forward(self, input_ids, attention_mask, token_type_ids=None):\n        out = self.bert(input_ids=input_ids,\n                        attention_mask=attention_mask,\n                        token_type_ids=token_type_ids)\n        cls_rep = out.last_hidden_state[:, 0, :]   # [CLS] token at position 0\n        return self.classifier(self.dropout(cls_rep))\n\n# Tokenise and run one training step\ntokenizer = BertTokenizer.from_pretrained(\u0027bert-base-uncased\u0027)\ntexts     = [\u0027I love this film!\u0027, \u0027The movie was terrible.\u0027]\nlabels    = torch.tensor([1, 0])\nenc       = tokenizer(texts, return_tensors=\u0027pt\u0027, padding=True, truncation=True)\n\nmodel   = BertForSentiment()\noptimr  = AdamW(model.parameters(), lr=2e-5, weight_decay=0.01)\nloss_fn = nn.CrossEntropyLoss()\n\nmodel.train()\nlogits = model(enc[\u0027input_ids\u0027], enc[\u0027attention_mask\u0027])\nloss   = loss_fn(logits, labels)\nloss.backward()\noptimr.step()\nprint(\u0027Logits:\u0027, logits.detach())\nprint(\u0027Loss:  \u0027, round(loss.item(), 4))"},{"type":"heading","level":2,"content":"Code 4 — ELECTRA Replaced Token Detection"},{"type":"text","content":"ELECTRA (Clark et al. 2020) replaces MLM with a discriminative objective: a small generator corrupts tokens, and the discriminator must classify each token as real or replaced. More sample-efficient than MLM because the loss signal covers all tokens, not just the 15% masked."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport random\n\ndef simulate_rtd(token_ids: torch.Tensor, gen_logits: torch.Tensor,\n                 replace_prob: float = 0.15):\n    \"\"\"Simulate ELECTRA replaced token detection data creation.\n    gen_logits: (B, L, V) — generator\u0027s token distribution at each position.\n    Returns (corrupted_ids, rtd_labels) where rtd_labels: 0=real, 1=replaced.\n    \"\"\"\n    B, L = token_ids.shape\n    corrupted = token_ids.clone()\n    rtd_labels = torch.zeros(B, L, dtype=torch.float)\n    probs = torch.softmax(gen_logits, dim=-1)\n    for b in range(B):\n        for pos in range(L):\n            if random.random() \u003c replace_prob:\n                orig        = token_ids[b, pos].item()\n                replacement = torch.multinomial(probs[b, pos], 1).item()\n                if replacement != orig:\n                    corrupted[b, pos]  = replacement\n                    rtd_labels[b, pos] = 1.0   # mark as replaced\n    return corrupted, rtd_labels\n\nclass RTDHead(nn.Module):\n    \"\"\"Discriminator head: binary classification at every token position.\"\"\"\n    def __init__(self, d_model: int):\n        super().__init__()\n        self.linear = nn.Linear(d_model, 1)\n    def forward(self, hidden): return self.linear(hidden).squeeze(-1)  # (B, L)\n\ntorch.manual_seed(0); random.seed(0)\nB, L, V, d = 2, 8, 1000, 256\ntoken_ids  = torch.randint(5, V, (B, L))\ngen_logits = torch.randn(B, L, V)\ncorrupt, rtd_lbl = simulate_rtd(token_ids, gen_logits)\nprint(\u0027Original: \u0027, token_ids[0].tolist())\nprint(\u0027Corrupted:\u0027, corrupt[0].tolist())\nprint(\u0027RTD labels (1=replaced):\u0027, rtd_lbl[0].tolist())\nhead    = RTDHead(d)\nhidden  = torch.randn(B, L, d)\nrtd_out = head(hidden)\nloss    = nn.BCEWithLogitsLoss()(rtd_out, rtd_lbl)\nprint(f\u0027RTD discriminator loss: {loss.item():.4f}\u0027)"},{"type":"heading","level":2,"content":"Encoder Models Compared"},{"type":"table","headers":["Model","Pretraining Objective","Params","Tokens Seen","GLUE Score","Key Innovation"],"rows":[["BERT-base","MLM + NSP","110M","16B","80.5","Bidirectional pretrain on large corpus"],["BERT-large","MLM + NSP","340M","16B","82.1","Scale: more layers, wider model"],["RoBERTa","MLM only (no NSP)","125M","~2T","88.5","Longer training, larger batches, more data"],["ELECTRA-base","Replaced Token Detection","110M","128B","88.8","Sample-efficient discriminative objective"],["DeBERTa-base","MLM + disentangled attn","140M","78B","90.3","Separate position and content attention keys"]]},{"type":"text","content":"Encoder-only models remain the top choice for NLU tasks — text classification, NER, extractive QA — where the full input is known at inference time. RoBERTa is the practical default: it significantly outperforms original BERT with only a training recipe change, no architecture modification. ELECTRA is the best choice when compute budget is tight, since its sample efficiency means it reaches RoBERTa-level quality with far less pretraining. DeBERTa currently holds the highest GLUE and SuperGLUE scores among encoder-only models, owing to its disentangled position and content attention."}]"
---
# Encoder-Only Transformers — BERT, RoBERTa, and DeBERTa

Encoder-only Transformers use bidirectional self-attention: every token can attend to every other token in both directions simultaneously. There is no causal mask. This makes encoder models ideal for tasks that require understanding the full context of an input — classification, named entity recognition, question answering, and natural language inference — but they cannot generate text autoregressively. BERT (Devlin et al. 2018) established the encoder-only paradigm and set off a wave of improvements: RoBERTa, ELECTRA, DeBERTa, and many others.

## Bidirectional Attention — Seeing All Tokens

In a standard encoder self-attention layer, the attention score matrix S = QKᵀ / √d_k has no mask applied — all L×L entries are used. This means every position can draw information from every other position, including future tokens. The attention weights form a dense L×L matrix after softmax. Bidirectionality is what makes encoders powerful for understanding tasks: the representation of the word 'bank' can simultaneously look left at 'river' and right at 'deposit' to resolve its meaning.

- Encoder: all positions attend to all others — full L×L attention matrix
- Decoder (causal): position i attends only to j ≤ i — lower-triangular matrix
- Encoder input: [CLS] token + real tokens + [SEP] token (WordPiece tokenised)
- [CLS] representation aggregates the whole-sequence meaning — used for classification
- Padding mask still applied: PAD tokens blocked from receiving attention (key_padding_mask)

> **Why Encoders Cannot Generate Text**: During inference, an autoregressive generator must predict token t given tokens 0 through t-1 without seeing t+1, t+2, … Encoder-only models have no such constraint — they always see the entire input sequence. This makes them excellent understanders but incapable of sequential generation without modification (e.g., adding a causal decoder or using masked-token prediction iteratively).

## Masked Language Modelling — BERT's Pretraining Objective

BERT is pretrained with Masked Language Modelling (MLM): 15% of input tokens are randomly selected. Of those, 80% are replaced with the special [MASK] token, 10% are replaced with a random token from the vocabulary, and 10% are left unchanged. The model is trained to predict the original token at each masked position using cross-entropy loss. This forces the model to build rich contextual representations because predicting a masked word requires understanding its left and right context simultaneously.

## BERT Architecture and Fine-Tuning

BERT-base: 12 layers, 12 attention heads, d_model=768, d_ff=3072, 110M parameters. BERT-large: 24 layers, 16 heads, d_model=1024, d_ff=4096, 340M parameters. Fine-tuning adds a task-specific head on top of the pretrained encoder. For sentence classification, a linear layer maps the [CLS] token representation (shape d_model) to the number of classes. For token-level tasks (NER, POS tagging), a linear head is applied to every token's representation. BERT popularised the pretrain-then-finetune paradigm that now dominates NLP.

## Code 1 — Encoder-Only Transformer Block from Scratch

A bidirectional (no causal mask) Transformer encoder block, showing that all L×L attention weight entries are non-zero.

```python
import torch
import torch.nn as nn

class EncoderBlock(nn.Module):
    """Encoder-only Transformer block: bidirectional self-attention, no causal mask.
    Pre-norm layout (modern variant).
    """
    def __init__(self, d_model: int, n_heads: int, d_ff: int,
                 dropout: float = 0.1):
        super().__init__()
        self.norm1 = nn.LayerNorm(d_model)
        self.norm2 = nn.LayerNorm(d_model)
        self.attn  = nn.MultiheadAttention(d_model, n_heads,
                                            dropout=dropout, batch_first=True)
        self.ff1   = nn.Linear(d_model, d_ff)
        self.ff2   = nn.Linear(d_ff, d_model)
        self.act   = nn.GELU()
        self.drop  = nn.Dropout(dropout)

    def forward(self, x: torch.Tensor,
                key_padding_mask: torch.Tensor = None):
        # No attn_mask passed -> bidirectional (all positions attend to all)
        n = self.norm1(x)
        a, weights = self.attn(n, n, n, key_padding_mask=key_padding_mask)
        x = x + self.drop(a)
        x = x + self.drop(self.ff2(self.act(self.ff1(self.norm2(x)))))
        return x, weights

# BERT-base dimensions
block = EncoderBlock(d_model=768, n_heads=12, d_ff=3072)
x = torch.randn(2, 12, 768)
out, attn = block(x)
print('Encoder output:', out.shape)          # (2, 12, 768)
print('Attention weights:', attn.shape)      # (2, 12, 12)
print('Non-zero weights:', (attn > 1e-6).sum().item(), '(all positions attend all)')
```

## Code 2 — MLM Data Preparation

Implementing the BERT masking strategy: 15% of tokens selected, 80% replaced with [MASK], 10% random, 10% unchanged. Labels of -100 at non-masked positions are ignored by CrossEntropyLoss.

```python
import torch
import random

def prepare_mlm_batch(token_ids: list, vocab_size: int,
                       mask_token_id: int, mask_prob: float = 0.15,
                       pad_id: int = 0):
    """BERT-style MLM masking.
    Of selected positions: 80% -> [MASK], 10% -> random, 10% -> unchanged.
    Returns (input_ids, labels, attention_mask) as tensors.
    labels[b, pos] = -100 (ignored) for non-masked positions.
    """
    max_len = max(len(s) for s in token_ids)
    inputs, labels, att_masks = [], [], []
    for seq in token_ids:
        ids   = list(seq)
        label = [-100] * max_len
        am    = [1] * len(seq) + [0] * (max_len - len(seq))
        ids  += [pad_id] * (max_len - len(seq))
        for pos in range(len(seq)):
            if random.random() < mask_prob:
                label[pos] = ids[pos]          # store original token as target
                r = random.random()
                if r < 0.80:                   # 80%: replace with [MASK]
                    ids[pos] = mask_token_id
                elif r < 0.90:                 # 10%: replace with random token
                    ids[pos] = random.randint(5, vocab_size - 1)
                # 10%: leave unchanged
        inputs.append(ids); labels.append(label); att_masks.append(am)
    return torch.tensor(inputs), torch.tensor(labels), torch.tensor(att_masks)

random.seed(42)
seqs   = [[101, 2054, 2003, 1996, 3007, 102], [101, 4067, 2024, 4658, 102]]
inp, lbl, am = prepare_mlm_batch(seqs, vocab_size=30000, mask_token_id=103)
print('Input IDs:')
print(inp)
print('Labels (-100 = not masked):')
print(lbl)
```

## Code 3 — BERT Fine-Tuning for Classification

Using HuggingFace transformers to fine-tune BERT for binary classification: a linear head on the [CLS] token representation with AdamW optimiser.

```python
import torch
import torch.nn as nn
from transformers import BertModel, BertTokenizer
from torch.optim import AdamW

class BertForSentiment(nn.Module):
    """BERT encoder + linear classification head on the [CLS] token."""
    def __init__(self, n_classes: int = 2, dropout: float = 0.1):
        super().__init__()
        self.bert       = BertModel.from_pretrained('bert-base-uncased')
        self.dropout    = nn.Dropout(dropout)
        self.classifier = nn.Linear(768, n_classes)

    def forward(self, input_ids, attention_mask, token_type_ids=None):
        out = self.bert(input_ids=input_ids,
                        attention_mask=attention_mask,
                        token_type_ids=token_type_ids)
        cls_rep = out.last_hidden_state[:, 0, :]   # [CLS] token at position 0
        return self.classifier(self.dropout(cls_rep))

# Tokenise and run one training step
tokenizer = BertTokenizer.from_pretrained('bert-base-uncased')
texts     = ['I love this film!', 'The movie was terrible.']
labels    = torch.tensor([1, 0])
enc       = tokenizer(texts, return_tensors='pt', padding=True, truncation=True)

model   = BertForSentiment()
optimr  = AdamW(model.parameters(), lr=2e-5, weight_decay=0.01)
loss_fn = nn.CrossEntropyLoss()

model.train()
logits = model(enc['input_ids'], enc['attention_mask'])
loss   = loss_fn(logits, labels)
loss.backward()
optimr.step()
print('Logits:', logits.detach())
print('Loss:  ', round(loss.item(), 4))
```

## Code 4 — ELECTRA Replaced Token Detection

ELECTRA (Clark et al. 2020) replaces MLM with a discriminative objective: a small generator corrupts tokens, and the discriminator must classify each token as real or replaced. More sample-efficient than MLM because the loss signal covers all tokens, not just the 15% masked.

```python
import torch
import torch.nn as nn
import random

def simulate_rtd(token_ids: torch.Tensor, gen_logits: torch.Tensor,
                 replace_prob: float = 0.15):
    """Simulate ELECTRA replaced token detection data creation.
    gen_logits: (B, L, V) — generator's token distribution at each position.
    Returns (corrupted_ids, rtd_labels) where rtd_labels: 0=real, 1=replaced.
    """
    B, L = token_ids.shape
    corrupted = token_ids.clone()
    rtd_labels = torch.zeros(B, L, dtype=torch.float)
    probs = torch.softmax(gen_logits, dim=-1)
    for b in range(B):
        for pos in range(L):
            if random.random() < replace_prob:
                orig        = token_ids[b, pos].item()
                replacement = torch.multinomial(probs[b, pos], 1).item()
                if replacement != orig:
                    corrupted[b, pos]  = replacement
                    rtd_labels[b, pos] = 1.0   # mark as replaced
    return corrupted, rtd_labels

class RTDHead(nn.Module):
    """Discriminator head: binary classification at every token position."""
    def __init__(self, d_model: int):
        super().__init__()
        self.linear = nn.Linear(d_model, 1)
    def forward(self, hidden): return self.linear(hidden).squeeze(-1)  # (B, L)

torch.manual_seed(0); random.seed(0)
B, L, V, d = 2, 8, 1000, 256
token_ids  = torch.randint(5, V, (B, L))
gen_logits = torch.randn(B, L, V)
corrupt, rtd_lbl = simulate_rtd(token_ids, gen_logits)
print('Original: ', token_ids[0].tolist())
print('Corrupted:', corrupt[0].tolist())
print('RTD labels (1=replaced):', rtd_lbl[0].tolist())
head    = RTDHead(d)
hidden  = torch.randn(B, L, d)
rtd_out = head(hidden)
loss    = nn.BCEWithLogitsLoss()(rtd_out, rtd_lbl)
print(f'RTD discriminator loss: {loss.item():.4f}')
```

## Encoder Models Compared

| Model | Pretraining Objective | Params | Tokens Seen | GLUE Score | Key Innovation |
| --- | --- | --- | --- | --- | --- |
| BERT-base | MLM + NSP | 110M | 16B | 80.5 | Bidirectional pretrain on large corpus |
| BERT-large | MLM + NSP | 340M | 16B | 82.1 | Scale: more layers, wider model |
| RoBERTa | MLM only (no NSP) | 125M | ~2T | 88.5 | Longer training, larger batches, more data |
| ELECTRA-base | Replaced Token Detection | 110M | 128B | 88.8 | Sample-efficient discriminative objective |
| DeBERTa-base | MLM + disentangled attn | 140M | 78B | 90.3 | Separate position and content attention keys |

Encoder-only models remain the top choice for NLU tasks — text classification, NER, extractive QA — where the full input is known at inference time. RoBERTa is the practical default: it significantly outperforms original BERT with only a training recipe change, no architecture modification. ELECTRA is the best choice when compute budget is tight, since its sample efficiency means it reaches RoBERTa-level quality with far less pretraining. DeBERTa currently holds the highest GLUE and SuperGLUE scores among encoder-only models, owing to its disentangled position and content attention.

