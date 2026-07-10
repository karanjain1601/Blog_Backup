---
title: "Code Tokenization — Whitespace, Indentation, and Programming Language Fertility"
slug: "code-tokenization"
description: "Code imposes unique challenges for BPE tokenizers: whitespace is semantic in Python, operators split unexpectedly, and identifier naming conventions affect token counts. Covers GPT-2/GPT-4 BPE artifacts in code, indentation encoding, operator splitting, and cross-language fertility differences."
tags: ["deep-learning", "llm"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"Code tokenization differs fundamentally from natural language tokenization. In Python, whitespace encodes program semantics — four spaces of indentation is not stylistic but structural. Operators like == or -\u003e carry precise meaning but may tokenize as one or two tokens depending on the vocabulary. Identifier naming conventions (camelCase, snake_case, PascalCase) affect how identifiers split across token boundaries. Understanding these artifacts is critical for code model fine-tuning, token budget estimation, and span-level code highlighting in IDE tooling."},{"type":"heading","level":2,"content":"GPT-2/GPT-4 BPE Artifacts in Code"},{"type":"text","content":"GPT-2 and GPT-4 BPE tokenizers use special Unicode markers to encode whitespace. A space before a word is represented by the Ġ prefix (Unicode U+0120), so \u0027 def\u0027 becomes \u0027Ġdef\u0027. Newlines are encoded as Ċ (U+010A). Consecutive spaces get their own merged tokens: \u0027    \u0027 (four spaces) may tokenize as a single \u0027Ġ   \u0027 token or as four individual space tokens depending on vocabulary frequency. This means Python indentation tokens are highly tokenizer-specific — the same indented block may consume 1 or 4 tokens depending on training corpus composition."},{"type":"text","content":"CodeBERT and StarCoder use code-specific vocabularies pre-trained on GitHub repositories. Their vocabularies include common programming tokens like \u0027def\u0027, \u0027return\u0027, \u0027import\u0027, \u0027class\u0027, and common operators as single tokens. This gives them lower fertility on code than general-purpose tokenizers, but higher fertility on natural language descriptions and docstrings. The tradeoff is deliberate: code models optimise their token budget for the domain they will primarily process."},{"type":"heading","level":2,"content":"Code Tokenization Analysis Across Languages"},{"type":"code","language":"python","content":"import tiktoken\nfrom transformers import AutoTokenizer\n\ndef tokenize_algorithm(algo_text, tokenizer_fn, tokenizer_name):\n    tokens = tokenizer_fn(algo_text)\n    return {\u0027n\u0027: len(tokens), \u0027name\u0027: tokenizer_name}\n\n# Same bubble sort algorithm in three languages\nalgorithms = {\n    \u0027python\u0027: \u0027def bubble_sort(arr):\\n    n = len(arr)\\n    for i in range(n):\\n        for j in range(n - i - 1):\\n            if arr[j] \u003e arr[j + 1]:\\n                arr[j], arr[j + 1] = arr[j + 1], arr[j]\\n    return arr\u0027,\n    \u0027javascript\u0027: \u0027function bubbleSort(arr) {\\n  const n = arr.length;\\n  for (let i = 0; i \u003c n; i++) {\\n    for (let j = 0; j \u003c n - i - 1; j++) {\\n      if (arr[j] \u003e arr[j + 1]) {\\n        [arr[j], arr[j + 1]] = [arr[j + 1], arr[j]];\\n      }\\n    }\\n  }\\n  return arr;\\n}\u0027,\n    \u0027java\u0027: \u0027public static void bubbleSort(int[] arr) {\\n    int n = arr.length;\\n    for (int i = 0; i \u003c n - 1; i++) {\\n        for (int j = 0; j \u003c n - i - 1; j++) {\\n            if (arr[j] \u003e arr[j + 1]) {\\n                int tmp = arr[j];\\n                arr[j] = arr[j + 1];\\n                arr[j + 1] = tmp;\\n            }\\n        }\\n    }\\n}\u0027,\n}\nenc_gpt4 = tiktoken.get_encoding(\u0027cl100k_base\u0027)\nenc_gpt2 = tiktoken.get_encoding(\u0027gpt2\u0027)\nstarcoder = AutoTokenizer.from_pretrained(\u0027bigcode/starcoder\u0027)\nfor lang, code in algorithms.items():\n    n_gpt4 = len(enc_gpt4.encode(code))\n    n_gpt2 = len(enc_gpt2.encode(code))\n    n_star = len(starcoder.encode(code))\n    print(f\u0027{lang:\u003c12}: gpt4={n_gpt4:\u003e4}  gpt2={n_gpt2:\u003e4}  starcoder={n_star:\u003e4}\u0027)"},{"type":"heading","level":2,"content":"Indentation Token Analysis"},{"type":"text","content":"Python indentation is semantically critical — stripping or modifying it changes program meaning. A standard 4-space indent tokenizes differently across tokenizers: GPT-4 (cl100k_base) merges consecutive spaces into a single token for common indent widths, while GPT-2 may split them into individual space tokens. Tab characters (\\t) typically tokenize as a single token. Nested indentation (8 or 12 spaces for doubly or triply nested blocks) further compounds the token count, making deeply nested Python code disproportionately expensive."},{"type":"code","language":"python","content":"import tiktoken\n\ndef analyze_indentation(tokenizer_name=\u0027cl100k_base\u0027):\n    enc = tiktoken.get_encoding(tokenizer_name)\n    indent_styles = {\n        \u00272-space indent\u0027:   \u0027  x = 1\u0027,\n        \u00274-space indent\u0027:   \u0027    x = 1\u0027,\n        \u00278-space indent\u0027:   \u0027        x = 1\u0027,\n        \u002712-space indent\u0027:  \u0027            x = 1\u0027,\n        \u0027tab indent\u0027:       \u0027\\tx = 1\u0027,\n        \u0027tab+4 indent\u0027:     \u0027\\t    x = 1\u0027,\n    }\n    print(f\u0027Tokenizer: {tokenizer_name}\u0027)\n    for label, text in indent_styles.items():\n        tokens = enc.encode(text)\n        decoded = [enc.decode([t]) for t in tokens]\n        display = [repr(d) for d in decoded]\n        print(f\u0027  {label:\u003c20}: {len(tokens)} tokens  {display}\u0027)\n\nanalyze_indentation(\u0027cl100k_base\u0027)\nprint()\nanalyze_indentation(\u0027gpt2\u0027)"},{"type":"heading","level":2,"content":"Operator and Identifier Tokenization"},{"type":"text","content":"Identifier naming conventions interact strongly with BPE tokenization. A snake_case identifier like \u0027calculate_gradient_norm\u0027 typically splits at underscores, producing 3–4 tokens. A camelCase identifier like \u0027calculateGradientNorm\u0027 may split at case boundaries (some tokenizers treat uppercase letters as split points) or remain merged if the whole identifier appears in training data. Operators like == usually tokenize as a single token in code-aware vocabularies, while -\u003e and =\u003e may be one or two tokens depending on the training corpus."},{"type":"code","language":"python","content":"import tiktoken\n\ndef analyze_identifiers_and_ops(tokenizer_name=\u0027cl100k_base\u0027):\n    enc = tiktoken.get_encoding(tokenizer_name)\n    samples = {\n        \u0027camelCase\u0027:    \u0027calculateGradientNorm\u0027,\n        \u0027snake_case\u0027:   \u0027calculate_gradient_norm\u0027,\n        \u0027PascalCase\u0027:   \u0027CalculateGradientNorm\u0027,\n        \u0027SCREAMING\u0027:    \u0027MAX_GRADIENT_NORM\u0027,\n        \u0027eq operator\u0027:  \u0027==\u0027,\n        \u0027ne operator\u0027:  \u0027!=\u0027,\n        \u0027arrow (C++)\u0027:  \u0027-\u003e\u0027,\n        \u0027fat arrow\u0027:    \u0027=\u003e\u0027,\n        \u0027walrus\u0027:       \u0027:=\u0027,\n        \u0027type hint\u0027:    \u0027list[int]\u0027,\n        \u0027decorator\u0027:    \u0027@torch.no_grad()\u0027,\n    }\n    print(f\u0027Operator/identifier tokenization ({tokenizer_name})\u0027)\n    for label, text in samples.items():\n        tokens = enc.encode(text)\n        pieces = [enc.decode([t]) for t in tokens]\n        print(f\u0027  {label:\u003c16}: {len(tokens)} tok  {pieces}\u0027)\n\nanalyze_identifiers_and_ops(\u0027cl100k_base\u0027)\nprint()\nanalyze_identifiers_and_ops(\u0027gpt2\u0027)"},{"type":"heading","level":2,"content":"Cross-Language Fertility"},{"type":"code","language":"python","content":"import tiktoken\n\ndef tokens_per_line(code_snippet, enc):\n    lines = [l for l in code_snippet.split(\u0027\\n\u0027) if l.strip()]\n    if not lines:\n        return 0.0\n    total = sum(len(enc.encode(l)) for l in lines)\n    return total / len(lines)\n\nenc = tiktoken.get_encoding(\u0027cl100k_base\u0027)\nsnippets = {\n    \u0027Python\u0027:     \u0027def add(a, b):\\n    return a + b\\nresult = add(1, 2)\u0027,\n    \u0027JavaScript\u0027: \u0027const add = (a, b) =\u003e a + b;\\nconst result = add(1, 2);\u0027,\n    \u0027Java\u0027:       \u0027public int add(int a, int b) { return a + b; }\\nint result = add(1, 2);\u0027,\n    \u0027SQL\u0027:        \u0027SELECT id, name FROM users WHERE active = 1 ORDER BY name ASC;\u0027,\n    \u0027LaTeX\u0027:      \u0027\\\\frac{\\\\partial L}{\\\\partial w} = \\\\sum_{i=1}^{n} x_i (y_i - \\\\hat{y}_i)\u0027,\n    \u0027JSON\u0027:       \u0027{\"model\": \"gpt-4\", \"temperature\": 0.7, \"max_tokens\": 512}\u0027,\n    \u0027Regex\u0027:      \u0027^(?:[0-9]{1,3}\\\\.){3}[0-9]{1,3}$\u0027,\n    \u0027Bash\u0027:       \u0027for f in *.py; do python $f --output results/; done\u0027,\n}\nprint(f\u0027{\"Language\":\u003c14} {\"Tok/Line\":\u003e10} {\"Total Tok\":\u003e10}\u0027)\nfor lang, code in snippets.items():\n    tpl = tokens_per_line(code, enc)\n    total = len(enc.encode(code))\n    print(f\u0027{lang:\u003c14} {tpl:\u003e10.2f} {total:\u003e10}\u0027)"},{"type":"heading","level":2,"content":"Code Tokenization Characteristics"},{"type":"table","headers":["Language","Avg Tokens/Line","Key Tokenization Artifact","Indentation Handling","Operator Splitting"],"rows":[["Python","6–10","Ġ prefix on space tokens; merged indent blocks","4 spaces → 1–4 tokens (tokenizer-dependent)","== as 1 token; // as 2 tokens usually"],["JavaScript","5–9","{ } merge with preceding token; =\u003e split","Braces not indented; space after { is separate","=\u003e may be 1–2 tokens; === is 2–3 tokens"],["Java","7–12","Long class/method names split at case boundaries","Braces on same or next line; indentation less semantic","-\u003e lambda arrow: 1–2 tokens"],["SQL","4–8","UPPERCASE keywords often single tokens; lowercase variants split","No indentation semantics","!= and \u003c\u003e both tokenize as 2 tokens"],["LaTeX","8–15","Backslash sequences: \\\\frac splits into 2–3 tokens","No indentation; heavy use of { } braces","_ and ^ as single tokens; subscripts split"],["JSON","3–6","Colon and quotes often merge with key tokens","No semantic indentation",": usually 1 token; {} and [] as 1 token each"]]},{"type":"heading","level":2,"content":"Token Alignment to Source Code Lines"},{"type":"text","content":"IDE tooling for code models — inline completions, error explanations, span highlighting — requires mapping token indices back to source line and column positions. BPE tokens do not align to line boundaries: a token may span a newline character, and a single logical line may produce dozens of tokens. To build the token-to-line mapping, reconstruct the character offset of each token by decoding prefix token sequences, then binary-search against the newline positions of the original source string."},{"type":"text","content":"The HumanEval benchmark uses code in a specific format: function signature followed by docstring followed by implementation. Tokenizing this format with different tokenizers produces different prompt lengths, affecting the number of completion tokens available within the model\u0027s context window. Code models fine-tuned with a specific tokenizer must use that same tokenizer at inference time — cross-tokenizer evaluation invalidates token count comparisons across papers."},{"type":"heading","level":2,"content":"Fine-Tuning Code Models — Tokenizer Implications"},{"type":"callout","variant":"tip","title":"Check Operator Merging Before Fine-Tuning","content":"When fine-tuning code models, check that the tokenizer correctly merges common operators in your target language — some tokenizers split \u0027-\u003e\u0027 into 2 tokens and \u0027=\u003e\u0027 into 2 tokens, affecting token budget predictions by 10–20%. Run the indentation and operator analysis on a representative sample of your training code before committing to a tokenizer, and prefer code-specific vocabularies (StarCoder, CodeLlama) for code-heavy workloads to minimise fertility and maximise effective context window usage."},{"type":"list","ordered":false,"items":["Use code-specific tokenizers (StarCoder, CodeLlama) for code-heavy tasks — 15–30% lower fertility than GPT-2.","Indentation is semantic in Python: normalise to spaces before tokenizing to avoid tab/space fertility differences.","Operator splitting affects token budget: test ==, !=, -\u003e, =\u003e, := on your target tokenizer before estimating costs.","camelCase identifiers may tokenize as 1 token if they appear frequently in training; rare identifiers always split.","SQL UPPERCASE keywords tokenize better than lowercase variants in tokenizers trained on mixed-case corpora.","HumanEval evaluations must match training tokenizer exactly — cross-tokenizer comparisons are invalid."]},{"type":"text","content":"A practical code tokenization workflow: (1) sample 1000 lines of production code in your target language, (2) tokenize with each candidate tokenizer and compute mean tokens per line, (3) select the tokenizer with lowest fertility for your dominant language, (4) verify operator and identifier splitting for the 20 most common constructs in your codebase, (5) measure context window headroom with your typical prompt template. This analysis typically takes under an hour and prevents costly mis-estimates at production scale."},{"type":"divider"}]"
---
# Code Tokenization — Whitespace, Indentation, and Programming Language Fertility

