---
title: "Joint Entropy and Conditional Entropy"
slug: "joint-conditional-entropy"
description: "Joint entropy H(X,Y), conditional entropy H(Y|X), the chain rule, subadditivity, and information-theoretic implications for deep learning pipelines."
tags: ["information-theory","math","foundations"]
topic: "math-foundations"
status: "published"
updated: "2026-07-10"
blocks_json: "[
  {"type":"text","content":"Joint and conditional entropy extend Shannon entropy to pairs and sequences of random variables, formalizing how information is shared between variables and how observing one variable changes uncertainty about another. They give rise to the chain rule of entropy — the algebraic identity underlying autoregressive language model training — and to subadditivity, which shows how correlation compresses joint uncertainty. Mastering these quantities is prerequisite to mutual information, the data processing inequality, and the information bottleneck theory of deep learning."},
  {"type":"heading","level":2,"content":"Core Definition: Joint and Conditional Entropy"},
  {"type":"text","content":"Joint entropy H(X,Y) = -sum_{x,y} p(x,y) log p(x,y) = E[-log p(X,Y)] measures total uncertainty of the pair. It satisfies H(X,Y) >= max(H(X), H(Y)) and generalizes naturally to n variables: H(X1,...,Xn) = -E[log p(X1,...,Xn)]. Conditional entropy H(Y|X) = sum_x p(x) H(Y|X=x) = -sum_{x,y} p(x,y) log p(y|x) = E[-log p(Y|X)] is the expected remaining uncertainty about Y after observing X. Both are always non-negative. H(Y|X)=0 iff Y is a deterministic function of X; H(Y|X)=H(Y) iff X and Y are independent."},
  {"type":"code","language":"python","content":"import numpy as np\n\ndef entropy_bits(p):\n    p = np.asarray(p, dtype=float)\n    mask = p > 0\n    return float(-np.sum(p[mask] * np.log2(p[mask])))\n\ndef joint_entropy(p_xy):\n    # H(X,Y) from 2-D joint probability matrix\n    return entropy_bits(p_xy.flatten())\n\ndef conditional_entropy(p_xy):\n    # H(Y|X) = H(X,Y) - H(X)\n    p_x = p_xy.sum(axis=1)  # marginal of X (row sums)\n    return joint_entropy(p_xy) - entropy_bits(p_x)\n\n# Correlated binary variables\np_xy = np.array([[0.40, 0.10],\n                  [0.10, 0.40]])\np_x = p_xy.sum(axis=1)   # [0.5, 0.5]\np_y = p_xy.sum(axis=0)   # [0.5, 0.5]\n\nh_xy        = joint_entropy(p_xy)        # 1.722 bits\nh_x         = entropy_bits(p_x)          # 1.000 bit\nh_y         = entropy_bits(p_y)          # 1.000 bit\nh_y_given_x = conditional_entropy(p_xy)  # 0.722 bit < h_y\nmi          = h_x + h_y - h_xy          # 0.278 bit shared info\n\nprint(f'H(X,Y) = {h_xy:.3f} bits')\nprint(f'H(Y|X) = {h_y_given_x:.3f} bits  [< H(Y)={h_y:.3f}]')\nprint(f'I(X;Y) = {mi:.3f} bits')"},
  {"type":"heading","level":2,"content":"Mathematical Properties"},
  {"type":"text","content":"Chain rule: H(X,Y) = H(X) + H(Y|X) = H(Y) + H(X|Y). Multivariate chain rule: H(X1,...,Xn) = H(X1) + H(X2|X1) + ... + H(Xn|X1,...,X_{n-1}) = sum_i H(Xi|X1,...,X_{i-1}). This is the log form of the probability chain rule log p(x1,...,xn) = sum_i log p(xi|x1,...,x_{i-1}). Subadditivity: H(X,Y) <= H(X)+H(Y), equality iff X and Y are independent; the gap H(X)+H(Y)-H(X,Y) equals mutual information I(X;Y). Conditioning reduces entropy: H(Y|X) <= H(Y), equality iff independent. Entropy of functions: H(f(X)) <= H(X) for any deterministic f, with equality iff f is invertible on the support of X."},
  {"type":"code","language":"python","content":"import numpy as np\n\ndef entropy_bits(p):\n    p = np.asarray(p, dtype=float)\n    mask = p > 0\n    return float(-np.sum(p[mask] * np.log2(p[mask])))\n\n# Verify chain rule: H(X,Y) == H(X) + H(Y|X)\np_xy = np.array([[0.30, 0.20], [0.10, 0.40]])\np_x  = p_xy.sum(axis=1)\np_y  = p_xy.sum(axis=0)\n\nh_xy        = entropy_bits(p_xy.flatten())\nh_x         = entropy_bits(p_x)\nh_y         = entropy_bits(p_y)\nh_y_given_x = h_xy - h_x\nh_x_given_y = h_xy - h_y\n\nprint(f'H(X,Y)         = {h_xy:.4f}')\nprint(f'H(X)+H(Y|X)    = {h_x:.4f} + {h_y_given_x:.4f} = {h_x+h_y_given_x:.4f}')  # equals H(X,Y)\nprint(f'Subadditivity gap I(X;Y) = {h_x+h_y-h_xy:.4f} bits')\n\n# Independent case: gap should be zero\np_xy_indep = np.outer(p_x, p_y)  # product distribution\nh_indep    = entropy_bits(p_xy_indep.flatten())\nprint(f'H(X,Y) independent = {h_indep:.4f}, H(X)+H(Y) = {h_x+h_y:.4f}')"},
  {"type":"heading","level":2,"content":"Variants and Special Cases"},
  {"type":"text","content":"For i.i.d. sources the multivariate chain rule simplifies to H(X1,...,Xn)=n*H(X1). For Markov chains H(Xt|X1,...,X_{t-1})=H(Xt|X_{t-1}), giving entropy rate h = H(X2|X1). Entropy of functions H(f(X)) <= H(X): many-to-one functions strictly reduce entropy; bijections preserve it exactly. Data Processing Inequality (DPI) for entropy: if X -> Y -> Z is a Markov chain then H(X|Z) >= H(X|Y) — downstream processing cannot recover information lost at an intermediate step. Conditioning on a specific value x0 can raise entropy H(Y|X=x0) > H(Y); the inequality H(Y|X) <= H(Y) holds only in expectation over X."},
  {"type":"heading","level":2,"content":"ML and AI Connections"},
  {"type":"text","content":"Autoregressive LM training maximizes sum_t log p(xt|x1,...,x_{t-1}), which by the chain rule equals log p(x1,...,xT) — the full sequence joint log-probability under the model. Perplexity PPL = exp(average token cross-entropy) directly estimates exp(H_rate). The information bottleneck theory views each neural layer as compressing X into Z: H(Z) <= H(X), and the learning goal is to retain I(Z;Y) while minimizing I(X;Z). Feature engineering works precisely because adding informative features reduces H(Y|features), lowering the Bayes-optimal error. Decision tree information gain is the reduction in H(Y|feature), selecting splits that most reduce conditional entropy."},
  {"type":"code","language":"python","content":"import numpy as np\n\ndef entropy_bits(p):\n    p = np.asarray(p, dtype=float)\n    mask = p > 0\n    return float(-np.sum(p[mask] * np.log2(p[mask])))\n\ndef mutual_info_from_joint(p_xy):\n    p_x   = p_xy.sum(axis=1)\n    p_y   = p_xy.sum(axis=0)\n    h_xy  = entropy_bits(p_xy.flatten())\n    h_x   = entropy_bits(p_x)\n    h_y   = entropy_bits(p_y)\n    h_y_x = h_xy - h_x   # H(Y|X)\n    mi    = h_y - h_y_x  # I(X;Y) = H(Y) - H(Y|X)\n    return h_y, h_y_x, mi\n\n# Conditioning reduces entropy more when variables are correlated\np_strong = np.array([[0.45, 0.05], [0.05, 0.45]])  # high correlation\np_weak   = np.array([[0.26, 0.24], [0.24, 0.26]])  # low correlation\np_indep  = np.array([[0.25, 0.25], [0.25, 0.25]])  # independent\n\nfor name, p in [('strong', p_strong), ('weak', p_weak), ('indep', p_indep)]:\n    h_y, h_y_x, mi = mutual_info_from_joint(p)\n    print(f'{name:6s}: H(Y)={h_y:.3f}  H(Y|X)={h_y_x:.3f}  I(X;Y)={mi:.3f}')"},
  {"type":"heading","level":2,"content":"Implementation Pitfalls"},
  {"type":"text","content":"When computing joint entropy from empirical counts, normalize the count matrix to probabilities and verify it sums to 1 before proceeding. For computing H(Y|X) = sum_x p(x)*H(Y|X=x), handle rows where p_x=0 by skipping them — dividing a row by zero probability creates NaN. Beware that H(Y|X=x0) for a specific value can exceed H(Y): conditioning on a specific outcome is not the same as conditioning on the variable in expectation. For sequence models, track each conditional term H(Xt|X_{<t}) separately to identify which positions are most uncertain, rather than averaging perplexity across all positions."},
  {"type":"heading","level":2,"content":"Practical Guidance"},
  {"type":"text","content":"Use conditional entropy H(Label|Features) to quantify how much residual uncertainty the features leave — lower is better. Compute I(X;Y) = H(Y) - H(Y|X) to measure feature relevance without fitting a model. For LLM debugging, track per-position entropy H(Xt|context) to locate high-uncertainty positions in sequences — these correspond to ambiguous tokens where the model spreads probability mass. When analyzing information flow in a pipeline X -> Y -> Z, measure I(X;Y) and I(Y;Z) separately to localize where information is lost. Residual connections in transformers maintain H(layer output) ~= H(layer input) by keeping each layer nearly invertible."},
  {"type":"code","language":"python","content":"import numpy as np\n\ndef entropy_bits(p):\n    p = np.asarray(p, dtype=float)\n    mask = p > 0\n    return float(-np.sum(p[mask] * np.log2(p[mask])))\n\ndef transform_entropy_loss(probs, transform_fn):\n    # Compute H(X) and H(f(X)) to measure information loss\n    p  = np.array(probs)\n    xs = np.arange(len(p))\n    ys = np.array([transform_fn(x) for x in xs])\n    # aggregate probability mass at each output value\n    out_vals = np.unique(ys)\n    p_out = np.array([p[ys == v].sum() for v in out_vals])\n    return entropy_bits(p), entropy_bits(p_out)\n\np = [0.25, 0.25, 0.25, 0.25]   # uniform over {0,1,2,3}\nh_x, h_id   = transform_entropy_loss(p, lambda x: x)       # identity\nh_x, h_mod2 = transform_entropy_loss(p, lambda x: x % 2)  # many-to-one\nh_x, h_sq   = transform_entropy_loss(p, lambda x: x*x)    # injective\n\nprint(f'H(X)           = {h_x:.3f} bits')\nprint(f'H(identity(X)) = {h_id:.3f} bits  [no loss, bijection]')\nprint(f'H(X mod 2)     = {h_mod2:.3f} bits  [info lost, many-to-one]')\nprint(f'H(X squared)   = {h_sq:.3f} bits  [injective on support, no loss]')"},
  {"type":"callout","variant":"info","title":"Autoregressive Models and the Chain Rule","content":"GPT-style models maximize sum_t log p(xt | x1,...,x_{t-1}). By the chain rule, this is exactly log p(x1,...,xT) — the joint log-probability of the sequence. Training cross-entropy is H(p_true, q_model) where the chain rule factors both p_true and q_model identically. Perplexity = exp(average token CE) = exp(H(p,q)) directly estimates the effective branching factor at each step, interpretable as how many equally likely choices the model faces on average."},
  {"type":"table","headers":["Quantity","Formula","Key Property"],"rows":[["H(X,Y)","E[-log p(X,Y)]","Total uncertainty; always >= max(H(X),H(Y))"],["H(Y|X)","H(X,Y) - H(X)","Remaining uncertainty about Y given X"],["Chain rule","H(X,Y) = H(X) + H(Y|X)","Fundamental decomposition of joint entropy"],["Subadditivity","H(X,Y) <= H(X)+H(Y)","Equality iff X and Y independent"],["Conditioning","H(Y|X) <= H(Y)","Equality iff X and Y independent"],["Functions","H(f(X)) <= H(X)","Equality iff f invertible on support of X"],["DPI","H(X|Z) >= H(X|Y) for X->Y->Z","Processing cannot recover lost information"]]},
  {"type":"divider"},
  {"type":"heading","level":2,"content":"Key Takeaways"},
  {"type":"list","ordered":false,"items":["H(X,Y) = E[-log p(X,Y)] — joint entropy measures total uncertainty of a pair; always at least as large as each marginal","H(Y|X) = H(X,Y) - H(X) — conditional entropy is remaining uncertainty about Y after observing X; always non-negative","Chain rule H(X,Y)=H(X)+H(Y|X) is the foundation of autoregressive LM training and sequence likelihood factorization","Subadditivity H(X,Y) <= H(X)+H(Y) — the gap I(X;Y) = H(X)+H(Y)-H(X,Y) is the mutual information between variables","Conditioning reduces entropy in expectation; for a specific outcome x0, H(Y|X=x0) can exceed H(Y)","H(f(X)) <= H(X) for any deterministic function — information can only be lost or preserved, never created, by processing","Data processing inequality: for X->Y->Z Markov chain, H(X|Z) >= H(X|Y) — no downstream stage can recover lost information"]}
]
"
---
# Joint Entropy and Conditional Entropy

