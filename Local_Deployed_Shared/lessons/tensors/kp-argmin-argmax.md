---
kc: torch.argmin-argmax
title: Locating extremes — argmin and argmax
supporting: [torch.aggregations, torch.slicing-views]
new_syntax: [Tensor.argmax, torch.abs, torch.argmax, torch.argmin]
faded: [38, 219, 98]
guided: [1]
independent: [24, 61, 168, 1508, 1509, 1576, 1577, 1578]
integrated: [1510, 1511, 1579, 1580, 1658, 1659, 1660, 1661]
---

## Concept: argmin/argmax — the index, not the value

`min`/`max` tell you the extreme **value**; the `arg` twins tell you **where
it lives**:

- **`t.argmin(v)` / `v.argmin()`** — index of the smallest element.
- **`t.argmax(v)` / `v.argmax()`** — index of the largest.

**Ties break to the first occurrence.** If the extreme value appears more
than once, you get the smallest index — deterministically. Many drills state
"replace only the first occurrence"; argmin/argmax gives exactly that for
free.

Like other reductions, the result is a 0-dim TENSOR, not a Python int;
wrap in `int(...)` when
a plain Python int is required. (Per-row/column argmax with `axis=` appears
in the broadcasting lesson — same idea, one axis at a time.)

## Worked example

```python
import torch as t

v = t.tensor([4.0, 2.0, 7.0, 2.0, 9.0])

# Index of the minimum. 2.0 appears twice — argmin
# reports the FIRST.
i = int(t.argmin(v))

# The value at that index is the min itself.
print("v", v)
print("argmin ->", i, "| v[i] =", v[i].item(),
      "| v.min() =", v.min().item())
# Hidden checks
assert i == 1
assert v[i] == v.min()
```

Why: `int(...)` at the boundary again — graders asking for "a plain Python
int" reject `t.int64`. And `v[v.argmax()]` is how you get the value back
when you need both.

## Faded practice

### q38
Index of the smallest element (first occurrence on ties), as a plain int.

```python starter
import torch as t

def solve(v):
    """Index of v's smallest element, first occurrence on ties."""
    return int(t._____(v))
```

```python solution
import torch as t

def solve(v):
    """Index of v's smallest element, first occurrence on ties."""
    return int(t.argmin(v))
```

## Concept: the index as a handle for surgery

"Replace the largest entry with 0" is: copy (if the input must survive), then
`out[out.argmax()] = 0`. One read, one write, no scanning loop — the index is
a *handle* you use to edit the array.

The habit to build: **protect the input, then operate.** Copy first, then
assign through the index. It reads cleanest and never backfires.

## Worked example

```python
import torch as t

v = t.tensor([4.0, 2.0, 7.0, 2.0, 9.0])

# Replace the max with 0 on a copy: the index is the
# handle.
out = v.clone()
# argmax -> 4; out[4] = 0
out[out.argmax()] = 0.0
print("out", out)
print("v  ", v, " <- untouched")
# Hidden checks
assert out.tolist() == [4.0, 2.0, 7.0, 2.0, 0.0]
assert v.tolist() == [4.0, 2.0, 7.0, 2.0, 9.0]   # input intact
```

Why: the copy-then-assign order matters when the input must survive —
`v[v.argmax()] = 0` would mutate the caller's array.

## Faded practice

### q219
Largest entry replaced with 0 (first occurrence only), input untouched.

```python starter
import torch as t

def solve(x):
    """x with its largest entry replaced by 0.0, without mutating x."""
    result = x._____()
    result[t.argmax(x)] = 0.0
    return result
```

```python solution
import torch as t

def solve(x):
    """x with its largest entry replaced by 0.0, without mutating x."""
    result = x.clone()
    result[t.argmax(x)] = 0.0
    return result
```

## Concept: closest-to-target — argmin on a transformed array

argmin/argmax compose with transformed arrays. The pattern
`t.argmin(t.abs(z - target))` answers "which entry is *closest to*
target?" — build the quantity you want minimized, then ask where its minimum
sits. Any "closest / best / most-similar" task is this pattern with a
different transform.

Keep the roles straight: the *transformed* array chooses the index; the
*original* array supplies the value at that index.

## Worked example

```python
import torch as t

v = t.tensor([4.0, 2.0, 7.0, 2.0, 9.0])

# "Closest to target" = argmin of a transformed array.
target = 6.5
j = int(t.argmin(t.abs(v - target)))
closest_value = v[j]
print("gaps to", target, ":", t.abs(v - target))
print("smallest gap at index", j, "-> value",
      closest_value.item())
# Hidden checks
assert j == 2                     # |7.0 - 6.5| = 0.5 is the smallest gap
assert closest_value == 7.0
```

Why: no sorting needed — sorting is O(n log n) and loses positions;
`argmin(|v - t|)` is one pass and keeps them.

## Faded practice

### q98
The INDEX of the entry closest to target, as a plain int.

```python starter
import torch as t

def solve(z, target):
    """Index of the entry of z closest to target."""
    return int(t.argmin(t._____(z - target)))
```

```python solution
import torch as t

def solve(z, target):
    """Index of the entry of z closest to target."""
    return int(t.argmin(t.abs(z - target)))
```

## Guided practice

### q1
1. Per row means the reduction runs ALONG the columns — which axis number
   is that for a 2-D tensor?
2. You want the position of the max, not the max itself, and torch already
   breaks ties leftmost.
3. `z.argmax(dim=1)` — first-occurrence tie-breaking is the documented
   default, so no extra work is needed.

## Solo practice

### q24
Replace the first largest value with zero, in a copy.

### q61
The VALUE closest to v: transform, find the position, then read the original.

### q168
Per-row position of the maximum, breaking ties by the LAST occurrence instead of the default first.

### q1508
Per column, where the smallest value sits.

### q1509
Locate the overall maximum as a row-and-column pair.

### q1576
Where the extremes sit — positions, not values.

### q1577
One winner per row — pick the axis that runs along the row.

### q1578
Nearest to a target: transform first, then ask where the minimum is.

## Integrated practice

### q1510
Closest-to-target, but one answer per row.

### q1511
The runner-up's position, without disturbing the input.

### q1579
Find both extremes, then use the two positions to swap — without losing either value.

### q1580
Nearest to a target on a grid: a flat winner, then turned back into a row and a column.

### q1658
Farthest from the mean: a transform with an absolute value, then the winner's index.

### q1659
Largest magnitude: the index from the transformed values, the sign from the originals.

### q1660
Nearest and farthest from a target at once: one transformed vector, both extremes located.

### q1661
Replace the extreme with the mean of the OTHERS: index as a handle, a fresh tensor, an excluded average.

## Misconceptions

- **"argmax returns the maximum."** — It returns the *index* of the maximum.
  `v[v.argmax()]` is the value; needing both is common and costs one extra
  read.
- **"Ties are an error / unspecified."** — Ties resolve to the first
  occurrence, deterministically. Tasks that say "first occurrence" are
  describing argmin/argmax's default, not asking for extra work.
- **"Closest-to-target needs sorting."** — Sorting is O(n log n) and loses
  positions; `argmin(|v - t|)` is one pass and keeps them. Save sorting for
  when you need full order, not one winner.
