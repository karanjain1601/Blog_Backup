---
title: "Encoder-Decoder Transformers — T5, BART, and Seq2Seq"
slug: "encoder-decoder-t5-bart"
description: "Encoder-decoder architecture for seq2seq tasks: bidirectional encoder, autoregressive decoder with cross-attention, T5 text-to-text framing, BART denoising pretraining, and comparison with decoder-only models."
tags: ["deep-learning", "transformers", "attention-efficiency"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"Encoder-decoder transformers process input sequences with a bidirectional encoder — every position can attend to every other position — and generate output sequences with a causal decoder that additionally attends to the encoder\u0027s output via cross-attention. This architecture is natural for tasks where the input and output sequences have different lengths and structures: translation, summarization, and question answering. T5 and BART are the canonical encoder-decoder pretrained language models and remain strong baselines for many structured generation tasks."},{"type":"heading","level":2,"content":"Encoder-Decoder Architecture"},{"type":"text","content":"The encoder receives the source sequence, applies L_enc layers of bidirectional self-attention and FFN, and outputs a sequence of context vectors H_enc ∈ ℝ^{S×d}. The decoder receives the target prefix, applies L_dec layers of causal self-attention followed by cross-attention over H_enc, then FFN. Cross-attention computes Q from the decoder hidden state, K and V from H_enc: CrossAttn(x_dec, H_enc) = softmax(QK^T/√d)V. This allows the decoder to selectively focus on different parts of the source at each generation step."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.nn.functional as F\n\nclass CrossAttention(nn.Module):\n    def __init__(self, d_model=512, n_heads=8):\n        super().__init__()\n        self.n_heads, self.d_head = n_heads, d_model // n_heads\n        self.q_proj = nn.Linear(d_model, d_model, bias=False)\n        self.kv_proj = nn.Linear(d_model, 2 * d_model, bias=False)\n        self.out_proj = nn.Linear(d_model, d_model, bias=False)\n\n    def forward(self, x_dec, enc_out):\n        B, T_dec, C = x_dec.shape\n        T_enc = enc_out.shape[1]\n        q = self.q_proj(x_dec).view(B, T_dec, self.n_heads, self.d_head).transpose(1, 2)\n        k, v = self.kv_proj(enc_out).split(C, dim=-1)\n        k = k.view(B, T_enc, self.n_heads, self.d_head).transpose(1, 2)\n        v = v.view(B, T_enc, self.n_heads, self.d_head).transpose(1, 2)\n        att = F.softmax((q @ k.transpose(-2, -1)) * self.d_head ** -0.5, dim=-1)\n        out = (att @ v).transpose(1, 2).contiguous().view(B, T_dec, C)\n        return self.out_proj(out)\n\n# Simulate encoder output and decoder query\nenc_out = torch.randn(2, 20, 512)   # source: 20 tokens\ndec_query = torch.randn(2, 5, 512)  # target prefix: 5 tokens\ncross_attn = CrossAttention()\nout = cross_attn(dec_query, enc_out)\nprint(f\u0027Cross-attention output: {out.shape}\u0027)  # (2, 5, 512)\nprint(f\u0027Each decoder position attends to all {enc_out.shape[1]} encoder positions\u0027)"},{"type":"heading","level":2,"content":"T5: Text-to-Text Transfer Transformer"},{"type":"text","content":"T5 (Raffel et al. 2020) unifies all NLP tasks by framing them as text-to-text: the input is a task-prefixed string (e.g., \u0027summarize: ...\u0027, \u0027translate English to French: ...\u0027) and the output is always a string. This single architecture handles classification (output is a class label string), regression (output is a number string), and generation tasks uniformly. T5 replaces absolute position embeddings with learned relative position biases added to attention logits: attn_logit(i,j) += b(i−j), where b is a scalar bias indexed by relative distance."},{"type":"code","language":"python","content":"from transformers import T5ForConditionalGeneration, T5Tokenizer\nimport torch\n\n# T5 text-to-text fine-tuning example (illustrative)\ntokenizer = T5Tokenizer.from_pretrained(\u0027t5-small\u0027)\nmodel = T5ForConditionalGeneration.from_pretrained(\u0027t5-small\u0027)\nmodel.train()\noptimizer = torch.optim.AdamW(model.parameters(), lr=3e-4)\n\n# Simulate a summarization batch\ninput_texts = [\n    \u0027summarize: The quick brown fox jumps over the lazy dog. \u0027\n    \u0027Foxes are known for their agility and speed.\u0027,\n    \u0027summarize: Neural networks learn representations from data. \u0027\n    \u0027Deep networks stack multiple layers of nonlinear transformations.\u0027\n]\ntarget_texts = [\u0027Fox jumps over dog.\u0027, \u0027Neural nets learn from data.\u0027]\n\ninputs = tokenizer(input_texts, return_tensors=\u0027pt\u0027, padding=True, truncation=True, max_length=128)\nlabels = tokenizer(target_texts, return_tensors=\u0027pt\u0027, padding=True).input_ids\nlabels[labels == tokenizer.pad_token_id] = -100  # ignore padding in loss\n\noutputs = model(**inputs, labels=labels)\nprint(f\u0027Loss: {outputs.loss.item():.4f}\u0027)\noutputs.loss.backward()\noptimizer.step(); optimizer.zero_grad()\nprint(f\u0027T5-small params: {sum(p.numel() for p in model.parameters()):,}\u0027)"},{"type":"heading","level":2,"content":"BART: Denoising Autoencoder"},{"type":"text","content":"BART (Lewis et al. 2020) pretrained an encoder-decoder by corrupting input text and training the model to reconstruct the original. The encoder is bidirectional BERT-style; the decoder is GPT-style autoregressive. Corruption strategies include: token masking (like BERT), token deletion, text infilling (replace a span with one MASK token), sentence permutation, and document rotation. BART\u0027s pretraining objective makes its decoder particularly well-suited for generation tasks — it already knows how to produce fluent text conditioned on a noisy input."},{"type":"callout","variant":"info","title":"BART vs T5 Task Strengths","content":"BART excels at generation tasks (summarization, dialogue, translation) because its pretraining directly trains the decoder to generate fluent text. T5\u0027s text-to-text framing makes it stronger on classification-style tasks framed as generation (e.g., NLI, sentiment) because any label can be a token string. For ROUGE scores on CNN/DailyMail summarization, BART-large typically outperforms T5-large by 1-2 ROUGE points."},{"type":"code","language":"python","content":"from transformers import BartForConditionalGeneration, BartTokenizer\nimport torch\n\ntokenizer = BartTokenizer.from_pretrained(\u0027facebook/bart-base\u0027)\nmodel = BartForConditionalGeneration.from_pretrained(\u0027facebook/bart-base\u0027)\nmodel.eval()\n\narticle = (\n    \u0027Transformer models have revolutionized natural language processing. \u0027\n    \u0027Originally proposed for machine translation, they now dominate tasks ranging \u0027\n    \u0027from text classification to open-ended generation. The key innovation is the \u0027\n    \u0027attention mechanism, which allows every token to attend to every other token.\u0027\n)\n\ninputs = tokenizer(article, return_tensors=\u0027pt\u0027, max_length=512, truncation=True)\nwith torch.no_grad():\n    summary_ids = model.generate(\n        inputs[\u0027input_ids\u0027],\n        num_beams=4,\n        max_length=60,\n        min_length=10,\n        length_penalty=2.0,\n        early_stopping=True\n    )\nsummary = tokenizer.decode(summary_ids[0], skip_special_tokens=True)\nprint(f\u0027Article length: {len(article.split())} words\u0027)\nprint(f\u0027Summary: {summary}\u0027)\nprint(f\u0027BART-base params: {sum(p.numel() for p in model.parameters()):,}\u0027)"},{"type":"heading","level":2,"content":"Comparing BART vs T5 vs GPT-2 on Summarization"},{"type":"code","language":"python","content":"# Simulated ROUGE comparison (representative published numbers)\nimport numpy as np\n\nmodels = [\u0027GPT-2 (117M)\u0027, \u0027T5-base (250M)\u0027, \u0027T5-large (770M)\u0027, \u0027BART-base (140M)\u0027, \u0027BART-large (400M)\u0027]\n# CNN/DailyMail ROUGE-1, ROUGE-2, ROUGE-L (approximate published values)\nresults = [\n    [29.3, 8.6, 26.2],   # GPT-2 (fine-tuned)\n    [42.5, 20.9, 39.8],  # T5-base fine-tuned\n    [43.1, 21.6, 40.3],  # T5-large fine-tuned\n    [44.2, 21.3, 40.9],  # BART-base fine-tuned\n    [44.2, 21.3, 40.9],  # BART-large fine-tuned\n]\n\nprint(f\u0027{\u0027Model\u0027:\u003c25} {\u0027R-1\u0027:\u003e6} {\u0027R-2\u0027:\u003e6} {\u0027R-L\u0027:\u003e6}\u0027)\nprint(\u0027-\u0027 * 45)\nfor name, (r1, r2, rl) in zip(models, results):\n    print(f\u0027{name:\u003c25} {r1:\u003e6.1f} {r2:\u003e6.1f} {rl:\u003e6.1f}\u0027)\n\nbest_r1_idx = np.argmax([r[0] for r in results])\nprint(f\u0027\\nBest ROUGE-1: {models[best_r1_idx]} with {results[best_r1_idx][0]}\u0027)\nprint(\u0027BART-large and T5-large are both competitive; BART stronger on gen tasks.\u0027)\nprint(\u0027GPT-2 lags significantly — decoder-only without enc context is disadvantaged for summarization.\u0027)"},{"type":"heading","level":2,"content":"Architecture Comparison: Encoder Types"},{"type":"table","headers":["Attribute","Encoder-Only (BERT)","Decoder-Only (GPT)","Encoder-Decoder (T5/BART)"],"rows":[["Attention type","Bidirectional self-attention","Causal self-attention","Bidir encoder + causal decoder + cross-attn"],["Pretraining objective","MLM / NSP","Causal LM (NLL)","Text-to-text LM / denoising"],["Autoregressive generation","No","Yes","Yes (decoder side)"],["Input representation","Full context, best for understanding","Left-context only","Full source, autoregressive target"],["Inference cost","O(n) — single forward pass","O(n) per step; KV cache helps","O(n_src) encoder + O(n_tgt) per step decoder"],["Best tasks","Classification, NER, QA extractive","Open generation, chat, code","Translation, summarization, QA abstractive"],["Examples","BERT, RoBERTa, DeBERTa","GPT-2/3/4, LLaMA, Mistral","T5, BART, mT5, PEGASUS"]]},{"type":"heading","level":2,"content":"T5-Specific Design Choices"},{"type":"text","content":"T5 eliminates all bias terms from linear projections (no bias in Q, K, V, FFN, or output layers), which reduces parameters slightly and was found not to hurt performance. Instead of absolute position embeddings, T5 uses learned relative position biases: scalar offsets b(i−j) added to attention logits, indexed by relative distance and clipped to a maximum offset. These biases are shared across attention heads and across layers, making them extremely parameter-efficient. Relative position biases generalize better to sequence lengths longer than those seen during training — a key advantage over learned absolute positions."},{"type":"heading","level":2,"content":"Cross-Attention Complexity and Inference Cost"},{"type":"text","content":"Cross-attention has complexity O(S × T) where S is source length and T is target length. For long documents (S=8192) with long summaries (T=512), this is 4M attention computations per layer per head — not cheap. Decoder-only models avoid cross-attention entirely, which simplifies the architecture and reduces memory bandwidth. However, decoder-only models must fit the entire source into their context window as prefix text, which also has O(n²) attention cost. For very long source + short target tasks, encoder-decoder is competitive because the encoder processes source once."},{"type":"list","ordered":false,"items":["T5 relative position bias: bias b(i-j) added to attention logits; shared across heads; generalizes to unseen lengths.","BART positional embeddings: learned absolute positions (like GPT-2), max 1024 by default.","T5 uses no bias terms in any linear projection — a design choice that reduces parameters slightly.","BART encoder uses BERT-style architecture with pre-trained weights; decoder uses GPT-style causal masking.","Beam search is standard for encoder-decoder generation; decoder-only typically uses sampling instead."]},{"type":"text","content":"Encoder-decoder architectures remain the preferred choice for structured generation tasks with long inputs and short outputs — particularly document summarization, controlled translation, and data-to-text generation — where the bidirectional encoder produces richer source representations than a decoder-only prefix. As context windows for decoder-only models have grown to 128K+ tokens, the architectural advantage of encoder-decoder has narrowed, and many practical systems now simply prepend the source as context for a decoder-only model."},{"type":"divider"}]"
---
# Encoder-Decoder Transformers — T5, BART, and Seq2Seq

Encoder-decoder transformers process input sequences with a bidirectional encoder — every position can attend to every other position — and generate output sequences with a causal decoder that additionally attends to the encoder's output via cross-attention. This architecture is natural for tasks where the input and output sequences have different lengths and structures: translation, summarization, and question answering. T5 and BART are the canonical encoder-decoder pretrained language models and remain strong baselines for many structured generation tasks.

## Encoder-Decoder Architecture

The encoder receives the source sequence, applies L_enc layers of bidirectional self-attention and FFN, and outputs a sequence of context vectors H_enc ∈ ℝ^{S×d}. The decoder receives the target prefix, applies L_dec layers of causal self-attention followed by cross-attention over H_enc, then FFN. Cross-attention computes Q from the decoder hidden state, K and V from H_enc: CrossAttn(x_dec, H_enc) = softmax(QK^T/√d)V. This allows the decoder to selectively focus on different parts of the source at each generation step.

```python
import torch
import torch.nn as nn
import torch.nn.functional as F

class CrossAttention(nn.Module):
    def __init__(self, d_model=512, n_heads=8):
        super().__init__()
        self.n_heads, self.d_head = n_heads, d_model // n_heads
        self.q_proj = nn.Linear(d_model, d_model, bias=False)
        self.kv_proj = nn.Linear(d_model, 2 * d_model, bias=False)
        self.out_proj = nn.Linear(d_model, d_model, bias=False)

    def forward(self, x_dec, enc_out):
        B, T_dec, C = x_dec.shape
        T_enc = enc_out.shape[1]
        q = self.q_proj(x_dec).view(B, T_dec, self.n_heads, self.d_head).transpose(1, 2)
        k, v = self.kv_proj(enc_out).split(C, dim=-1)
        k = k.view(B, T_enc, self.n_heads, self.d_head).transpose(1, 2)
        v = v.view(B, T_enc, self.n_heads, self.d_head).transpose(1, 2)
        att = F.softmax((q @ k.transpose(-2, -1)) * self.d_head ** -0.5, dim=-1)
        out = (att @ v).transpose(1, 2).contiguous().view(B, T_dec, C)
        return self.out_proj(out)

# Simulate encoder output and decoder query
enc_out = torch.randn(2, 20, 512)   # source: 20 tokens
dec_query = torch.randn(2, 5, 512)  # target prefix: 5 tokens
cross_attn = CrossAttention()
out = cross_attn(dec_query, enc_out)
print(f'Cross-attention output: {out.shape}')  # (2, 5, 512)
print(f'Each decoder position attends to all {enc_out.shape[1]} encoder positions')
```

## T5: Text-to-Text Transfer Transformer

T5 (Raffel et al. 2020) unifies all NLP tasks by framing them as text-to-text: the input is a task-prefixed string (e.g., 'summarize: ...', 'translate English to French: ...') and the output is always a string. This single architecture handles classification (output is a class label string), regression (output is a number string), and generation tasks uniformly. T5 replaces absolute position embeddings with learned relative position biases added to attention logits: attn_logit(i,j) += b(i−j), where b is a scalar bias indexed by relative distance.

```python
from transformers import T5ForConditionalGeneration, T5Tokenizer
import torch

# T5 text-to-text fine-tuning example (illustrative)
tokenizer = T5Tokenizer.from_pretrained('t5-small')
model = T5ForConditionalGeneration.from_pretrained('t5-small')
model.train()
optimizer = torch.optim.AdamW(model.parameters(), lr=3e-4)

# Simulate a summarization batch
input_texts = [
    'summarize: The quick brown fox jumps over the lazy dog. '
    'Foxes are known for their agility and speed.',
    'summarize: Neural networks learn representations from data. '
    'Deep networks stack multiple layers of nonlinear transformations.'
]
target_texts = ['Fox jumps over dog.', 'Neural nets learn from data.']

inputs = tokenizer(input_texts, return_tensors='pt', padding=True, truncation=True, max_length=128)
labels = tokenizer(target_texts, return_tensors='pt', padding=True).input_ids
labels[labels == tokenizer.pad_token_id] = -100  # ignore padding in loss

outputs = model(**inputs, labels=labels)
print(f'Loss: {outputs.loss.item():.4f}')
outputs.loss.backward()
optimizer.step(); optimizer.zero_grad()
print(f'T5-small params: {sum(p.numel() for p in model.parameters()):,}')
```

## BART: Denoising Autoencoder

BART (Lewis et al. 2020) pretrained an encoder-decoder by corrupting input text and training the model to reconstruct the original. The encoder is bidirectional BERT-style; the decoder is GPT-style autoregressive. Corruption strategies include: token masking (like BERT), token deletion, text infilling (replace a span with one MASK token), sentence permutation, and document rotation. BART's pretraining objective makes its decoder particularly well-suited for generation tasks — it already knows how to produce fluent text conditioned on a noisy input.

> **BART vs T5 Task Strengths**: BART excels at generation tasks (summarization, dialogue, translation) because its pretraining directly trains the decoder to generate fluent text. T5's text-to-text framing makes it stronger on classification-style tasks framed as generation (e.g., NLI, sentiment) because any label can be a token string. For ROUGE scores on CNN/DailyMail summarization, BART-large typically outperforms T5-large by 1-2 ROUGE points.

```python
from transformers import BartForConditionalGeneration, BartTokenizer
import torch

tokenizer = BartTokenizer.from_pretrained('facebook/bart-base')
model = BartForConditionalGeneration.from_pretrained('facebook/bart-base')
model.eval()

article = (
    'Transformer models have revolutionized natural language processing. '
    'Originally proposed for machine translation, they now dominate tasks ranging '
    'from text classification to open-ended generation. The key innovation is the '
    'attention mechanism, which allows every token to attend to every other token.'
)

inputs = tokenizer(article, return_tensors='pt', max_length=512, truncation=True)
with torch.no_grad():
    summary_ids = model.generate(
        inputs['input_ids'],
        num_beams=4,
        max_length=60,
        min_length=10,
        length_penalty=2.0,
        early_stopping=True
    )
summary = tokenizer.decode(summary_ids[0], skip_special_tokens=True)
print(f'Article length: {len(article.split())} words')
print(f'Summary: {summary}')
print(f'BART-base params: {sum(p.numel() for p in model.parameters()):,}')
```

## Comparing BART vs T5 vs GPT-2 on Summarization

```python
# Simulated ROUGE comparison (representative published numbers)
import numpy as np

models = ['GPT-2 (117M)', 'T5-base (250M)', 'T5-large (770M)', 'BART-base (140M)', 'BART-large (400M)']
# CNN/DailyMail ROUGE-1, ROUGE-2, ROUGE-L (approximate published values)
results = [
    [29.3, 8.6, 26.2],   # GPT-2 (fine-tuned)
    [42.5, 20.9, 39.8],  # T5-base fine-tuned
    [43.1, 21.6, 40.3],  # T5-large fine-tuned
    [44.2, 21.3, 40.9],  # BART-base fine-tuned
    [44.2, 21.3, 40.9],  # BART-large fine-tuned
]

print(f'{'Model':<25} {'R-1':>6} {'R-2':>6} {'R-L':>6}')
print('-' * 45)
for name, (r1, r2, rl) in zip(models, results):
    print(f'{name:<25} {r1:>6.1f} {r2:>6.1f} {rl:>6.1f}')

best_r1_idx = np.argmax([r[0] for r in results])
print(f'\nBest ROUGE-1: {models[best_r1_idx]} with {results[best_r1_idx][0]}')
print('BART-large and T5-large are both competitive; BART stronger on gen tasks.')
print('GPT-2 lags significantly — decoder-only without enc context is disadvantaged for summarization.')
```

## Architecture Comparison: Encoder Types

| Attribute | Encoder-Only (BERT) | Decoder-Only (GPT) | Encoder-Decoder (T5/BART) |
| --- | --- | --- | --- |
| Attention type | Bidirectional self-attention | Causal self-attention | Bidir encoder + causal decoder + cross-attn |
| Pretraining objective | MLM / NSP | Causal LM (NLL) | Text-to-text LM / denoising |
| Autoregressive generation | No | Yes | Yes (decoder side) |
| Input representation | Full context, best for understanding | Left-context only | Full source, autoregressive target |
| Inference cost | O(n) — single forward pass | O(n) per step; KV cache helps | O(n_src) encoder + O(n_tgt) per step decoder |
| Best tasks | Classification, NER, QA extractive | Open generation, chat, code | Translation, summarization, QA abstractive |
| Examples | BERT, RoBERTa, DeBERTa | GPT-2/3/4, LLaMA, Mistral | T5, BART, mT5, PEGASUS |

## T5-Specific Design Choices

T5 eliminates all bias terms from linear projections (no bias in Q, K, V, FFN, or output layers), which reduces parameters slightly and was found not to hurt performance. Instead of absolute position embeddings, T5 uses learned relative position biases: scalar offsets b(i−j) added to attention logits, indexed by relative distance and clipped to a maximum offset. These biases are shared across attention heads and across layers, making them extremely parameter-efficient. Relative position biases generalize better to sequence lengths longer than those seen during training — a key advantage over learned absolute positions.

## Cross-Attention Complexity and Inference Cost

Cross-attention has complexity O(S × T) where S is source length and T is target length. For long documents (S=8192) with long summaries (T=512), this is 4M attention computations per layer per head — not cheap. Decoder-only models avoid cross-attention entirely, which simplifies the architecture and reduces memory bandwidth. However, decoder-only models must fit the entire source into their context window as prefix text, which also has O(n²) attention cost. For very long source + short target tasks, encoder-decoder is competitive because the encoder processes source once.

- T5 relative position bias: bias b(i-j) added to attention logits; shared across heads; generalizes to unseen lengths.
- BART positional embeddings: learned absolute positions (like GPT-2), max 1024 by default.
- T5 uses no bias terms in any linear projection — a design choice that reduces parameters slightly.
- BART encoder uses BERT-style architecture with pre-trained weights; decoder uses GPT-style causal masking.
- Beam search is standard for encoder-decoder generation; decoder-only typically uses sampling instead.

Encoder-decoder architectures remain the preferred choice for structured generation tasks with long inputs and short outputs — particularly document summarization, controlled translation, and data-to-text generation — where the bidirectional encoder produces richer source representations than a decoder-only prefix. As context windows for decoder-only models have grown to 128K+ tokens, the architectural advantage of encoder-decoder has narrowed, and many practical systems now simply prepend the source as context for a decoder-only model.

---