Joint and conditional entropy extend Shannon entropy to pairs and sequences of random variables, formalizing how information is shared between variables and how observing one variable changes uncertainty about another. They give rise to the chain rule of entropy — the algebraic identity underlying autoregressive language model training — and to subadditivity, which shows how correlation compresses joint uncertainty. Mastering these quantities is prerequisite to mutual information, the data processing inequality, and the information bottleneck theory of deep learning.

## Core Definition: Joint and Conditional Entropy

Joint entropy H(X,Y) = -sum_{x,y} p(x,y) log p(x,y) = E[-log p(X,Y)] measures total uncertainty of the pair. It satisfies H(X,Y) >= max(H(X), H(Y)) and generalizes naturally to n variables: H(X1,...,Xn) = -E[log p(X1,...,Xn)]. Conditional entropy H(Y|X) = sum_x p(x) H(Y|X=x) = -sum_{x,y} p(x,y) log p(y|x) = E[-log p(Y|X)] is the expected remaining uncertainty about Y after observing X. Both are always non-negative. H(Y|X)=0 iff Y is a deterministic function of X; H(Y|X)=H(Y) iff X and Y are independent.

```python
import numpy as np

def entropy_bits(p):
    p = np.asarray(p, dtype=float)
    mask = p > 0
    return float(-np.sum(p[mask] * np.log2(p[mask])))

def joint_entropy(p_xy):
    # H(X,Y) from 2-D joint probability matrix
    return entropy_bits(p_xy.flatten())

def conditional_entropy(p_xy):
    # H(Y|X) = H(X,Y) - H(X)
    p_x = p_xy.sum(axis=1)  # marginal of X (row sums)
    return joint_entropy(p_xy) - entropy_bits(p_x)

# Correlated binary variables
p_xy = np.array([[0.40, 0.10],
                  [0.10, 0.40]])
p_x = p_xy.sum(axis=1)   # [0.5, 0.5]
p_y = p_xy.sum(axis=0)   # [0.5, 0.5]

h_xy        = joint_entropy(p_xy)        # 1.722 bits
h_x         = entropy_bits(p_x)          # 1.000 bit
h_y         = entropy_bits(p_y)          # 1.000 bit
h_y_given_x = conditional_entropy(p_xy)  # 0.722 bit < h_y
mi          = h_x + h_y - h_xy          # 0.278 bit shared info

print(f'H(X,Y) = {h_xy:.3f} bits')
print(f'H(Y|X) = {h_y_given_x:.3f} bits  [< H(Y)={h_y:.3f}]')
print(f'I(X;Y) = {mi:.3f} bits')
```

