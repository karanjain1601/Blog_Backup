---
title: "BPE — Byte-Pair Encoding and LLM Vocabulary Construction"
slug: "bpe-tokenization"
description: "How BPE builds LLM vocabularies by iteratively merging frequent character pairs, covering the merge algorithm, pre-tokenization, fertility analysis, and HuggingFace integration."
tags: ["deep-learning", "llm"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"Byte-Pair Encoding (BPE) is the tokenization algorithm used by GPT-2, GPT-3, and GPT-4. Originally a lossless data-compression technique, BPE was adapted for NLP by Sennrich et al. (2016) to handle open vocabularies in neural machine translation without out-of-vocabulary tokens. The algorithm starts with a vocabulary of individual characters (or bytes), then iteratively merges the most frequent adjacent symbol pair until the vocabulary reaches a target size V. The result is a set of subword units ranging from single characters to complete common words, with rare words split into their most frequent constituent pieces. Because every possible byte is in the initial vocabulary, byte-level BPE guarantees that any input text can be encoded without an [UNK] token."},{"type":"heading","level":2,"content":"Introduction"},{"type":"text","content":"Word-level vocabularies suffer from out-of-vocabulary tokens and require 500K+ entries to cover morphologically rich languages. Character-level models avoid OOV but produce very long sequences. BPE finds a middle ground: a 32K–100K subword vocabulary covers any input without UNK while keeping average sequence length manageable. GPT-2 uses 50,257-token byte-level BPE where all 256 bytes form the base vocabulary, ensuring zero OOV. GPT-4\u0027s cl100k_base uses 100,277 tokens with a refined 5-pattern regex pre-tokenizer. The fertility metric—average tokens per word—measures how efficiently a tokenizer uses context-window space; GPT-4\u0027s larger vocabulary achieves roughly 1.2–1.3 tokens/word on English text, versus 1.3–1.5 for GPT-2."},{"type":"heading","level":2,"content":"Merge Algorithm"},{"type":"text","content":"BPE training maintains a frequency table mapping each current token sequence (a word represented as its current tokens) to its corpus count. At each iteration: (1) count all adjacent token pairs across all words, weighting by word frequency; (2) select the most frequent pair (a, b); (3) add the merged token ab to the vocabulary; (4) update the token sequences by replacing every occurrence of (a b) with ab. The result is an ordered merge table—the order matters because encoding applies merges in the same order. A priority queue over pair frequencies reduces the per-merge scan from O(N) to O(log N), which is how tiktoken achieves fast encoding."},{"type":"code","language":"python","content":"from collections import Counter\nimport re\n\ndef build_vocab(corpus):\n    vocab = Counter()\n    for word in corpus.split():\n        vocab[\u0027 \u0027.join(list(word)) + \u0027 \u003c/w\u003e\u0027] += 1\n    return dict(vocab)\n\ndef get_pair_stats(vocab):\n    pairs = Counter()\n    for word, freq in vocab.items():\n        symbols = word.split()\n        for i in range(len(symbols) - 1):\n            pairs[(symbols[i], symbols[i+1])] += freq\n    return pairs\n\ndef merge_pair(pair, vocab):\n    pat = re.compile(r\u0027(?\u003c!\\S)\u0027 + re.escape(\u0027 \u0027.join(pair)) + r\u0027(?!\\S)\u0027)\n    return {pat.sub(\u0027\u0027.join(pair), w): f for w, f in vocab.items()}\n\ndef train_bpe(corpus, num_merges):\n    vocab, merges = build_vocab(corpus), []\n    for i in range(num_merges):\n        stats = get_pair_stats(vocab)\n        if not stats:\n            break\n        best = max(stats, key=stats.get)\n        vocab = merge_pair(best, vocab)\n        merges.append(best)\n        print(f\u0027  Merge {i+1:2d}: {best[0]+\" \"+best[1]:\u003c20} -\u003e {\"|\".join(best):\u003c18} freq={stats[best]}\u0027)\n    return merges\n\ncorpus = \u0027low lower lowest newer newest wider widest running runner runs \u0027 * 25\nprint(\u0027BPE Training:\u0027)\nmerge_table = train_bpe(corpus, num_merges=15)\nprint(f\u0027Total merges learned: {len(merge_table)}\u0027)"},{"type":"heading","level":2,"content":"Vocabulary Construction"},{"type":"text","content":"After training, the vocabulary = initial character set + one new token per merge. For GPT-2\u0027s byte-level BPE: 256 byte tokens + 50,000 merges + 1 special token = 50,257. Larger vocabularies reduce fertility but increase embedding-matrix memory. At 768 dimensions, a 100K-token vocabulary uses 100K × 768 × 4 bytes ≈ 295 MB for embeddings alone. Tail tokens—tokens that appear very rarely in the training corpus—consume vocabulary slots without contributing meaningfully to model quality; some tokenizer implementations prune tokens below a minimum frequency threshold before finalising the vocabulary."},{"type":"code","language":"python","content":"def bpe_encode(word, merges):\n    tokens = list(word) + [\u0027\u003c/w\u003e\u0027]\n    for pair in merges:\n        i, new = 0, []\n        while i \u003c len(tokens):\n            if i \u003c len(tokens) - 1 and (tokens[i], tokens[i+1]) == pair:\n                new.append(\u0027\u0027.join(pair))\n                i += 2\n            else:\n                new.append(tokens[i])\n                i += 1\n        tokens = new\n    return tokens\n\ndef bpe_decode(tokens):\n    return \u0027\u0027.join(tokens).replace(\u0027\u003c/w\u003e\u0027, \u0027\u0027)\n\ntest_words = [\u0027low\u0027, \u0027lower\u0027, \u0027lowest\u0027, \u0027newer\u0027, \u0027widest\u0027, \u0027unknown\u0027, \u0027runner\u0027]\nprint(f\u0027{\"Word\":\u003c12} {\"BPE Tokens\":\u003c42} {\"Count\":\u003e5}\u0027)\nprint(\u0027-\u0027 * 62)\nfor w in test_words:\n    toks = bpe_encode(w, merge_table)\n    dec  = bpe_decode(toks)\n    ok   = \u0027OK\u0027 if dec == w else \u0027ERR\u0027\n    print(f\u0027{w:\u003c12} {str(toks):\u003c42} {len(toks):\u003e5}  [{ok}]\u0027)\n\nprint(\u0027\\nDecoding: join tokens, strip \u003c/w\u003e. Lossless for known chars.\u0027)\nprint(\u0027Unknown words split to chars first, then merges applied where possible.\u0027)"},{"type":"heading","level":2,"content":"Encoding and Decoding"},{"type":"text","content":"BPE encoding applies learned merges in order: scan the current token list for the highest-priority merge pair, apply it, rescan. This greedy process is O(M × T) per word where M is the number of merges and T is the word length. The tiktoken library uses a priority-queue approach that achieves near-linear time and is 5–20× faster than Python BPE implementations. Decoding is trivial: concatenate the subword tokens and remove the end-of-word marker (\u003c/w\u003e for standard BPE; byte-level GPT-2 uses a separate byte-to-unicode mapping where space ð  and newline Ā are represented as single Unicode characters). Because every byte is in the initial vocabulary, decoding is always lossless."},{"type":"heading","level":2,"content":"Pre-Tokenization and Regex Splits"},{"type":"text","content":"Before BPE is applied, GPT-4\u0027s cl100k_base uses a 5-pattern regex to split text into pre-tokens: (1) contractions like \u0027s, \u0027t, \u0027re; (2) sequences of letters; (3) sequences of digits; (4) sequences of non-whitespace, non-letter, non-digit characters; (5) whitespace. This prevents BPE from producing cross-word merges such as \u0027e \u0027 (end of \u0027the\u0027 fused with the space before the next word). Without pre-tokenization, BPE would freely merge across word boundaries, creating tokens that depend on context rather than just subword content. GPT-2 uses a simpler regex. Language-specific pre-tokenizers for Chinese, Japanese, and code use different split strategies."},{"type":"code","language":"python","content":"import re\nfrom collections import Counter\n\ndef simple_bpe_fertility(corpus, n_merges):\n    \"\"\"Compute avg tokens/word after n_merges BPE operations.\"\"\"\n    word_freq = Counter(corpus.split())\n    vocab = {\u0027 \u0027.join(list(w)) + \u0027 \u003c/w\u003e\u0027: f for w, f in word_freq.items()}\n\n    def get_stats(v):\n        pairs = Counter()\n        for word, freq in v.items():\n            syms = word.split()\n            for i in range(len(syms) - 1):\n                pairs[(syms[i], syms[i+1])] += freq\n        return pairs\n\n    def merge(pair, v):\n        pat = re.compile(r\u0027(?\u003c!\\S)\u0027 + re.escape(\u0027 \u0027.join(pair)) + r\u0027(?!\\S)\u0027)\n        return {pat.sub(\u0027\u0027.join(pair), w): f for w, f in v.items()}\n\n    for _ in range(n_merges):\n        stats = get_stats(vocab)\n        if not stats:\n            break\n        vocab = merge(max(stats, key=stats.get), vocab)\n\n    total_tok = sum(len(w.split()) * f for w, f in vocab.items())\n    return total_tok / sum(word_freq.values())\n\ncorpus = (\u0027the quick brown fox jumps over the lazy dog \u0027\n          \u0027running runner runs lower lowest newer newest wider widest \u0027) * 30\nprint(\u0027Corpus fertility vs BPE merge count:\u0027)\nprint(f\u0027{\"Merges\":\u003e8} {\"Approx Scale\":\u003e14} {\"Fertility\":\u003e12}\u0027)\nprint(\u0027-\u0027 * 38)\nfor n, label in [(0, \u0027char-level\u0027), (8, \u0027~1K vocab\u0027), (20, \u0027~8K vocab\u0027), (40, \u0027~32K vocab\u0027)]:\n    f = simple_bpe_fertility(corpus, n)\n    print(f\u0027{n:\u003e8} {label:\u003e14} {f:\u003e12.3f}\u0027)"},{"type":"heading","level":2,"content":"Fertility and Vocabulary Size"},{"type":"text","content":"Fertility = average tokens per word. For English, GPT-2 (50K vocab) achieves fertility ≈1.3–1.5; GPT-4 (100K) achieves ≈1.2–1.3. Non-English languages suffer higher fertility when under-represented in training data: Chinese text may reach 2–4 tokens/word on GPT-2 because CJK characters are rare in its English-heavy corpus. Fertility directly determines effective context window length: at fertility 2.0, a 4096-token context holds only ≈2048 words. Choosing vocabulary size V requires balancing fertility, embedding-matrix memory, and frequency of tail tokens in the training corpus."},{"type":"table","headers":["Method","OOV Rate","Avg Fertility","Vocab Size","Training Complexity","Used By"],"rows":[["Character-level","0%","4–6 tok/word","~100–300","O(C) trivial","Early char-RNNs"],["Word-level","1–5%","1.0 tok/word","50K–500K","O(V) fast","Classic NLP, word2vec"],["BPE","0% (byte-level)","1.2–1.8 tok/word","32K–100K","O(V × merges)","GPT-2/3/4, RoBERTa"],["Unigram LM","0% (byte fallback)","1.2–1.8 tok/word","16K–64K","O(V × EM iters)","T5, mT5, Gemma, LLaMA"],["WordPiece","~0.1% ([UNK])","1.3–2.0 tok/word","28K–32K","O(V × likelihood)","BERT, DistilBERT, ELECTRA"]]},{"type":"heading","level":2,"content":"HuggingFace Integration"},{"type":"text","content":"HuggingFace AutoTokenizer loads the correct tokenizer class for any model checkpoint. GPT-2 uses PreTrainedTokenizerFast, backed by the Rust tokenizers library—typically 10–100× faster than the Python implementation and supporting offset_mapping to align token positions back to character spans in the original text. This is essential for span-extraction tasks such as NER and QA. For GPT-4\u0027s cl100k_base, use the tiktoken library directly (not available through HuggingFace), which is the production tokenizer used by OpenAI\u0027s API."},{"type":"code","language":"python","content":"from transformers import AutoTokenizer\n\n# Load GPT-2 tokenizer (50,257-token byte-level BPE)\ntokenizer = AutoTokenizer.from_pretrained(\u0027gpt2\u0027)\n\ntext = \u0027Byte-pair encoding merges frequent character pairs iteratively.\u0027\nencoding = tokenizer(text, return_tensors=\u0027pt\u0027, return_offsets_mapping=True)\nids     = encoding[\u0027input_ids\u0027][0].tolist()\noffsets = encoding[\u0027offset_mapping\u0027][0].tolist()\ntokens  = tokenizer.convert_ids_to_tokens(ids)\n\nprint(f\u0027Text   : {text}\u0027)\nprint(f\u0027Tokens : {tokens}\u0027)\nprint(f\u0027Vocab size : {tokenizer.vocab_size}\u0027)\nprint(f\u0027Special    : {tokenizer.all_special_tokens}\u0027)\nprint()\nprint(f\u0027{\"Token\":\u003c22} {\"ID\":\u003e6}  Char span\u0027)\nfor tok, tid, (s, e) in zip(tokens, ids, offsets):\n    print(f\u0027{repr(tok):\u003c22} {tid:\u003e6}  [{s}:{e}] -\u003e {repr(text[s:e])}\u0027)\n\nwords = [\u0027Hello\u0027, \u0027Supercalifragilistic\u0027, \u0027tokenization\u0027, \u0027GPT-4\u0027]\nprint(\u0027\\nFertility samples (GPT-2 tokenizer):\u0027)\nfor w in words:\n    toks = tokenizer.tokenize(w)\n    print(f\u0027  {w!r:\u003c25} -\u003e {len(toks)} tokens: {toks}\u0027)"},{"type":"callout","variant":"warning","title":"Merge Order Dependency","content":"BPE merges are greedy and order-dependent — different corpus samples or random seeds produce different merge orders even for the same final vocabulary size, leading to different tokenizations of the same text. Two BPE tokenizers trained on different corpora with identical target vocabulary sizes will generally disagree on how to tokenize identical inputs. Always use the exact tokenizer checkpoint that was used during model training; substituting a different BPE tokenizer of the same nominal vocab size will produce incorrect token IDs and degrade model quality."},{"type":"heading","level":2,"content":"Key Takeaways"},{"type":"list","ordered":false,"items":["BPE starts from a character (or byte) vocabulary and greedily merges the most frequent adjacent pair — one merge per vocabulary slot.","GPT-2 uses byte-level BPE with 50,257 tokens; GPT-4 uses cl100k_base with 100,277 tokens and a 5-pattern regex pre-tokenizer.","Fertility (avg tokens per word) measures tokenizer efficiency; lower fertility means fewer tokens per word and more text fits in a fixed context window.","Pre-tokenization with regex prevents cross-word merges; GPT-4\u0027s regex splits on contractions, letters, digits, and punctuation separately.","Byte-level BPE guarantees zero OOV — any byte sequence can be encoded using the 256 initial byte tokens.","Larger vocabulary sizes reduce fertility but increase embedding-matrix memory; 100K × 768d = 295 MB for embeddings alone.","Use tiktoken for GPT-4 tokenization; use HuggingFace AutoTokenizer with return_offsets_mapping=True for span-extraction tasks."]},{"type":"divider"}]"
---
# BPE — Byte-Pair Encoding and LLM Vocabulary Construction