Code tokenization differs fundamentally from natural language tokenization. In Python, whitespace encodes program semantics — four spaces of indentation is not stylistic but structural. Operators like == or -> carry precise meaning but may tokenize as one or two tokens depending on the vocabulary. Identifier naming conventions (camelCase, snake_case, PascalCase) affect how identifiers split across token boundaries. Understanding these artifacts is critical for code model fine-tuning, token budget estimation, and span-level code highlighting in IDE tooling.

## GPT-2/GPT-4 BPE Artifacts in Code

GPT-2 and GPT-4 BPE tokenizers use special Unicode markers to encode whitespace. A space before a word is represented by the Ġ prefix (Unicode U+0120), so ' def' becomes 'Ġdef'. Newlines are encoded as Ċ (U+010A). Consecutive spaces get their own merged tokens: '    ' (four spaces) may tokenize as a single 'Ġ   ' token or as four individual space tokens depending on vocabulary frequency. This means Python indentation tokens are highly tokenizer-specific — the same indented block may consume 1 or 4 tokens depending on training corpus composition.

CodeBERT and StarCoder use code-specific vocabularies pre-trained on GitHub repositories. Their vocabularies include common programming tokens like 'def', 'return', 'import', 'class', and common operators as single tokens. This gives them lower fertility on code than general-purpose tokenizers, but higher fertility on natural language descriptions and docstrings. The tradeoff is deliberate: code models optimise their token budget for the domain they will primarily process.