## Mathematical Properties

Chain rule: H(X,Y) = H(X) + H(Y|X) = H(Y) + H(X|Y). Multivariate chain rule: H(X1,...,Xn) = H(X1) + H(X2|X1) + ... + H(Xn|X1,...,X_{n-1}) = sum_i H(Xi|X1,...,X_{i-1}). This is the log form of the probability chain rule log p(x1,...,xn) = sum_i log p(xi|x1,...,x_{i-1}). Subadditivity: H(X,Y) <= H(X)+H(Y), equality iff X and Y are independent; the gap H(X)+H(Y)-H(X,Y) equals mutual information I(X;Y). Conditioning reduces entropy: H(Y|X) <= H(Y), equality iff independent. Entropy of functions: H(f(X)) <= H(X) for any deterministic f, with equality iff f is invertible on the support of X.

```python
import numpy as np

def entropy_bits(p):
    p = np.asarray(p, dtype=float)
    mask = p > 0
    return float(-np.sum(p[mask] * np.log2(p[mask])))

# Verify chain rule: H(X,Y) == H(X) + H(Y|X)
p_xy = np.array([[0.30, 0.20], [0.10, 0.40]])
p_x  = p_xy.sum(axis=1)
p_y  = p_xy.sum(axis=0)

h_xy        = entropy_bits(p_xy.flatten())
h_x         = entropy_bits(p_x)
h_y         = entropy_bits(p_y)
h_y_given_x = h_xy - h_x
h_x_given_y = h_xy - h_y

print(f'H(X,Y)         = {h_xy:.4f}')
print(f'H(X)+H(Y|X)    = {h_x:.4f} + {h_y_given_x:.4f} = {h_x+h_y_given_x:.4f}')  # equals H(X,Y)
print(f'Subadditivity gap I(X;Y) = {h_x+h_y-h_xy:.4f} bits')

# Independent case: gap should be zero
p_xy_indep = np.outer(p_x, p_y)  # product distribution
h_indep    = entropy_bits(p_xy_indep.flatten())
print(f'H(X,Y) independent = {h_indep:.4f}, H(X)+H(Y) = {h_x+h_y:.4f}')
```