Byte-Pair Encoding (BPE) is the tokenization algorithm used by GPT-2, GPT-3, and GPT-4. Originally a lossless data-compression technique, BPE was adapted for NLP by Sennrich et al. (2016) to handle open vocabularies in neural machine translation without out-of-vocabulary tokens. The algorithm starts with a vocabulary of individual characters (or bytes), then iteratively merges the most frequent adjacent symbol pair until the vocabulary reaches a target size V. The result is a set of subword units ranging from single characters to complete common words, with rare words split into their most frequent constituent pieces. Because every possible byte is in the initial vocabulary, byte-level BPE guarantees that any input text can be encoded without an [UNK] token.

## Introduction

Word-level vocabularies suffer from out-of-vocabulary tokens and require 500K+ entries to cover morphologically rich languages. Character-level models avoid OOV but produce very long sequences. BPE finds a middle ground: a 32K–100K subword vocabulary covers any input without UNK while keeping average sequence length manageable. GPT-2 uses 50,257-token byte-level BPE where all 256 bytes form the base vocabulary, ensuring zero OOV. GPT-4's cl100k_base uses 100,277 tokens with a refined 5-pattern regex pre-tokenizer. The fertility metric—average tokens per word—measures how efficiently a tokenizer uses context-window space; GPT-4's larger vocabulary achieves roughly 1.2–1.3 tokens/word on English text, versus 1.3–1.5 for GPT-2.