## Code Tokenization Analysis Across Languages

```python
import tiktoken
from transformers import AutoTokenizer

def tokenize_algorithm(algo_text, tokenizer_fn, tokenizer_name):
    tokens = tokenizer_fn(algo_text)
    return {'n': len(tokens), 'name': tokenizer_name}

# Same bubble sort algorithm in three languages
algorithms = {
    'python': 'def bubble_sort(arr):\n    n = len(arr)\n    for i in range(n):\n        for j in range(n - i - 1):\n            if arr[j] > arr[j + 1]:\n                arr[j], arr[j + 1] = arr[j + 1], arr[j]\n    return arr',
    'javascript': 'function bubbleSort(arr) {\n  const n = arr.length;\n  for (let i = 0; i < n; i++) {\n    for (let j = 0; j < n - i - 1; j++) {\n      if (arr[j] > arr[j + 1]) {\n        [arr[j], arr[j + 1]] = [arr[j + 1], arr[j]];\n      }\n    }\n  }\n  return arr;\n}',
    'java': 'public static void bubbleSort(int[] arr) {\n    int n = arr.length;\n    for (int i = 0; i < n - 1; i++) {\n        for (int j = 0; j < n - i - 1; j++) {\n            if (arr[j] > arr[j + 1]) {\n                int tmp = arr[j];\n                arr[j] = arr[j + 1];\n                arr[j + 1] = tmp;\n            }\n        }\n    }\n}',
}
enc_gpt4 = tiktoken.get_encoding('cl100k_base')
enc_gpt2 = tiktoken.get_encoding('gpt2')
starcoder = AutoTokenizer.from_pretrained('bigcode/starcoder')
for lang, code in algorithms.items():
    n_gpt4 = len(enc_gpt4.encode(code))
    n_gpt2 = len(enc_gpt2.encode(code))
    n_star = len(starcoder.encode(code))
    print(f'{lang:<12}: gpt4={n_gpt4:>4}  gpt2={n_gpt2:>4}  starcoder={n_star:>4}')
```