## Variants and Special Cases

For i.i.d. sources the multivariate chain rule simplifies to H(X1,...,Xn)=n*H(X1). For Markov chains H(Xt|X1,...,X_{t-1})=H(Xt|X_{t-1}), giving entropy rate h = H(X2|X1). Entropy of functions H(f(X)) <= H(X): many-to-one functions strictly reduce entropy; bijections preserve it exactly. Data Processing Inequality (DPI) for entropy: if X -> Y -> Z is a Markov chain then H(X|Z) >= H(X|Y) — downstream processing cannot recover information lost at an intermediate step. Conditioning on a specific value x0 can raise entropy H(Y|X=x0) > H(Y); the inequality H(Y|X) <= H(Y) holds only in expectation over X.

## ML and AI Connections

Autoregressive LM training maximizes sum_t log p(xt|x1,...,x_{t-1}), which by the chain rule equals log p(x1,...,xT) — the full sequence joint log-probability under the model. Perplexity PPL = exp(average token cross-entropy) directly estimates exp(H_rate). The information bottleneck theory views each neural layer as compressing X into Z: H(Z) <= H(X), and the learning goal is to retain I(Z;Y) while minimizing I(X;Z). Feature engineering works precisely because adding informative features reduces H(Y|features), lowering the Bayes-optimal error. Decision tree information gain is the reduction in H(Y|feature), selecting splits that most reduce conditional entropy.