## Merge Algorithm

BPE training maintains a frequency table mapping each current token sequence (a word represented as its current tokens) to its corpus count. At each iteration: (1) count all adjacent token pairs across all words, weighting by word frequency; (2) select the most frequent pair (a, b); (3) add the merged token ab to the vocabulary; (4) update the token sequences by replacing every occurrence of (a b) with ab. The result is an ordered merge table—the order matters because encoding applies merges in the same order. A priority queue over pair frequencies reduces the per-merge scan from O(N) to O(log N), which is how tiktoken achieves fast encoding.

```python
from collections import Counter
import re

def build_vocab(corpus):
    vocab = Counter()
    for word in corpus.split():
        vocab[' '.join(list(word)) + ' </w>'] += 1
    return dict(vocab)

def get_pair_stats(vocab):
    pairs = Counter()
    for word, freq in vocab.items():
        symbols = word.split()
        for i in range(len(symbols) - 1):
            pairs[(symbols[i], symbols[i+1])] += freq
    return pairs

def merge_pair(pair, vocab):
    pat = re.compile(r'(?<!\S)' + re.escape(' '.join(pair)) + r'(?!\S)')
    return {pat.sub(''.join(pair), w): f for w, f in vocab.items()}

def train_bpe(corpus, num_merges):
    vocab, merges = build_vocab(corpus), []
    for i in range(num_merges):
        stats = get_pair_stats(vocab)
        if not stats:
            break
        best = max(stats, key=stats.get)
        vocab = merge_pair(best, vocab)
        merges.append(best)
        print(f'  Merge {i+1:2d}: {best[0]+" "+best[1]:<20} -> {"|".join(best):<18} freq={stats[best]}')
    return merges

corpus = 'low lower lowest newer newest wider widest running runner runs ' * 25
print('BPE Training:')
merge_table = train_bpe(corpus, num_merges=15)
print(f'Total merges learned: {len(merge_table)}')
```