## Indentation Token Analysis

Python indentation is semantically critical — stripping or modifying it changes program meaning. A standard 4-space indent tokenizes differently across tokenizers: GPT-4 (cl100k_base) merges consecutive spaces into a single token for common indent widths, while GPT-2 may split them into individual space tokens. Tab characters (\t) typically tokenize as a single token. Nested indentation (8 or 12 spaces for doubly or triply nested blocks) further compounds the token count, making deeply nested Python code disproportionately expensive.

```python
import tiktoken

def analyze_indentation(tokenizer_name='cl100k_base'):
    enc = tiktoken.get_encoding(tokenizer_name)
    indent_styles = {
        '2-space indent':   '  x = 1',
        '4-space indent':   '    x = 1',
        '8-space indent':   '        x = 1',
        '12-space indent':  '            x = 1',
        'tab indent':       '\tx = 1',
        'tab+4 indent':     '\t    x = 1',
    }
    print(f'Tokenizer: {tokenizer_name}')
    for label, text in indent_styles.items():
        tokens = enc.encode(text)
        decoded = [enc.decode([t]) for t in tokens]
        display = [repr(d) for d in decoded]
        print(f'  {label:<20}: {len(tokens)} tokens  {display}')

analyze_indentation('cl100k_base')
print()
analyze_indentation('gpt2')
```

