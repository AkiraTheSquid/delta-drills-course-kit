---
kc: torch.broadcasting-rules
title: Broadcasting rules
supporting: [torch.elementwise-ops, torch.reshape-flatten]
new_syntax: [none-newaxis-indexing, torch.broadcast_shapes, syntax.none]
faded: [111, 949, 151, 948, 950, 951]
guided: [499, 500, 952, 953]
independent: [501, 502, 954, 955, 1530, 1531, 1532, 1533, 1534]
integrated: [956, 957, 958, 1535, 1536, 1537]
---

## Concept: the right-alignment rule

Elementwise operations "require matching shapes" — except PyTorch will
**stretch** certain mismatched shapes to fit, following one mechanical rule
set called **broadcasting**. It is the engine under half of idiomatic
tensor code,
and it is fully predictable:

> **Align the two shapes from the RIGHT. For each axis pair, the sizes are
> compatible if they are equal, or if one of them is 1** (that axis gets
> conceptually copied to match). **A missing leading axis counts as 1.**

Work `(m, 1) + (1, n)` by hand: align → axis 0 is m vs 1 (stretch the 1 → m),
axis 1 is 1 vs n (stretch → n) — result shape `(m, n)`, where entry [i, j] =
`a[i, 0] + b[0, j]`. Every pairwise-combination table, distance matrix, and
outer product starts exactly like this.