## Vocabulary Construction

After training, the vocabulary = initial character set + one new token per merge. For GPT-2's byte-level BPE: 256 byte tokens + 50,000 merges + 1 special token = 50,257. Larger vocabularies reduce fertility but increase embedding-matrix memory. At 768 dimensions, a 100K-token vocabulary uses 100K × 768 × 4 bytes ≈ 295 MB for embeddings alone. Tail tokens—tokens that appear very rarely in the training corpus—consume vocabulary slots without contributing meaningfully to model quality; some tokenizer implementations prune tokens below a minimum frequency threshold before finalising the vocabulary.

```python
def bpe_encode(word, merges):
    tokens = list(word) + ['</w>']
    for pair in merges:
        i, new = 0, []
        while i < len(tokens):
            if i < len(tokens) - 1 and (tokens[i], tokens[i+1]) == pair:
                new.append(''.join(pair))
                i += 2
            else:
                new.append(tokens[i])
                i += 1
        tokens = new
    return tokens

def bpe_decode(tokens):
    return ''.join(tokens).replace('</w>', '')

test_words = ['low', 'lower', 'lowest', 'newer', 'widest', 'unknown', 'runner']
print(f'{"Word":<12} {"BPE Tokens":<42} {"Count":>5}')
print('-' * 62)
for w in test_words:
    toks = bpe_encode(w, merge_table)
    dec  = bpe_decode(toks)
    ok   = 'OK' if dec == w else 'ERR'
    print(f'{w:<12} {str(toks):<42} {len(toks):>5}  [{ok}]')

print('\nDecoding: join tokens, strip </w>. Lossless for known chars.')
print('Unknown words split to chars first, then merges applied where possible.')
```

