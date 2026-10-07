---
kc: torch.dot-matmul-patterns
title: Dot products and matrix-multiply patterns
supporting: [torch.linalg-basics, torch.axis-reductions, torch.broadcasting-rules]
new_syntax: [torch.dot]
faded: [37, 144, 121]
guided: [514]
independent: [141, 515, 95, 1517, 1518, 1645, 1646, 1647]
integrated: [1519, 1520, 1648, 1649]
---

## Concept: the dot product — multiply, then sum

The **dot product** of two equal-length vectors — multiply corresponding
entries, add them up — is the atom that all of linear algebra's products are
built from. PyTorch spells it three interchangeable ways:

```python no-run
t.dot(a, b)      ==  a @ b  ==  (a * b).sum()
```

The third spelling is the important one conceptually: *dot = elementwise
multiply + reduction.* Holding the decomposition lets you build variants
(weighted dots, masked dots, batch dots) instead of hunting for a function
that may not exist.

## Worked example

```python
import torch as t

a = t.tensor([1.0, 2.0, 3.0])
b = t.tensor([4.0, -5.0, 6.0])

# The atom, three spellings — same number.
d = float(t.dot(a, b))
print("a * b (no sum yet):", a * b)
print("t.dot:", d, "| a @ b:", float(a @ b),
      "| (a*b).sum():", float((a * b).sum()))
# Hidden checks
assert d == float(a @ b) == float((a * b).sum()) == 12.0
```

Why: verifying the three dot spellings agree once buys permanent fluency:
when you see `(x * w).sum()` in someone's code, you now read "dot".

## Faded practice

### q37
Dot product of two vectors, as a plain float.

```python starter
import torch as t

def solve(a, b):
    """The dot product of vectors a and b."""
    return float(t._____(a, b))
```

```python solution
import torch as t

def solve(a, b):
    """The dot product of vectors a and b."""
    return float(t.dot(a, b))
```

## Concept: matrix @ vector — one dot per row

**Matrix @ vector** (`z @ v`, shapes (n, m) @ (m,)): one dot per row of z —
"each row dotted with v" in a single call. Result shape (n,). (Matrix @
matrix is one dot per (row, column) pair — the previous KP.)

Check one output by hand and the shape rule follows: matmul = a dot per
row, so an (n, m) matrix against a length-m vector yields n dots.

## Worked example

```python
import torch as t

# Matrix @ vector: row i of the result = (row i of z)
# . v
z = t.tensor([[1.0, 2.0],
              [3.0, 4.0]])
v = t.tensor([10.0, 1.0])
zv = z @ v
print(tuple(z.shape), "@", tuple(v.shape), "->",
      tuple(zv.shape), ":", zv)
# Hidden checks
assert zv.tolist() == [12.0, 34.0]        # 1*10+2*1, 3*10+4*1
```

Why: checking one output by hand (1·10 + 2·1 = 12) anchors "matmul = a dot
per row" — and predicts the result's shape (n,) without memorizing another
rule.

## Faded practice

### q144
Each row of z dotted with v.

```python starter
import torch as t

def solve(z, v):
    """Length-n array: entry i = (row i of z) . v."""
    return z _____ v
```

```python solution
import torch as t

def solve(z, v):
    """Length-n array: entry i = (row i of z) . v."""
    return z @ v
```

## Concept: when @ doesn't fit — multiply, then reduce an axis

When the pattern you need is *not* one of the packaged shapes, the
decomposition rescues you. "Dot each row of `a` with the CORRESPONDING row
of `b`" (same shapes) is not `a @ b` — matmul dots every row with every
COLUMN. But per the atom: multiply elementwise, then reduce each row:

```python no-run
(a * b).sum(dim=1)          # row-wise dots
```

That multiply-then-reduce-an-axis maneuver covers the "batch of dots" tasks
— and a later course will name that whole move in one string, with the
summed axis simply left off the output.

## Worked example

```python
import torch as t

# Row-wise dots of two SAME-SHAPE matrices: NOT a
# matmul.
p = t.tensor([[1.0, 2.0],
              [3.0, 4.0]])
q = t.tensor([[5.0, 6.0],
              [7.0, 8.0]])
row_dots = (p * q).sum(dim=1)
print("row-wise dots", row_dots)
print("p @ q would be something else entirely:")
print(p @ q)
# Hidden checks
assert row_dots.tolist() == [17.0, 53.0]  # 1*5+2*6, 3*7+4*8
```

Why: this case is deliberately a trap — `p @ q` runs on these square
matrices and returns the WRONG thing (full matrix product). Decomposing to
multiply+sum(axis=1) is the general escape whenever the packaged products
don't match the pairing you need.

## Faded practice

### q121
Dot each row of a with the corresponding row of b.

```python starter
import torch as t

def solve(a, b):
    """Length-n array: entry i = (row i of a) . (row i of b)."""
    return (a * b).sum(dim=_____)
```

```python solution
import torch as t

def solve(a, b):
    """Length-n array: entry i = (row i of a) . (row i of b)."""
    return (a * b).sum(dim=1)
```

## Solo practice

### q141
Diagonal of a @ b WITHOUT computing the full product — think about which dots the diagonal actually needs: row i of a with COLUMN i of b.

### q515
Rescale every row to unit length.

### q95
RGB to grayscale — a weighted sum over the channel axis, no loops.

### q1517
Each row dotted with itself.

### q1518
Every row of one matrix against every row of another.

### q1645
Dot = multiply, then sum: a third factor slots into the multiply.

### q1646
A masked dot: zero out the terms you don't want, then sum.

### q1647
Row-wise dots: multiply elementwise, reduce the feature axis.

## Guided practice

### q514
1. Do not reach for the built-in dot product — the question wants the two
   steps it is made of.
2. Multiply the pairs elementwise, then collapse the result to one number.
3. `float((a * b).sum())`.

## Integrated practice

### q1519
A linear layer: contract, then add a bias to every row.

### q1520
All-pairs squared distances from three dot-product pieces.

### q1648
One matrix-vector product for all the scores, then one more dot.

### q1649
Every row against every row: one matmul against the transpose.

## Misconceptions

- **"Row-wise dots of two matrices = a @ b."** — Matmul dots every row with
  every COLUMN. Corresponding-rows pairing is elementwise-multiply + row
  reduction: `(a * b).sum(axis=1)`.
- **"The dot product is its own primitive."** — It's multiply + sum. Holding
  the decomposition lets you build variants (weighted dots, masked dots,
  batch dots) instead of hunting for a function that may not exist.
- **"norm of a matrix = largest row norm."** — Default `t.linalg.norm(z)` on
  2-D is FROBENIUS: all entries squared, summed, rooted — as if the matrix
  were one long vector. Operator norms exist behind `ord=`, but Frobenius is
  the drills' default meaning of "the norm".