## Operator and Identifier Tokenization

Identifier naming conventions interact strongly with BPE tokenization. A snake_case identifier like 'calculate_gradient_norm' typically splits at underscores, producing 3–4 tokens. A camelCase identifier like 'calculateGradientNorm' may split at case boundaries (some tokenizers treat uppercase letters as split points) or remain merged if the whole identifier appears in training data. Operators like == usually tokenize as a single token in code-aware vocabularies, while -> and => may be one or two tokens depending on the training corpus.

```python
import tiktoken

def analyze_identifiers_and_ops(tokenizer_name='cl100k_base'):
    enc = tiktoken.get_encoding(tokenizer_name)
    samples = {
        'camelCase':    'calculateGradientNorm',
        'snake_case':   'calculate_gradient_norm',
        'PascalCase':   'CalculateGradientNorm',
        'SCREAMING':    'MAX_GRADIENT_NORM',
        'eq operator':  '==',
        'ne operator':  '!=',
        'arrow (C++)':  '->',
        'fat arrow':    '=>',
        'walrus':       ':=',
        'type hint':    'list[int]',
        'decorator':    '@torch.no_grad()',
    }
    print(f'Operator/identifier tokenization ({tokenizer_name})')
    for label, text in samples.items():
        tokens = enc.encode(text)
        pieces = [enc.decode([t]) for t in tokens]
        print(f'  {label:<16}: {len(tokens)} tok  {pieces}')

analyze_identifiers_and_ops('cl100k_base')
print()
analyze_identifiers_and_ops('gpt2')
```

## Cross-Language Fertility