## Encoding and Decoding

BPE encoding applies learned merges in order: scan the current token list for the highest-priority merge pair, apply it, rescan. This greedy process is O(M × T) per word where M is the number of merges and T is the word length. The tiktoken library uses a priority-queue approach that achieves near-linear time and is 5–20× faster than Python BPE implementations. Decoding is trivial: concatenate the subword tokens and remove the end-of-word marker (</w> for standard BPE; byte-level GPT-2 uses a separate byte-to-unicode mapping where space ð  and newline Ā are represented as single Unicode characters). Because every byte is in the initial vocabulary, decoding is always lossless.

## Pre-Tokenization and Regex Splits

Before BPE is applied, GPT-4's cl100k_base uses a 5-pattern regex to split text into pre-tokens: (1) contractions like 's, 't, 're; (2) sequences of letters; (3) sequences of digits; (4) sequences of non-whitespace, non-letter, non-digit characters; (5) whitespace. This prevents BPE from producing cross-word merges such as 'e ' (end of 'the' fused with the space before the next word). Without pre-tokenization, BPE would freely merge across word boundaries, creating tokens that depend on context rather than just subword content. GPT-2 uses a simpler regex. Language-specific pre-tokenizers for Chinese, Japanese, and code use different split strategies.

```python
import re
from collections import Counter

def simple_bpe_fertility(corpus, n_merges):
    """Compute avg tokens/word after n_merges BPE operations."""
    word_freq = Counter(corpus.split())
    vocab = {' '.join(list(w)) + ' </w>': f for w, f in word_freq.items()}

    def get_stats(v):
        pairs = Counter()
        for word, freq in v.items():
            syms = word.split()
            for i in range(len(syms) - 1):
                pairs[(syms[i], syms[i+1])] += freq
        return pairs

    def merge(pair, v):
        pat = re.compile(r'(?<!\S)' + re.escape(' '.join(pair)) + r'(?!\S)')
        return {pat.sub(''.join(pair), w): f for w, f in v.items()}

    for _ in range(n_merges):
        stats = get_stats(vocab)
        if not stats:
            break
        vocab = merge(max(stats, key=stats.get), vocab)

    total_tok = sum(len(w.split()) * f for w, f in vocab.items())
    return total_tok / sum(word_freq.values())

corpus = ('the quick brown fox jumps over the lazy dog '
          'running runner runs lower lowest newer newest wider widest ') * 30
print('Corpus fertility vs BPE merge count:')
print(f'{"Merges":>8} {"Approx Scale":>14} {"Fertility":>12}')
print('-' * 38)
for n, label in [(0, 'char-level'), (8, '~1K vocab'), (20, '~8K vocab'), (40, '~32K vocab')]:
    f = simple_bpe_fertility(corpus, n)
    print(f'{n:>8} {label:>14} {f:>12.3f}')
```