```python
import numpy as np

def entropy_bits(p):
    p = np.asarray(p, dtype=float)
    mask = p > 0
    return float(-np.sum(p[mask] * np.log2(p[mask])))

def mutual_info_from_joint(p_xy):
    p_x   = p_xy.sum(axis=1)
    p_y   = p_xy.sum(axis=0)
    h_xy  = entropy_bits(p_xy.flatten())
    h_x   = entropy_bits(p_x)
    h_y   = entropy_bits(p_y)
    h_y_x = h_xy - h_x   # H(Y|X)
    mi    = h_y - h_y_x  # I(X;Y) = H(Y) - H(Y|X)
    return h_y, h_y_x, mi

# Conditioning reduces entropy more when variables are correlated
p_strong = np.array([[0.45, 0.05], [0.05, 0.45]])  # high correlation
p_weak   = np.array([[0.26, 0.24], [0.24, 0.26]])  # low correlation
p_indep  = np.array([[0.25, 0.25], [0.25, 0.25]])  # independent

for name, p in [('strong', p_strong), ('weak', p_weak), ('indep', p_indep)]:
    h_y, h_y_x, mi = mutual_info_from_joint(p)
    print(f'{name:6s}: H(Y)={h_y:.3f}  H(Y|X)={h_y_x:.3f}  I(X;Y)={mi:.3f}')
```

## Implementation Pitfalls

When computing joint entropy from empirical counts, normalize the count matrix to probabilities and verify it sums to 1 before proceeding. For computing H(Y|X) = sum_x p(x)*H(Y|X=x), handle rows where p_x=0 by skipping them — dividing a row by zero probability creates NaN. Beware that H(Y|X=x0) for a specific value can exceed H(Y): conditioning on a specific outcome is not the same as conditioning on the variable in expectation. For sequence models, track each conditional term H(Xt|X_{<t}) separately to identify which positions are most uncertain, rather than averaging perplexity across all positions.