```python
import tiktoken

def tokens_per_line(code_snippet, enc):
    lines = [l for l in code_snippet.split('\n') if l.strip()]
    if not lines:
        return 0.0
    total = sum(len(enc.encode(l)) for l in lines)
    return total / len(lines)

enc = tiktoken.get_encoding('cl100k_base')
snippets = {
    'Python':     'def add(a, b):\n    return a + b\nresult = add(1, 2)',
    'JavaScript': 'const add = (a, b) => a + b;\nconst result = add(1, 2);',
    'Java':       'public int add(int a, int b) { return a + b; }\nint result = add(1, 2);',
    'SQL':        'SELECT id, name FROM users WHERE active = 1 ORDER BY name ASC;',
    'LaTeX':      '\\frac{\\partial L}{\\partial w} = \\sum_{i=1}^{n} x_i (y_i - \\hat{y}_i)',
    'JSON':       '{"model": "gpt-4", "temperature": 0.7, "max_tokens": 512}',
    'Regex':      '^(?:[0-9]{1,3}\\.){3}[0-9]{1,3}$',
    'Bash':       'for f in *.py; do python $f --output results/; done',
}
print(f'{"Language":<14} {"Tok/Line":>10} {"Total Tok":>10}')
for lang, code in snippets.items():
    tpl = tokens_per_line(code, enc)
    total = len(enc.encode(code))
    print(f'{lang:<14} {tpl:>10.2f} {total:>10}')
```

## Code Tokenization Characteristics

| Language | Avg Tokens/Line | Key Tokenization Artifact | Indentation Handling | Operator Splitting |
| --- | --- | --- | --- | --- |
| Python | 6–10 | Ġ prefix on space tokens; merged indent blocks | 4 spaces → 1–4 tokens (tokenizer-dependent) | == as 1 token; // as 2 tokens usually |
| JavaScript | 5–9 | { } merge with preceding token; => split | Braces not indented; space after { is separate | => may be 1–2 tokens; === is 2–3 tokens |
| Java | 7–12 | Long class/method names split at case boundaries | Braces on same or next line; indentation less semantic | -> lambda arrow: 1–2 tokens |
| SQL | 4–8 | UPPERCASE keywords often single tokens; lowercase variants split | No indentation semantics | != and <> both tokenize as 2 tokens |
| LaTeX | 8–15 | Backslash sequences: \\frac splits into 2–3 tokens | No indentation; heavy use of { } braces | _ and ^ as single tokens; subscripts split |
| JSON | 3–6 | Colon and quotes often merge with key tokens | No semantic indentation | : usually 1 token; {} and [] as 1 token each |

## Token Alignment to Source Code Lines

IDE tooling for code models — inline completions, error explanations, span highlighting — requires mapping token indices back to source line and column positions. BPE tokens do not align to line boundaries: a token may span a newline character, and a single logical line may produce dozens of tokens. To build the token-to-line mapping, reconstruct the character offset of each token by decoding prefix token sequences, then binary-search against the newline positions of the original source string.

The HumanEval benchmark uses code in a specific format: function signature followed by docstring followed by implementation. Tokenizing this format with different tokenizers produces different prompt lengths, affecting the number of completion tokens available within the model's context window. Code models fine-tuned with a specific tokenizer must use that same tokenizer at inference time — cross-tokenizer evaluation invalidates token count comparisons across papers.

## Fine-Tuning Code Models — Tokenizer Implications

> **Check Operator Merging Before Fine-Tuning**: When fine-tuning code models, check that the tokenizer correctly merges common operators in your target language — some tokenizers split '->' into 2 tokens and '=>' into 2 tokens, affecting token budget predictions by 10–20%. Run the indentation and operator analysis on a representative sample of your training code before committing to a tokenizer, and prefer code-specific vocabularies (StarCoder, CodeLlama) for code-heavy workloads to minimise fertility and maximise effective context window usage.

- Use code-specific tokenizers (StarCoder, CodeLlama) for code-heavy tasks — 15–30% lower fertility than GPT-2.
- Indentation is semantic in Python: normalise to spaces before tokenizing to avoid tab/space fertility differences.
- Operator splitting affects token budget: test ==, !=, ->, =>, := on your target tokenizer before estimating costs.
- camelCase identifiers may tokenize as 1 token if they appear frequently in training; rare identifiers always split.
- SQL UPPERCASE keywords tokenize better than lowercase variants in tokenizers trained on mixed-case corpora.
- HumanEval evaluations must match training tokenizer exactly — cross-tokenizer comparisons are invalid.

A practical code tokenization workflow: (1) sample 1000 lines of production code in your target language, (2) tokenize with each candidate tokenizer and compute mean tokens per line, (3) select the tokenizer with lowest fertility for your dominant language, (4) verify operator and identifier splitting for the 20 most common constructs in your codebase, (5) measure context window headroom with your typical prompt template. This analysis typically takes under an hour and prevents costly mis-estimates at production scale.

---