## Fertility and Vocabulary Size

Fertility = average tokens per word. For English, GPT-2 (50K vocab) achieves fertility ≈1.3–1.5; GPT-4 (100K) achieves ≈1.2–1.3. Non-English languages suffer higher fertility when under-represented in training data: Chinese text may reach 2–4 tokens/word on GPT-2 because CJK characters are rare in its English-heavy corpus. Fertility directly determines effective context window length: at fertility 2.0, a 4096-token context holds only ≈2048 words. Choosing vocabulary size V requires balancing fertility, embedding-matrix memory, and frequency of tail tokens in the training corpus.

| Method | OOV Rate | Avg Fertility | Vocab Size | Training Complexity | Used By |
| --- | --- | --- | --- | --- | --- |
| Character-level | 0% | 4–6 tok/word | ~100–300 | O(C) trivial | Early char-RNNs |
| Word-level | 1–5% | 1.0 tok/word | 50K–500K | O(V) fast | Classic NLP, word2vec |
| BPE | 0% (byte-level) | 1.2–1.8 tok/word | 32K–100K | O(V × merges) | GPT-2/3/4, RoBERTa |
| Unigram LM | 0% (byte fallback) | 1.2–1.8 tok/word | 16K–64K | O(V × EM iters) | T5, mT5, Gemma, LLaMA |
| WordPiece | ~0.1% ([UNK]) | 1.3–2.0 tok/word | 28K–32K | O(V × likelihood) | BERT, DistilBERT, ELECTRA |