## Practical Guidance

Use conditional entropy H(Label|Features) to quantify how much residual uncertainty the features leave — lower is better. Compute I(X;Y) = H(Y) - H(Y|X) to measure feature relevance without fitting a model. For LLM debugging, track per-position entropy H(Xt|context) to locate high-uncertainty positions in sequences — these correspond to ambiguous tokens where the model spreads probability mass. When analyzing information flow in a pipeline X -> Y -> Z, measure I(X;Y) and I(Y;Z) separately to localize where information is lost. Residual connections in transformers maintain H(layer output) ~= H(layer input) by keeping each layer nearly invertible.

```python
import numpy as np

def entropy_bits(p):
    p = np.asarray(p, dtype=float)
    mask = p > 0
    return float(-np.sum(p[mask] * np.log2(p[mask])))

def transform_entropy_loss(probs, transform_fn):
    # Compute H(X) and H(f(X)) to measure information loss
    p  = np.array(probs)
    xs = np.arange(len(p))
    ys = np.array([transform_fn(x) for x in xs])
    # aggregate probability mass at each output value
    out_vals = np.unique(ys)
    p_out = np.array([p[ys == v].sum() for v in out_vals])
    return entropy_bits(p), entropy_bits(p_out)

p = [0.25, 0.25, 0.25, 0.25]   # uniform over {0,1,2,3}
h_x, h_id   = transform_entropy_loss(p, lambda x: x)       # identity
h_x, h_mod2 = transform_entropy_loss(p, lambda x: x % 2)  # many-to-one
h_x, h_sq   = transform_entropy_loss(p, lambda x: x*x)    # injective

print(f'H(X)           = {h_x:.3f} bits')
print(f'H(identity(X)) = {h_id:.3f} bits  [no loss, bijection]')
print(f'H(X mod 2)     = {h_mod2:.3f} bits  [info lost, many-to-one]')
print(f'H(X squared)   = {h_sq:.3f} bits  [injective on support, no loss]')
```

> **INFO: Autoregressive Models and the Chain Rule**
> GPT-style models maximize sum_t log p(xt | x1,...,x_{t-1}). By the chain rule, this is exactly log p(x1,...,xT) — the joint log-probability of the sequence. Training cross-entropy is H(p_true, q_model) where the chain rule factors both p_true and q_model identically. Perplexity = exp(average token CE) = exp(H(p,q)) directly estimates the effective branching factor at each step.

| Quantity | Formula | Key Property |
|---|---|---|
| H(X,Y) | E[-log p(X,Y)] | Total uncertainty; always >= max(H(X),H(Y)) |
| H(Y\|X) | H(X,Y) - H(X) | Remaining uncertainty about Y given X |
| Chain rule | H(X,Y) = H(X) + H(Y\|X) | Fundamental decomposition of joint entropy |
| Subadditivity | H(X,Y) <= H(X)+H(Y) | Equality iff X and Y independent |
| Conditioning | H(Y\|X) <= H(Y) | Equality iff X and Y independent |
| Functions | H(f(X)) <= H(X) | Equality iff f invertible on support of X |
| DPI | H(X\|Z) >= H(X\|Y) for X->Y->Z | Processing cannot recover lost information |

---

## Key Takeaways

- H(X,Y) = E[-log p(X,Y)] — joint entropy measures total uncertainty of a pair; always at least as large as each marginal
- H(Y|X) = H(X,Y) - H(X) — conditional entropy is remaining uncertainty about Y after observing X; always non-negative
- Chain rule H(X,Y)=H(X)+H(Y|X) is the foundation of autoregressive LM training and sequence likelihood factorization
- Subadditivity H(X,Y) <= H(X)+H(Y) — the gap I(X;Y) = H(X)+H(Y)-H(X,Y) is the mutual information between variables
- Conditioning reduces entropy in expectation; for a specific outcome x0, H(Y|X=x0) can exceed H(Y)
- H(f(X)) <= H(X) for any deterministic function — information can only be lost or preserved, never created, by processing
- Data processing inequality: for X->Y->Z Markov chain, H(X|Z) >= H(X|Y) — no downstream stage can recover lost information