The stretching is *virtual* — no copies are made; PyTorch just reuses the
single row/column while iterating. Two everyday cases you have already been
using: scalar-with-array (`z * 2`) and matrix-with-row (`z - row` where row
has shape (n,) — aligned right, it matches z's last axis).

## Worked example

```python
import torch as t

# column: [[0], [1], [2]]           (3, 1)
a = t.arange(3).reshape(3, 1)
# row:    [[0, 1, 2, 3]]            (1, 4)
b = t.arange(4).reshape(1, 4)

# Align right:  (3, 1) (1, 4) axis 1: 1 vs 4 ->
# stretch a across columns; axis 0: 3 vs 1 -> stretch
# b down rows. Result (3, 4): the "addition table" of
# the two vectors.
table = a + b

# The result SHAPE is decidable from the two input
# shapes alone, with nothing allocated — which is what
# you want when the real tensors are large and you
# only need to know whether they will fit together.

# Incompatible shapes fail here too, and fail early.
print("(3,1) + (1,4) ->", tuple(table.shape))
print(table)

try:
    t.broadcast_shapes((3, 4), (5, 4))
except RuntimeError as err:
    print("RuntimeError:", err)
else:
    raise AssertionError(
        "(3, 4) and (5, 4) should not broadcast")
# Hidden checks
assert table.shape == (3, 4)
assert table.tolist() == [[0, 1, 2, 3],
                          [1, 2, 3, 4],
                          [2, 3, 4, 5]]
assert t.broadcast_shapes(a.shape, b.shape) == (3, 4)
```

Why: writing the two shapes one above the other, right-aligned, and
resolving each column IS the method — do it on paper until it's automatic.
The result shape falls out before any code runs, which is exactly what
`t.broadcast_shapes` is for: it answers the shape question without touching a
single element, so reach for it instead of building a result you intend to
throw away.

## Faded practice

### q111
The broadcast sum of a column (m, 1) and a row (1, n).

```python starter
import torch as t

def solve(a, b):
    """(m, n) table where entry [i, j] = a[i, 0] + b[0, j]."""
    return _____ + _____
```

```python solution
import torch as t

def solve(a, b):
    """(m, n) table where entry [i, j] = a[i, 0] + b[0, j]."""
    return a + b
```


### q949
The shape question, asked of the shapes themselves — there is no tensor
here to measure, so the answer has to come from the rule.

```python starter
import torch as t


def solve(s1, s2):
    """The shape broadcasting s1 and s2 together produces."""
    return tuple(t._____(s1, s2))
```

```python solution
import torch as t


def solve(s1, s2):
    """The shape broadcasting s1 and s2 together produces."""
    return tuple(t.broadcast_shapes(s1, s2))
```

## Concept: placing the 1s yourself with None

The craft skill is **placing the 1s yourself**. Indexing with `None` (alias
`None`, which is what NumPy spells `np.newaxis`) inserts a length-1 axis:
`v[:, None]` turns shape (n,) into a
**column** (n, 1); `v[None, :]` makes an explicit **row** (1, n). When an
operation needs a vector to run *down* rather than *across* (or to hit a
specific axis of a 3-D array), you reshape it with `None` until the alignment
says what you mean.

When shapes are incompatible (say (3,) with (4,)), PyTorch raises rather than
guessing — a broadcast error means your alignment is wrong, and the fix is
almost always a well-placed `None`. Never reshape at random until the error
goes away: work the right-alignment on paper, decide where the 1 belongs,
and place it deliberately.

## Worked example

```python
import torch as t

# The addition table again, from FLAT vectors — we
# place the 1-axes:
va, vb = t.arange(3), t.arange(4)
table = va[:, None] + vb[None, :]

# 3-D case: image (h, w, c) scaled per-PIXEL by map
# (h, w). Align right: (2, 2, 3) vs (2, 2) -> trailing
# axes are 3 vs 2: INCOMPATIBLE. The map needs its
# stretch-axis at the END: scale[:, :, None] is (2, 2,
# 1).
img = t.ones((2, 2, 3))
scale = t.tensor([[1.0, 2.0],
                  [3.0, 4.0]])
scaled = img * scale[:, :, None]
print("flat vectors, 1-axes placed by hand ->",
      tuple(table.shape))
print(table)
print("scale", tuple(scale.shape),
      "-> scale[:, :, None]",
      tuple(scale[:, :, None].shape), "-> img * it",
      tuple(scaled.shape))
print("pixel [1, 0] scaled by 3:", scaled[1, 0])
# Hidden checks
assert table.shape == (3, 4)
assert scaled.shape == (2, 2, 3)
assert scaled[1, 0].tolist() == [3.0, 3.0, 3.0]   # whole pixel scaled by 3
```

Why: the `va[:, None] + vb[None, :]` form is the general recipe for "all
pairs f(a_i, b_j)". In the 3-D case, the naive `img * scale` FAILS the
alignment check — working the rule shows the 1 must go at the end.

## Faded practice

### q151
Scale each pixel of an (h, w, c) image by a per-pixel (h, w) map.

```python starter
import torch as t

def solve(a, b):
    """(h, w, c) image a scaled per-pixel by (h, w) map b."""
    return a * b[_____]
```

```python solution
import torch as t

def solve(a, b):
    """(h, w, c) image a scaled per-pixel by (h, w) map b."""
    return a * b[:, :, None]
```


### q948
The pairwise table again, and this time the operation is a difference —
which means the order of the two operands matters.

```python starter
import torch as t


def solve(a, b):
    """(m, n) table where entry [i, j] = a[i] - b[j]."""
    return a[_____] - b[_____]
```

```python solution
import torch as t


def solve(a, b):
    """(m, n) table where entry [i, j] = a[i] - b[j]."""
    return a[:, None] - b[None, :]
```

### q950
A step past the image case: the stretch axis is the FIRST one, so the 1s
go after it — and there are two of them to add, not one.

```python starter
import torch as t


def solve(x, s):
    """Every element of sample i scaled by s[i]."""
    return x * s[_____]
```

```python solution
import torch as t


def solve(x, s):
    """Every element of sample i scaled by s[i]."""
    return x * s[:, None, None]
```

### q951
The row range has to run DOWN and the column range ACROSS. Both are flat
to begin with, so both need a 1 placed by hand.

```python starter
import torch as t


def solve(rows, cols):
    """(rows, cols) grid where entry [i, j] = i * cols + j."""
    return t.arange(rows)[_____] * cols + t.arange(cols)[_____]
```

```python solution
import torch as t


def solve(rows, cols):
    """(rows, cols) grid where entry [i, j] = i * cols + j."""
    return t.arange(rows)[:, None] * cols + t.arange(cols)[None, :]
```

## Solo practice

### q501
Scale each ROW by its own factor — right-alignment is not what you want.

### q502
A multiplication table from two ranges and no loop.

### q954
Scale each matrix row, then add one bias per column.

### q955
One three-axis product table from three vectors.

### q1530
A table of squared differences between two vectors — decide which one runs down the rows.

### q1531
Two shapes in, one shape out — or a refusal. No tensor is ever built.

### q1532
One weight per image ROW, applied to every image — the vector has to hit the middle axis.

### q1533
A product table for every batch row, with the batch axis kept in front.

### q1534
One value per row, handed over as a column — decide what, if anything, still needs placing.

## Guided practice

### q499
1. Do NOT tile the bias. Write the addition and let the shapes meet.
2. Shapes align from the RIGHT: a (cols,) vector already lines up with the
   last axis of a (rows, cols) matrix, and the missing axis is treated as 1.
3. `x + bias`.

### q500
1. You are asked for the resulting shape, not for a rule recited back.
2. There is a function that takes the two SHAPES and returns the combined one,
   without building anything — then convert its torch.Size to a plain tuple.
3. `tuple(t.broadcast_shapes(a.shape, b.shape))`.

### q952
1. Both inputs are FLAT, so neither of them runs down the page yet. Aligned right as they are, (m,) against (n,), the rule pairs m with n and refuses.
2. One of them has to become a column and the other a row. `v[:, None]` is the column form, `v[None, :]` the row form.
3. `a[:, None] * b[None, :]`.

### q953
1. Write the two shapes one above the other and align them from the RIGHT: (b, h, w, c) over (c,).
2. Every column of that alignment already resolves — c pairs with c, and the three missing leading axes each count as 1. Nothing needs placing by hand.
3. `imgs - mean`.

## Integrated practice

### q956
Subtract one value per colour channel, then apply one gain per image.

### q957
Return both the broadcast shape and the elementwise sum.

### q958
Given batched origins, directions, and distances, return every resulting 3-D
point with shape `(b, k, 3)`.

### q1535
Per-column centre and scale, then a per-row weight — one of the three vectors needs placing by hand.

### q1536
A function on a grid — which vector goes down the rows is part of the question, and so is the shape.

### q1537
Channels-first images: one vector aims at the second axis, the other at the first.

## Misconceptions

- **"Broadcasting matches shapes from the left."** — From the RIGHT. `(3,)`
  against `(3, 4)` aligns 3-with-4 and fails; `(4,)` against `(3, 4)` aligns
  4-with-4 and works. Most surprise errors are left-alignment intuition.
- **"Stretching copies the data."** — The stretch is virtual; memory is
  reused, not duplicated. Broadcasting a (10000, 1) against (1, 10000) does
  NOT allocate 10⁸ intermediate elements for the inputs.
- **"When shapes don't broadcast, reshape until the error goes away."** —
  Random reshaping produces silently WRONG results more often than errors.
  Work the right-alignment on paper, decide where the 1 belongs, and place it
  with `None` deliberately.