## HuggingFace Integration

HuggingFace AutoTokenizer loads the correct tokenizer class for any model checkpoint. GPT-2 uses PreTrainedTokenizerFast, backed by the Rust tokenizers library—typically 10–100× faster than the Python implementation and supporting offset_mapping to align token positions back to character spans in the original text. This is essential for span-extraction tasks such as NER and QA. For GPT-4's cl100k_base, use the tiktoken library directly (not available through HuggingFace), which is the production tokenizer used by OpenAI's API.

```python
from transformers import AutoTokenizer

# Load GPT-2 tokenizer (50,257-token byte-level BPE)
tokenizer = AutoTokenizer.from_pretrained('gpt2')

text = 'Byte-pair encoding merges frequent character pairs iteratively.'
encoding = tokenizer(text, return_tensors='pt', return_offsets_mapping=True)
ids     = encoding['input_ids'][0].tolist()
offsets = encoding['offset_mapping'][0].tolist()
tokens  = tokenizer.convert_ids_to_tokens(ids)

print(f'Text   : {text}')
print(f'Tokens : {tokens}')
print(f'Vocab size : {tokenizer.vocab_size}')
print(f'Special    : {tokenizer.all_special_tokens}')
print()
print(f'{"Token":<22} {"ID":>6}  Char span')
for tok, tid, (s, e) in zip(tokens, ids, offsets):
    print(f'{repr(tok):<22} {tid:>6}  [{s}:{e}] -> {repr(text[s:e])}')

words = ['Hello', 'Supercalifragilistic', 'tokenization', 'GPT-4']
print('\nFertility samples (GPT-2 tokenizer):')
for w in words:
    toks = tokenizer.tokenize(w)
    print(f'  {w!r:<25} -> {len(toks)} tokens: {toks}')
```

> **Merge Order Dependency**: BPE merges are greedy and order-dependent — different corpus samples or random seeds produce different merge orders even for the same final vocabulary size, leading to different tokenizations of the same text. Two BPE tokenizers trained on different corpora with identical target vocabulary sizes will generally disagree on how to tokenize identical inputs. Always use the exact tokenizer checkpoint that was used during model training; substituting a different BPE tokenizer of the same nominal vocab size will produce incorrect token IDs and degrade model quality.

## Key Takeaways

- BPE starts from a character (or byte) vocabulary and greedily merges the most frequent adjacent pair — one merge per vocabulary slot.
- GPT-2 uses byte-level BPE with 50,257 tokens; GPT-4 uses cl100k_base with 100,277 tokens and a 5-pattern regex pre-tokenizer.
- Fertility (avg tokens per word) measures tokenizer efficiency; lower fertility means fewer tokens per word and more text fits in a fixed context window.
- Pre-tokenization with regex prevents cross-word merges; GPT-4's regex splits on contractions, letters, digits, and punctuation separately.
- Byte-level BPE guarantees zero OOV — any byte sequence can be encoded using the 256 initial byte tokens.
- Larger vocabulary sizes reduce fertility but increase embedding-matrix memory; 100K × 768d = 295 MB for embeddings alone.
- Use tiktoken for GPT-4 tokenization; use HuggingFace AutoTokenizer with return_offsets_mapping=True for span-extraction tasks.

---

