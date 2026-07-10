---
title: "Tokenizer-Free Models — Byte-Level and Patch-Based Approaches"
slug: "tokenizer-free-models"
description: "Tokenizer-free architectures operate on raw bytes or characters, eliminating BPE artifacts, OOV failures, and language-specific fertility imbalances. Covers ByT5 byte-level processing, MegaByte hierarchical patch models, CharFormer GBST soft tokenization, and CANINE character-level transformers."
tags: ["deep-learning", "llm"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"Conventional language models interpose a tokenizer between raw text and the neural network: text is segmented into subword tokens drawn from a fixed vocabulary, then mapped to integer ids. This design introduces several failure modes: out-of-vocabulary characters degrade to byte-fallback with extreme fertility, pre-tokenization rules embed language-specific assumptions (spaces, hyphens, apostrophes), and token fertility imbalance disadvantages low-resource languages. Tokenizer-free architectures bypass this entirely by operating on raw bytes or characters, passing the segmentation problem to the neural network itself."},{"type":"heading","level":2,"content":"Why Eliminate the Tokenizer?"},{"type":"text","content":"The four main motivations for tokenizer-free models are: (1) OOV elimination — a byte-level vocabulary of 256 values handles any Unicode text via UTF-8 encoding, with no unknown-token fallback; (2) language equality — each language\u0027s fertility is determined by its UTF-8 byte density, not by its representation in the tokenizer\u0027s training corpus; (3) character-level task performance — tasks like spelling correction, typo robustness, morphological analysis, and phonetic transcription require character-level access that subword tokenization obscures; (4) elimination of pre-tokenization rules — regex-based pre-tokenizers (e.g., GPT\u0027s handling of contractions and punctuation) embed English-centric assumptions that impair multilingual performance."},{"type":"heading","level":2,"content":"Byte-Level Input Pipeline"},{"type":"code","language":"python","content":"import torch\nimport torch.nn.functional as F\n\ndef text_to_byte_patches(text, patch_size=4, pad_id=0):\n    # Encode text to UTF-8 bytes\n    raw_bytes = list(text.encode(\u0027utf-8\u0027))\n    n_bytes = len(raw_bytes)\n    # Pad to multiple of patch_size\n    pad_len = (patch_size - n_bytes % patch_size) % patch_size\n    raw_bytes = raw_bytes + [pad_id] * pad_len\n    byte_tensor = torch.tensor(raw_bytes, dtype=torch.long)\n    n_patches = len(raw_bytes) // patch_size\n    patches = byte_tensor.view(n_patches, patch_size)\n    attention_mask = torch.ones(n_patches, dtype=torch.long)\n    # Mask padding patches\n    for i in range(n_patches - 1, -1, -1):\n        if patches[i].sum() == 0:\n            attention_mask[i] = 0\n        else:\n            break\n    return patches, attention_mask\n\nsamples = [\u0027Hello world\u0027, \u0027こんにちは\u0027, \u0027مرحبا\u0027]\nfor text in samples:\n    raw = text.encode(\u0027utf-8\u0027)\n    patches, mask = text_to_byte_patches(text, patch_size=4)\n    print(f\u0027{text!r:\u003c20}: {len(raw)} bytes -\u003e {patches.shape[0]} patches\u0027)\n    print(f\u0027  byte values: {list(raw[:12])}...\u0027)\n    print(f\u0027  patch[0]:    {patches[0].tolist()}\u0027)"},{"type":"heading","level":2,"content":"MegaByte — Hierarchical Patch-Based Processing"},{"type":"text","content":"MegaByte (Yu et al. 2023) uses a two-level hierarchical architecture to reduce the quadratic cost of attention over raw bytes. A global transformer model processes sequences of patch embeddings (each patch being P consecutive bytes). A local transformer operates within each patch to predict the next P bytes given the global context. With patch size P=4, sequence length is reduced P-fold compared to pure byte-level models. The global model captures long-range dependencies across patches; the local model handles fine-grained character-level generation within each patch. This achieves competitive perplexity to GPT-style BPE models at 1/P the effective sequence length."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\n\nclass MegaByteLocal(nn.Module):\n    # Local model: given patch context, predict next byte in patch\n    def __init__(self, patch_size=4, d_model=128, n_heads=4, n_layers=2):\n        super().__init__()\n        self.patch_size = patch_size\n        self.byte_embed = nn.Embedding(256 + 1, d_model)  # 256 bytes + pad\n        self.pos_embed = nn.Embedding(patch_size, d_model)\n        encoder_layer = nn.TransformerEncoderLayer(d_model, n_heads, dim_feedforward=256, batch_first=True)\n        self.transformer = nn.TransformerEncoder(encoder_layer, num_layers=n_layers)\n        self.out_proj = nn.Linear(d_model, 256)\n\n    def forward(self, byte_ids, global_context):\n        # byte_ids: (batch, patch_size); global_context: (batch, d_model)\n        B, P = byte_ids.shape\n        pos = torch.arange(P, device=byte_ids.device)\n        x = self.byte_embed(byte_ids) + self.pos_embed(pos).unsqueeze(0)\n        x = x + global_context.unsqueeze(1)  # inject global context\n        x = self.transformer(x)\n        return self.out_proj(x)  # (batch, patch_size, 256)\n\nclass MegaByteGlobal(nn.Module):\n    # Global model: process patch embeddings to produce context vectors\n    def __init__(self, patch_size=4, d_model=128, n_heads=4, n_layers=3):\n        super().__init__()\n        self.patch_embed = nn.Linear(patch_size * d_model, d_model)\n        encoder_layer = nn.TransformerEncoderLayer(d_model, n_heads, dim_feedforward=256, batch_first=True)\n        self.transformer = nn.TransformerEncoder(encoder_layer, num_layers=n_layers)\n\n    def forward(self, patch_embeddings):\n        x = self.transformer(patch_embeddings)\n        return x  # (batch, n_patches, d_model)\n\n# Demo\nB, N_patches, P, D = 2, 8, 4, 128\nbyte_ids = torch.randint(0, 256, (B, P))\nglobal_ctx = torch.randn(B, D)\nlocal_model = MegaByteLocal(patch_size=P, d_model=D)\nlogits = local_model(byte_ids, global_ctx)\nprint(f\u0027MegaByte local output: {logits.shape}  (batch, patch, vocab=256)\u0027)"},{"type":"heading","level":2,"content":"CharFormer GBST Soft Tokenization"},{"type":"text","content":"CharFormer (Tay et al. 2021) introduces Gradient-Based Subword Tokenization (GBST), a differentiable module that learns to group characters into variable-length subword-like representations without a fixed vocabulary. A learnable scoring function assigns each character position a soft assignment over candidate block widths (1, 2, 3, ... characters). These soft assignments are learned end-to-end by gradient descent, allowing the model to discover optimal groupings for the task. The resulting representation has reduced sequence length (by roughly the mean block width) and is fully differentiable, unlike hard BPE segmentation."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.nn.functional as F\n\nclass GBSTBlock(nn.Module):\n    # Simplified GBST: learn soft merging of characters into subword blocks\n    def __init__(self, d_model=64, max_block=4, downsample_factor=2):\n        super().__init__()\n        self.max_block = max_block\n        self.downsample_factor = downsample_factor\n        self.char_embed = nn.Embedding(256, d_model)\n        self.score_proj = nn.Linear(d_model, max_block)\n        self.block_proj = nn.ModuleList([nn.Linear(d_model * w, d_model) for w in range(1, max_block + 1)])\n\n    def forward(self, char_ids):\n        # char_ids: (batch, seq_len)\n        B, L = char_ids.shape\n        x = self.char_embed(char_ids)  # (B, L, d_model)\n        scores = self.score_proj(x)     # (B, L, max_block) -- block width scores\n        weights = F.softmax(scores, dim=-1)  # soft block width assignment\n        # Aggregate: for position i, collect weighted sum across block widths\n        out = x.clone()\n        for w_idx, w in enumerate(range(1, self.max_block + 1)):\n            if w == 1:\n                contribution = x * weights[:, :, w_idx:w_idx+1]\n            else:\n                padded = F.pad(x, (0, 0, 0, w - 1))\n                pooled = padded.unfold(1, w, 1).mean(-1)  # (B, L, d_model)\n                contribution = pooled * weights[:, :, w_idx:w_idx+1]\n            out = out + contribution\n        # Downsample by taking every downsample_factor-th position\n        out = out[:, ::self.downsample_factor, :]  # (B, L//ds, d_model)\n        return out\n\ngbst = GBSTBlock(d_model=64, max_block=4, downsample_factor=2)\nchars = torch.randint(0, 256, (2, 16))\nout = gbst(chars)\nprint(f\u0027Input:  {chars.shape}  (batch=2, seq_len=16 chars)\u0027)\nprint(f\u0027Output: {out.shape}   (batch=2, seq_len={out.shape[1]} after 2x downsample)\u0027)"},{"type":"heading","level":2,"content":"ByT5 Tokenizer Usage"},{"type":"code","language":"python","content":"from transformers import AutoTokenizer, T5Tokenizer\nimport torch\n\ndef compare_byt5_vs_t5(texts):\n    byt5_tok = AutoTokenizer.from_pretrained(\u0027google/byt5-small\u0027)\n    t5_tok = T5Tokenizer.from_pretrained(\u0027t5-small\u0027)\n    print(f\u0027{\"Text\":\u003c40} {\"ByT5 tokens\":\u003e12} {\"T5 tokens\":\u003e12} {\"Ratio\":\u003e8}\u0027)\n    for text in texts:\n        byt5_ids = byt5_tok.encode(text)\n        t5_ids = t5_tok.encode(text)\n        ratio = len(byt5_ids) / max(len(t5_ids), 1)\n        short = text[:38] + \u0027..\u0027 if len(text) \u003e 40 else text\n        print(f\u0027{short:\u003c40} {len(byt5_ids):\u003e12} {len(t5_ids):\u003e12} {ratio:\u003e8.2f}x\u0027)\n    # Show byte-level tokens for a short text\n    sample = texts[0]\n    ids = byt5_tok.encode(sample)\n    decoded = [byt5_tok.decode([i]) for i in ids[:10]]\n    print(f\u0027\\nByT5 byte tokens for {repr(sample[:20])}:\u0027)\n    print(f\u0027  ids={ids[:10]}  decoded={decoded}\u0027)\n\ntexts = [\n    \u0027Hello world\u0027,\n    \u0027naïve café résumé\u0027,\n    \u0027Speling mistaek correksion\u0027,\n    \u0027日本語テキスト\u0027,\n    \u0027مرحبا بالعالم\u0027,\n]\ncompare_byt5_vs_t5(texts)"},{"type":"heading","level":2,"content":"Tokenizer-Free Architectures Comparison"},{"type":"table","headers":["Architecture","Approach","Effective Vocab","Seq Length Factor","Key Strength"],"rows":[["ByT5","Pure byte-level T5 encoder-decoder","256 bytes + 3 special","3–8× longer than BPE","No OOV; equal language treatment; robust to noise"],["MegaByte","Patch-based: global model over patches + local over bytes","256 bytes (local)","~1/P of byte-level (P=4–16)","Scales byte models to long sequences; competitive perplexity"],["CharFormer (GBST)","Differentiable soft character grouping","256 chars; learned subword blocks","~2–4× longer than BPE","End-to-end differentiable tokenization; task-adaptive grouping"],["CANINE","Char-level with strided conv compression","143,000+ Unicode code points","~4× longer than BPE then compressed","Multilingual with no script bias; hash-based embedding"],["Byte-level BPE","BPE applied to raw bytes instead of chars","256–50,000 merged byte tokens","Similar to subword BPE","Eliminates OOV while keeping BPE merge efficiency"]]},{"type":"heading","level":2,"content":"Tradeoffs vs Subword Models"},{"type":"text","content":"The fundamental tradeoff of tokenizer-free models is sequence length versus generality. Operating on bytes or characters increases sequence length by 3–8× compared to BPE on the same text. Transformer self-attention scales quadratically with sequence length, making byte-level models proportionally more expensive. ByT5-small achieves comparable translation quality to T5-small on multilingual benchmarks but requires 3–5× more FLOPs per forward pass. Patch-based models like MegaByte reduce this cost by grouping bytes, but require a two-level architecture that complicates training and inference."},{"type":"callout","variant":"info","title":"MegaByte Patch Models Reduce Sequence Length P-Fold","content":"MegaByte-style patch-based models achieve competitive perplexity at 1/P the sequence length of pure byte models by grouping bytes into patches — the local model handles intra-patch generation while the global model captures long-range context. With patch size P=8, a 1000-byte document requires only 125 global attention steps instead of 1000, bringing the quadratic attention cost down by 64×. The local model\u0027s cost is constant per patch and parallelisable across patches, making overall training cost comparable to a standard transformer on the same text with subword tokenisation."},{"type":"text","content":"Practical deployment considerations: ByT5 works best when the task is character-sensitive — spelling correction, transliteration, phonetic alignment, morphological analysis, or handling noisy user input with typos. For tasks where semantic content dominates and orthographic detail is irrelevant, BPE models are more efficient. CANINE and CharFormer are intermediate: they learn task-adaptive compression that reduces sequence length while retaining character-level access. For production multilingual systems where language equality matters more than inference cost, ByT5 or CANINE are strong baselines."},{"type":"list","ordered":false,"items":["ByT5 vocabulary: 256 raw bytes + 3 special tokens (pad, EOS, UNK) — the entire model is tokenizer-free.","MegaByte patch size P: larger P reduces sequence length but makes the local model\u0027s task harder; P=4–8 is typical.","CharFormer GBST is differentiable: the grouping is learned end-to-end, adapting to the task rather than text statistics.","CANINE uses hash embeddings for Unicode code points, avoiding a fixed character vocabulary while covering all scripts.","Byte-level BPE (used in GPT-2 and RoBERTa) is a hybrid: BPE merges applied to bytes, eliminating OOV at the cost of higher fertility for rare scripts.","Tokenizer-free models excel on noisy text, code-switching, low-resource languages, and character-level tasks."]},{"type":"text","content":"Research directions for tokenizer-free models include learned patch-size selection (adapting P per input region), combining patch-based compression with sparse attention for very long documents, and distilling knowledge from BPE models into byte-level models to warm-start training. The field is converging toward hybrid approaches — soft tokenization modules that learn BPE-like groupings differentially — which may eventually supersede the hand-designed tokenization pipelines of current frontier models."},{"type":"divider"}]"
---
# Tokenizer-Free Models — Byte-Level and Patch-Based Approaches

Conventional language models interpose a tokenizer between raw text and the neural network: text is segmented into subword tokens drawn from a fixed vocabulary, then mapped to integer ids. This design introduces several failure modes: out-of-vocabulary characters degrade to byte-fallback with extreme fertility, pre-tokenization rules embed language-specific assumptions (spaces, hyphens, apostrophes), and token fertility imbalance disadvantages low-resource languages. Tokenizer-free architectures bypass this entirely by operating on raw bytes or characters, passing the segmentation problem to the neural network itself.

## Why Eliminate the Tokenizer?

The four main motivations for tokenizer-free models are: (1) OOV elimination — a byte-level vocabulary of 256 values handles any Unicode text via UTF-8 encoding, with no unknown-token fallback; (2) language equality — each language's fertility is determined by its UTF-8 byte density, not by its representation in the tokenizer's training corpus; (3) character-level task performance — tasks like spelling correction, typo robustness, morphological analysis, and phonetic transcription require character-level access that subword tokenization obscures; (4) elimination of pre-tokenization rules — regex-based pre-tokenizers (e.g., GPT's handling of contractions and punctuation) embed English-centric assumptions that impair multilingual performance.

## Byte-Level Input Pipeline

```python
import torch
import torch.nn.functional as F

def text_to_byte_patches(text, patch_size=4, pad_id=0):
    # Encode text to UTF-8 bytes
    raw_bytes = list(text.encode('utf-8'))
    n_bytes = len(raw_bytes)
    # Pad to multiple of patch_size
    pad_len = (patch_size - n_bytes % patch_size) % patch_size
    raw_bytes = raw_bytes + [pad_id] * pad_len
    byte_tensor = torch.tensor(raw_bytes, dtype=torch.long)
    n_patches = len(raw_bytes) // patch_size
    patches = byte_tensor.view(n_patches, patch_size)
    attention_mask = torch.ones(n_patches, dtype=torch.long)
    # Mask padding patches
    for i in range(n_patches - 1, -1, -1):
        if patches[i].sum() == 0:
            attention_mask[i] = 0
        else:
            break
    return patches, attention_mask

samples = ['Hello world', 'こんにちは', 'مرحبا']
for text in samples:
    raw = text.encode('utf-8')
    patches, mask = text_to_byte_patches(text, patch_size=4)
    print(f'{text!r:<20}: {len(raw)} bytes -> {patches.shape[0]} patches')
    print(f'  byte values: {list(raw[:12])}...')
    print(f'  patch[0]:    {patches[0].tolist()}')
```

## MegaByte — Hierarchical Patch-Based Processing

MegaByte (Yu et al. 2023) uses a two-level hierarchical architecture to reduce the quadratic cost of attention over raw bytes. A global transformer model processes sequences of patch embeddings (each patch being P consecutive bytes). A local transformer operates within each patch to predict the next P bytes given the global context. With patch size P=4, sequence length is reduced P-fold compared to pure byte-level models. The global model captures long-range dependencies across patches; the local model handles fine-grained character-level generation within each patch. This achieves competitive perplexity to GPT-style BPE models at 1/P the effective sequence length.

```python
import torch
import torch.nn as nn

class MegaByteLocal(nn.Module):
    # Local model: given patch context, predict next byte in patch
    def __init__(self, patch_size=4, d_model=128, n_heads=4, n_layers=2):
        super().__init__()
        self.patch_size = patch_size
        self.byte_embed = nn.Embedding(256 + 1, d_model)  # 256 bytes + pad
        self.pos_embed = nn.Embedding(patch_size, d_model)
        encoder_layer = nn.TransformerEncoderLayer(d_model, n_heads, dim_feedforward=256, batch_first=True)
        self.transformer = nn.TransformerEncoder(encoder_layer, num_layers=n_layers)
        self.out_proj = nn.Linear(d_model, 256)

    def forward(self, byte_ids, global_context):
        # byte_ids: (batch, patch_size); global_context: (batch, d_model)
        B, P = byte_ids.shape
        pos = torch.arange(P, device=byte_ids.device)
        x = self.byte_embed(byte_ids) + self.pos_embed(pos).unsqueeze(0)
        x = x + global_context.unsqueeze(1)  # inject global context
        x = self.transformer(x)
        return self.out_proj(x)  # (batch, patch_size, 256)

class MegaByteGlobal(nn.Module):
    # Global model: process patch embeddings to produce context vectors
    def __init__(self, patch_size=4, d_model=128, n_heads=4, n_layers=3):
        super().__init__()
        self.patch_embed = nn.Linear(patch_size * d_model, d_model)
        encoder_layer = nn.TransformerEncoderLayer(d_model, n_heads, dim_feedforward=256, batch_first=True)
        self.transformer = nn.TransformerEncoder(encoder_layer, num_layers=n_layers)

    def forward(self, patch_embeddings):
        x = self.transformer(patch_embeddings)
        return x  # (batch, n_patches, d_model)

# Demo
B, N_patches, P, D = 2, 8, 4, 128
byte_ids = torch.randint(0, 256, (B, P))
global_ctx = torch.randn(B, D)
local_model = MegaByteLocal(patch_size=P, d_model=D)
logits = local_model(byte_ids, global_ctx)
print(f'MegaByte local output: {logits.shape}  (batch, patch, vocab=256)')
```

## CharFormer GBST Soft Tokenization

CharFormer (Tay et al. 2021) introduces Gradient-Based Subword Tokenization (GBST), a differentiable module that learns to group characters into variable-length subword-like representations without a fixed vocabulary. A learnable scoring function assigns each character position a soft assignment over candidate block widths (1, 2, 3, ... characters). These soft assignments are learned end-to-end by gradient descent, allowing the model to discover optimal groupings for the task. The resulting representation has reduced sequence length (by roughly the mean block width) and is fully differentiable, unlike hard BPE segmentation.

```python
import torch
import torch.nn as nn
import torch.nn.functional as F

class GBSTBlock(nn.Module):
    # Simplified GBST: learn soft merging of characters into subword blocks
    def __init__(self, d_model=64, max_block=4, downsample_factor=2):
        super().__init__()
        self.max_block = max_block
        self.downsample_factor = downsample_factor
        self.char_embed = nn.Embedding(256, d_model)
        self.score_proj = nn.Linear(d_model, max_block)
        self.block_proj = nn.ModuleList([nn.Linear(d_model * w, d_model) for w in range(1, max_block + 1)])

    def forward(self, char_ids):
        # char_ids: (batch, seq_len)
        B, L = char_ids.shape
        x = self.char_embed(char_ids)  # (B, L, d_model)
        scores = self.score_proj(x)     # (B, L, max_block) -- block width scores
        weights = F.softmax(scores, dim=-1)  # soft block width assignment
        # Aggregate: for position i, collect weighted sum across block widths
        out = x.clone()
        for w_idx, w in enumerate(range(1, self.max_block + 1)):
            if w == 1:
                contribution = x * weights[:, :, w_idx:w_idx+1]
            else:
                padded = F.pad(x, (0, 0, 0, w - 1))
                pooled = padded.unfold(1, w, 1).mean(-1)  # (B, L, d_model)
                contribution = pooled * weights[:, :, w_idx:w_idx+1]
            out = out + contribution
        # Downsample by taking every downsample_factor-th position
        out = out[:, ::self.downsample_factor, :]  # (B, L//ds, d_model)
        return out

gbst = GBSTBlock(d_model=64, max_block=4, downsample_factor=2)
chars = torch.randint(0, 256, (2, 16))
out = gbst(chars)
print(f'Input:  {chars.shape}  (batch=2, seq_len=16 chars)')
print(f'Output: {out.shape}   (batch=2, seq_len={out.shape[1]} after 2x downsample)')
```

## ByT5 Tokenizer Usage

```python
from transformers import AutoTokenizer, T5Tokenizer
import torch

def compare_byt5_vs_t5(texts):
    byt5_tok = AutoTokenizer.from_pretrained('google/byt5-small')
    t5_tok = T5Tokenizer.from_pretrained('t5-small')
    print(f'{"Text":<40} {"ByT5 tokens":>12} {"T5 tokens":>12} {"Ratio":>8}')
    for text in texts:
        byt5_ids = byt5_tok.encode(text)
        t5_ids = t5_tok.encode(text)
        ratio = len(byt5_ids) / max(len(t5_ids), 1)
        short = text[:38] + '..' if len(text) > 40 else text
        print(f'{short:<40} {len(byt5_ids):>12} {len(t5_ids):>12} {ratio:>8.2f}x')
    # Show byte-level tokens for a short text
    sample = texts[0]
    ids = byt5_tok.encode(sample)
    decoded = [byt5_tok.decode([i]) for i in ids[:10]]
    print(f'\nByT5 byte tokens for {repr(sample[:20])}:')
    print(f'  ids={ids[:10]}  decoded={decoded}')

texts = [
    'Hello world',
    'naïve café résumé',
    'Speling mistaek correksion',
    '日本語テキスト',
    'مرحبا بالعالم',
]
compare_byt5_vs_t5(texts)
```

## Tokenizer-Free Architectures Comparison

| Architecture | Approach | Effective Vocab | Seq Length Factor | Key Strength |
| --- | --- | --- | --- | --- |
| ByT5 | Pure byte-level T5 encoder-decoder | 256 bytes + 3 special | 3–8× longer than BPE | No OOV; equal language treatment; robust to noise |
| MegaByte | Patch-based: global model over patches + local over bytes | 256 bytes (local) | ~1/P of byte-level (P=4–16) | Scales byte models to long sequences; competitive perplexity |
| CharFormer (GBST) | Differentiable soft character grouping | 256 chars; learned subword blocks | ~2–4× longer than BPE | End-to-end differentiable tokenization; task-adaptive grouping |
| CANINE | Char-level with strided conv compression | 143,000+ Unicode code points | ~4× longer than BPE then compressed | Multilingual with no script bias; hash-based embedding |
| Byte-level BPE | BPE applied to raw bytes instead of chars | 256–50,000 merged byte tokens | Similar to subword BPE | Eliminates OOV while keeping BPE merge efficiency |

## Tradeoffs vs Subword Models

The fundamental tradeoff of tokenizer-free models is sequence length versus generality. Operating on bytes or characters increases sequence length by 3–8× compared to BPE on the same text. Transformer self-attention scales quadratically with sequence length, making byte-level models proportionally more expensive. ByT5-small achieves comparable translation quality to T5-small on multilingual benchmarks but requires 3–5× more FLOPs per forward pass. Patch-based models like MegaByte reduce this cost by grouping bytes, but require a two-level architecture that complicates training and inference.

> **MegaByte Patch Models Reduce Sequence Length P-Fold**: MegaByte-style patch-based models achieve competitive perplexity at 1/P the sequence length of pure byte models by grouping bytes into patches — the local model handles intra-patch generation while the global model captures long-range context. With patch size P=8, a 1000-byte document requires only 125 global attention steps instead of 1000, bringing the quadratic attention cost down by 64×. The local model's cost is constant per patch and parallelisable across patches, making overall training cost comparable to a standard transformer on the same text with subword tokenisation.

Practical deployment considerations: ByT5 works best when the task is character-sensitive — spelling correction, transliteration, phonetic alignment, morphological analysis, or handling noisy user input with typos. For tasks where semantic content dominates and orthographic detail is irrelevant, BPE models are more efficient. CANINE and CharFormer are intermediate: they learn task-adaptive compression that reduces sequence length while retaining character-level access. For production multilingual systems where language equality matters more than inference cost, ByT5 or CANINE are strong baselines.

- ByT5 vocabulary: 256 raw bytes + 3 special tokens (pad, EOS, UNK) — the entire model is tokenizer-free.
- MegaByte patch size P: larger P reduces sequence length but makes the local model's task harder; P=4–8 is typical.
- CharFormer GBST is differentiable: the grouping is learned end-to-end, adapting to the task rather than text statistics.
- CANINE uses hash embeddings for Unicode code points, avoiding a fixed character vocabulary while covering all scripts.
- Byte-level BPE (used in GPT-2 and RoBERTa) is a hybrid: BPE merges applied to bytes, eliminating OOV at the cost of higher fertility for rare scripts.
- Tokenizer-free models excel on noisy text, code-switching, low-resource languages, and character-level tasks.

Research directions for tokenizer-free models include learned patch-size selection (adapting P per input region), combining patch-based compression with sparse attention for very long documents, and distilling knowledge from BPE models into byte-level models to warm-start training. The field is converging toward hybrid approaches — soft tokenization modules that learn BPE-like groupings differentially — which may eventually supersede the hand-designed tokenization pipelines of current frontier models.

---

