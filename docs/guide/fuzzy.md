# Fuzzy (Łukasiewicz / BL) logic

The fuzzy layer interprets the Łukasiewicz / basic-logic (BL) connectives over the real interval `[0, 1]`: `fuzzy_evaluate` computes a truth **degree** under a valuation, and `fuzzy_is_satisfiable` / `fuzzy_is_valid` / `fuzzy_get_model` decide formulas via Z3 reals. Version 0.9.0 adds a t-norm selector (Łukasiewicz / Gödel / product) and quantifier grounding so quantified fuzzy validity is decidable.

Everything on this page is imported from the top-level package:

```python
from unicode_logic_kit import (
    MSFLParser,
    fuzzy_evaluate, fuzzy_is_valid, fuzzy_is_satisfiable, fuzzy_get_model,
    get_tnorm, TNORMS, TNorm,
    WeakConjunction, WeakDisjunction,
    StrongConjunction, StrongDisjunction,
    LukNegation, LukImplication, LukEquivalence,
    Atom,
)
```

## Parsing fuzzy formulas (FL / MSFL mode)

Parse with `MSFLParser(fuzzy=True)` for single-sorted FL (unsorted quantifiers, plain constants) or `MSFLParser(many_sorted=True, fuzzy=True)` for many-sorted MSFL (`∀x:Sort`, `alice:Sort`). In both modes the connectives carry Łukasiewicz semantics:

| Surface | Node | Semantics |
|---|---|---|
| weak `∧` | `WeakConjunction` | `min(x, y)` |
| weak `∨` | `WeakDisjunction` | `max(x, y)` |
| strong `⊗` | `StrongConjunction` | t-norm (default `max(0, x+y−1)`) |
| strong `⊕` | `StrongDisjunction` | t-conorm (default `min(1, x+y)`) |
| `¬` | `LukNegation` | `1 − x` |
| `→` | `LukImplication` | `min(1, 1−x+y)` |
| `↔` | `LukEquivalence` | `1 − \|x−y\|` |

Classical boolean nodes (`And`/`Or`/`Not`/…) are intentionally rejected by the evaluator: a formula meant for fuzzy evaluation must be parsed in FL/MSFL mode so its connectives are unambiguous. You can also build nodes directly — `StrongConjunction`, `LukNegation`, etc. — instead of parsing.

```python
from unicode_logic_kit import MSFLParser

fl = MSFLParser(fuzzy=True)                       # single-sorted FL
ms = MSFLParser(many_sorted=True, fuzzy=True)     # many-sorted MSFL

fl.parse("P ⊗ (Q → R)").to_unicode_str()          # → 'P ⊗ (Q → R)'
type(fl.parse("P ⊗ Q")).__name__                  # → 'StrongConjunction'
type(fl.parse("P ∧ Q")).__name__                  # → 'WeakConjunction'
type(fl.parse("¬P")).__name__                     # → 'LukNegation'

ms.parse("∀x:Person Tall(x)").to_unicode_str()    # → '∀x:Person Tall(x)'
ms.parse("Tall(alice:Person)").to_unicode_str()   # → 'Tall(alice:Person)'
```

`fuzzy=True` also combines with `modal=True`, `second_order=True` and `third_order=True`, each with or without `many_sorted=True`: the modal operators, the predicate quantifiers `∀P` / `∃P` and a predicate in argument position stand over the same seven connectives. A fuzzy mode has none of the forms whose reading is two-valued (the counting quantifier `∃≥n`, `but`, the measure term and the cardinality term). {doc}`parsing` has the table of the modes; the sections [Graded (fuzzy) Kripke semantics](#graded-fuzzy-kripke-semantics), [Predicate quantifiers](#predicate-quantifiers) and [Third-order atoms](#third-order-atoms) below say what evaluates and decides their formulas.

```python
fm = MSFLParser(fuzzy=True, modal=True)
fm.parse("□(P ⊗ Q) → □P").to_unicode_str()        # → '□(P ⊗ Q) → □P'
type(fm.parse("¬□P")).__name__                    # → 'LukNegation'

so = MSFLParser(fuzzy=True, second_order=True)
so.parse("∀P (P ⊕ ¬P)").to_unicode_str()          # → '∀P (P ⊕ ¬P)'

MSFLParser(fuzzy=True, third_order=True, modal=True, many_sorted=True)._mode
# → 'fltomodal_sorted'
```

Parsing a classical boolean formula in fuzzy mode (or feeding a classically parsed formula to the evaluator) is the one common mistake — the connective node carries no Łukasiewicz reading and the evaluator rejects it:

```python
from unicode_logic_kit import MSFLParser, fuzzy_evaluate

classical = MSFLParser()                            # default: classical FOL
fuzzy_evaluate(classical.parse("P ∧ Q"), {"P": 0.5, "Q": 0.5})
# raises TypeError: Classical connective And is not valid in fuzzy input …
```

## `fuzzy_evaluate` — truth degree under a valuation

`fuzzy_evaluate(node, valuation, domain=None, sort_universes=None, tnorm="lukasiewicz")` returns the degree in `[0, 1]`. The `valuation` maps each ground atom's key — `atom_key(atom)`, the text of the atom with every constant written by its bare name and a sorted constant `c:S` written as `c`, e.g. `"P(alice)"`, `"P(a)"` or just `"P"` — to a degree. The text of the atom as a formula (`atom.to_unicode_str()`) writes a constant in quotes when its bare name would read as something else, `"P('a')"`, and a valuation keyed that way is read as the same key; a valuation that holds both spellings of one atom with different degrees raises `ValueError`. A missing key raises `KeyError`. Two different atoms that print alike (the numeral `1` and a constant named `1`, a free variable `x` and a constant named `x`) would have one key and are refused with `NotImplementedError`, by the Z3 deciders below as by `fuzzy_evaluate`.

```python
from unicode_logic_kit import MSFLParser, fuzzy_evaluate

fl = MSFLParser(fuzzy=True)

fuzzy_evaluate(fl.parse("P ⊗ ¬P"), {"P": 0.6})           # → 0.0   (strong: max(0, 0.6+0.4−1))
fuzzy_evaluate(fl.parse("P ⊕ ¬P"), {"P": 0.6})           # → 1.0   (strong: min(1, 0.6+0.4))
fuzzy_evaluate(fl.parse("P ∧ ¬P"), {"P": 0.6})           # → 0.4   (weak: min(0.6, 0.4))
fuzzy_evaluate(fl.parse("P ↔ Q"), {"P": 0.6, "Q": 0.7})  # → 0.9   (1 − |0.6 − 0.7|)
fuzzy_evaluate(fl.parse("P → Q"), {"P": 0.8, "Q": 0.5})  # → 0.7   (min(1, 1−0.8+0.5))
```

### Weak vs strong, side by side

The weak `∧ / ∨` are the lattice `min / max`; the strong `⊗ / ⊕` are the t-norm and its t-conorm. They coincide only at the extremes — in the middle the strong pair is "more demanding" (`⊗ ≤ ∧`) and "more permissive" (`⊕ ≥ ∨`):

```python
v = {"P": 0.6, "Q": 0.7}
fuzzy_evaluate(fl.parse("P ∧ Q"), v)             # → 0.6   weak conjunction = min
round(fuzzy_evaluate(fl.parse("P ⊗ Q"), v), 10)  # → 0.3   strong  = max(0, 0.6+0.7−1)
fuzzy_evaluate(fl.parse("P ∨ Q"), v)             # → 0.7   weak disjunction = max
fuzzy_evaluate(fl.parse("P ⊕ Q"), v)             # → 1.0   strong  = min(1, 0.6+0.7)
```

> Many Łukasiewicz degrees are not exactly representable in binary floating point: `0.6 + 0.7 − 1` evaluates to `0.2999999999999998`, so the examples above wrap a noisy result in `round(..., 10)`. The evaluator computes in ordinary floating point, so the noise is in the returned value itself, and the rounding removes it.

### Negation and implication

Łukasiewicz negation `1 − x` is **involutive** (`¬¬P = P`), and the implication is the residuum of `⊗`:

```python
round(fuzzy_evaluate(fl.parse("¬P"), {"P": 0.3}), 10)    # → 0.7
round(fuzzy_evaluate(fl.parse("¬¬P"), {"P": 0.3}), 10)   # → 0.3   (involutive)

fuzzy_evaluate(fl.parse("P → Q"), {"P": 0.4, "Q": 0.9})  # → 1.0   (x ≤ y ⇒ implication is 1)
fuzzy_evaluate(fl.parse("P → Q"), {"P": 0.9, "Q": 0.4})  # → 0.5   (min(1, 1−0.9+0.4))
```

### A missing atom raises `KeyError`

Every ground atom that appears must have a degree in the valuation:

```python
fuzzy_evaluate(fl.parse("P ⊗ Q"), {"P": 0.6})
# raises KeyError: "No degree for ground atom 'Q' in the valuation. …"
```

The truth constants `⊤` and `⊥` are the exception: they are the degrees `1` and `0` under every valuation and need no entry. The Z3 deciders and `satisfies_fuzzy_modal` (below) read them the same way:

```python
fuzzy_evaluate(fl.parse("⊤ → P"), {"P": 0.4})  # → 0.4   (⊤ is the degree 1: min(1, 1−1+0.4))
fuzzy_evaluate(fl.parse("¬⊥"), {})             # → 1.0   (⊥ is the degree 0)
fuzzy_is_valid(fl.parse("⊥ → P"))              # → True  (degree min(1, 1−0+x) = 1 for every x)
```

### Quantifiers (inf / sup over a finite domain)

Quantifiers are the infimum (`∀` = min) and supremum (`∃` = max) over a finite `domain` of constant names; a `SortedQuantifier` ranges over `sort_universes[sort]`:

```python
fuzzy_evaluate(fl.parse("∀x P(x)"), {"P(a)": 0.3, "P(b)": 0.8}, domain={"a", "b"})  # → 0.3 (min)
fuzzy_evaluate(fl.parse("∃x P(x)"), {"P(a)": 0.3, "P(b)": 0.8}, domain={"a", "b"})  # → 0.8 (max)
```

The element `a` of the domain is the constant `a`, whose text as a formula is `'a'`: the key `"P('a')"` names the same atom as `"P(a)"`, and a valuation may use either (or one of each, as long as an atom is not given two different degrees):

```python
from unicode_logic_kit import Atom, Constant, atom_key

pa = Atom("P", [Constant("a")])
atom_key(pa)                                                      # → 'P(a)'
pa.to_unicode_str()                                               # → "P('a')"
fuzzy_evaluate(pa, {pa.to_unicode_str(): 0.3})                    # → 0.3  (keyed by the text of the formula)
fuzzy_evaluate(fl.parse("∀x P(x)"), {"P(a)": 0.3, "P('b')": 0.8}, domain={"a", "b"})  # → 0.3  (one key of each kind)
```

For sorted quantifiers, pass `sort_universes`. The bound variable is grounded to a bare constant, and a sorted constant `alice:Person` **is** the constant `alice`, so the valuation keys carry no sort annotation: `Tall(alice:Person)` has the key `'Tall(alice)'`, the key of the instance of `∀x:Person Tall(x)` at `alice`:

```python
ms = MSFLParser(many_sorted=True, fuzzy=True)
val = {"Tall(alice)": 0.7, "Tall(carol)": 0.4}
uni = {"Person": {"alice", "carol"}}

fuzzy_evaluate(ms.parse("∀x:Person Tall(x)"), val, sort_universes=uni)  # → 0.4 (inf)
fuzzy_evaluate(ms.parse("∃x:Person Tall(x)"), val, sort_universes=uni)  # → 0.7 (sup)
fuzzy_evaluate(ms.parse("Tall(alice:Person)"), val)                     # → 0.7 (the key 'Tall(alice)')
```

`fuzzy_is_valid`, `fuzzy_is_satisfiable`, `fuzzy_get_model` and `satisfies_fuzzy_modal` read a sorted constant the same way. So `(∀x:Person Tall(x)) → Tall(alice:Person)` is valid over a universe of `Person` that holds `alice`: the infimum over the universe is at most the degree at `alice`, so the implication has degree `1`:

```python
q = ms.parse("(∀x:Person Tall(x)) → Tall(alice:Person)")
fuzzy_evaluate(q, val, sort_universes=uni)  # → 1.0   (min(0.7, 0.4) ≤ 0.7)
fuzzy_is_valid(q, sort_universes=uni)       # → True
```

A universe of `Person` that does not hold `alice` contradicts the constant's own sort (a sorted constant is an element of its sort), so `fuzzy_evaluate` and the three Z3 deciders refuse it by name instead of deciding the formula as if `alice` were outside `Person`:

```python
fuzzy_is_valid(q, sort_universes={"Person": {"carol"}})
# raises ValueError: z3_fuzzy: the sorted constant alice:Person names an element that sort_universes['Person'] = ['carol'] does not hold. ...
```

Omitting the universe for a quantifier raises `ValueError`:

```python
fuzzy_evaluate(fl.parse("∀x P(x)"), {"P(a)": 0.5})
# raises ValueError: Evaluating an unsorted Quantifier requires a 'domain' …
```

## The three t-norms

A *t-norm* `T` fixes the **strong** connectives `⊗ ⊕ → ¬ ↔`; the weak `∧ / ∨` stay `min / max` and the quantifiers stay inf / sup regardless of `tnorm`. Three continuous t-norms ship — their ordinal sums generate every continuous t-norm (Mostert–Shields):

| `tnorm` | `⊗` | `⊕` | `→` | `¬` |
|---|---|---|---|---|
| `"lukasiewicz"` (default) | `max(0, x+y−1)` | `min(1, x+y)` | `min(1, 1−x+y)` | `1−x` (involutive) |
| `"godel"` | `min(x, y)` | `max(x, y)` | `1 if x≤y else y` | `1 if x≤0 else 0` |
| `"product"` | `x·y` | `x+y−x·y` | `1 if x≤y else y/x` | `1 if x≤0 else 0` |

Pass `tnorm=` to `fuzzy_evaluate` and to the deciders. The strong conjunction `⊗` is the clearest discriminator — same inputs, three answers:

```python
from unicode_logic_kit import MSFLParser, fuzzy_evaluate

fl = MSFLParser(fuzzy=True)
v = {"P": 0.5, "Q": 0.3}

fuzzy_evaluate(fl.parse("P ⊗ Q"), v, tnorm="lukasiewicz")  # → 0.0   max(0, 0.5+0.3−1)
fuzzy_evaluate(fl.parse("P ⊗ Q"), v, tnorm="godel")        # → 0.3   min(x, y)
fuzzy_evaluate(fl.parse("P ⊗ Q"), {"P": 0.5, "Q": 0.5}, tnorm="product")  # → 0.25  x·y
```

The implication `→` and equivalence `↔` differ too:

```python
w = {"P": 0.8, "Q": 0.4}
fuzzy_evaluate(fl.parse("P → Q"), w, tnorm="lukasiewicz")  # → 0.6    min(1, 1−0.8+0.4)
fuzzy_evaluate(fl.parse("P → Q"), w, tnorm="godel")        # → 0.4    1 if x≤y else y
fuzzy_evaluate(fl.parse("P → Q"), w, tnorm="product")      # → 0.5    1 if x≤y else y/x

e = {"P": 0.6, "Q": 0.7}
fuzzy_evaluate(fl.parse("P ↔ Q"), e, tnorm="lukasiewicz")          # → 0.9    1 − |x−y|
fuzzy_evaluate(fl.parse("P ↔ Q"), e, tnorm="godel")                # → 0.6    min(x→y, y→x)
round(fuzzy_evaluate(fl.parse("P ↔ Q"), e, tnorm="product"), 10)   # → 0.8571428571
```

### Negation: Łukasiewicz vs Gödel/product

Only Łukasiewicz negation is *involutive*. The Gödel and product negations are the residual "`x → 0`": `0` whenever `x > 0`, so they collapse all positive degrees:

```python
fuzzy_evaluate(fl.parse("¬P"), {"P": 0.3}, tnorm="godel")    # → 0.0   (any x>0 ↦ 0)
fuzzy_evaluate(fl.parse("¬P"), {"P": 0.0}, tnorm="godel")    # → 1.0
fuzzy_evaluate(fl.parse("¬¬P"), {"P": 0.3}, tnorm="godel")   # → 1.0   (NOT involutive!)
fuzzy_evaluate(fl.parse("¬¬P"), {"P": 0.0}, tnorm="godel")   # → 0.0
```

### `get_tnorm`, `TNORMS`, and the `TNorm` object

`get_tnorm(name)` returns the `TNorm` object and `TNORMS` is the registry dict. Each `TNorm` exposes the raw scalar operations `conj` / `disj` / `impl` / `neg` and the derived `equiv` — handy for plotting a connective or sanity-checking a hand calculation:

```python
from unicode_logic_kit import get_tnorm, TNORMS

sorted(TNORMS)                       # → ['godel', 'lukasiewicz', 'product']
get_tnorm("godel").name              # → 'godel'
get_tnorm("godel") is TNORMS["godel"]  # → True   (the registry instance)

luk = get_tnorm("lukasiewicz")
luk.conj(0.6, 0.7)                   # → 0.2999999999999998 (max(0, x+y−1))
luk.disj(0.6, 0.7)                   # → 1.0                (min(1, x+y))
luk.impl(0.8, 0.5)                   # → 0.7                (min(1, 1−x+y))
luk.neg(0.3)                         # → 0.7
luk.equiv(0.6, 0.7)                  # → 0.9                (min(x→y, y→x))

god = get_tnorm("godel")
god.impl(0.3, 0.5)                   # → 1.0   (x ≤ y)
god.impl(0.8, 0.5)                   # → 0.5   (else y)
god.neg(0.4)                         # → 0.0
```

An unknown name raises `ValueError`:

```python
get_tnorm("zadeh")
# raises ValueError: unknown t-norm 'zadeh'; use one of ['godel', 'lukasiewicz', 'product'].
```

## `fuzzy_is_satisfiable` / `fuzzy_is_valid` / `fuzzy_get_model` (Z3 reals)

Rather than fixing a valuation, you can ask the solver whether *some* (or *every*) assignment reaches a degree. Each ground atom becomes a Z3 `Real` constrained to `[0, 1]`, and the connectives become their piecewise-linear definitions.

- `fuzzy_is_valid(formula)` — `True` iff the degree is `1` under every valuation (it asserts `degree < 1` and checks unsatisfiability).
- `fuzzy_is_satisfiable(formula, threshold=1.0, strict=False)` — `True` iff some valuation reaches `degree >= threshold` (`> threshold` when `strict=True`).
- `fuzzy_get_model(formula, threshold=1.0)` — an atom→degree dict reaching the threshold (plus a `'degree'` entry), or `None`. An atom named `degree` (only a hand-built node can have one) is refused with `NotImplementedError`: the model reports the formula's own degree under that key.

```python
from unicode_logic_kit import (
    MSFLParser, fuzzy_is_valid, fuzzy_is_satisfiable, fuzzy_get_model,
)

fl = MSFLParser(fuzzy=True)

fuzzy_is_valid(fl.parse("P ⊕ ¬P"))                       # → True   (degree is 1 for every P)
fuzzy_is_satisfiable(fl.parse("P ⊗ ¬P"), threshold=0.5)  # → False  (strong: max degree is 0)
fuzzy_is_satisfiable(fl.parse("P ∧ ¬P"), threshold=0.5)  # → True   (weak: max degree is 0.5)

m = fuzzy_get_model(fl.parse("P → Q"), threshold=1.0)
sorted(m)         # → ['P', 'Q', 'degree']
m["degree"]       # → 1.0
```

The exact degrees a model assigns to `P` and `Q` are solver-dependent; only the `'degree'` it achieves (here `1.0`) is determined by the threshold.

### Thresholds and `strict`

The threshold is the bar the degree must clear. `strict=True` turns `>=` into `>`, which matters exactly at the boundary — the weak `P ∧ ¬P` peaks at `0.5`, so it reaches `0.5` but never *exceeds* it:

```python
fuzzy_is_satisfiable(fl.parse("P ∧ ¬P"), threshold=0.5)               # → True   (degree = 0.5 ≥ 0.5)
fuzzy_is_satisfiable(fl.parse("P ∧ ¬P"), threshold=0.5, strict=True)  # → False  (no valuation > 0.5)
fuzzy_is_satisfiable(fl.parse("P ∧ ¬P"))                              # → False  (default threshold 1.0)
fuzzy_is_satisfiable(fl.parse("P ⊗ Q"), threshold=0.3)               # → True
```

### A partial-degree model

Ask `fuzzy_get_model` for a witness that reaches a partial threshold; the returned `'degree'` meets it exactly when the solver can hit the bound, and is `None` when the threshold is unreachable:

```python
m = fuzzy_get_model(fl.parse("P ⊗ Q"), threshold=0.5)
sorted(m)          # → ['P', 'Q', 'degree']
m["degree"]        # → 0.5    (P + Q − 1 ≥ 0.5 has solutions, e.g. P = Q = 0.75)

fuzzy_get_model(fl.parse("P ⊗ ¬P"), threshold=1.0)   # → None  (max degree is 0)
```

### Validity differs by t-norm

The same formula can be valid under one t-norm and not another. Excluded middle `P ⊕ ¬P` is Łukasiewicz-valid (bounded sum reaches `1`) but Gödel-invalid (Gödel `⊕` is `max`, which only reaches `1` if `P` or `¬P` is `1`):

```python
fuzzy_is_valid(fl.parse("P ⊕ ¬P"), tnorm="lukasiewicz")  # → True
fuzzy_is_valid(fl.parse("P ⊕ ¬P"), tnorm="godel")        # → False

# Self-implication and double-negation introduction are robust:
fuzzy_is_valid(fl.parse("P → P"), tnorm="lukasiewicz")   # → True
fuzzy_is_valid(fl.parse("P → P"), tnorm="godel")         # → True

# Involution P ↔ ¬¬P holds only for Łukasiewicz:
fuzzy_is_valid(fl.parse("P ↔ ¬¬P"), tnorm="lukasiewicz")  # → True
fuzzy_is_valid(fl.parse("P ↔ ¬¬P"), tnorm="godel")        # → False
```

Modus ponens and a De Morgan law survive both deciders:

```python
fuzzy_is_valid(fl.parse("(P ⊗ (P → Q)) → Q"), tnorm="lukasiewicz")  # → True
fuzzy_is_valid(fl.parse("(P ⊗ (P → Q)) → Q"), tnorm="godel")        # → True
fuzzy_is_valid(fl.parse("¬(P ⊗ Q) ↔ (¬P ⊕ ¬Q)"), tnorm="lukasiewicz")  # → True
```

### The product t-norm is evaluator-only

The Łukasiewicz and Gödel t-norms are **piecewise-linear**, so Z3 decides them; `fuzzy_is_valid(…, tnorm="lukasiewicz")` and `fuzzy_is_valid(…, tnorm="godel")` are full decision procedures. The **product** t-norm needs nonlinear arithmetic (`x·y`, `y/x`) that Z3 cannot decide completely, so it is **evaluator-only** — `fuzzy_evaluate(…, tnorm="product")` works, but passing it to the Z3 deciders raises `NotImplementedError`:

```python
fuzzy_evaluate(fl.parse("P → Q"), {"P": 0.8, "Q": 0.4}, tnorm="product")  # → 0.5  (works)

fuzzy_is_satisfiable(fl.parse("P → Q"), tnorm="product")
# raises NotImplementedError: z3_fuzzy: the product t-norm needs nonlinear real arithmetic …
```

An unknown name still raises `ValueError` in the decider path:

```python
fuzzy_is_valid(fl.parse("P ⊕ ¬P"), tnorm="zadeh")
# raises ValueError: z3_fuzzy: unknown t-norm 'zadeh' (use lukasiewicz / godel).
```

### A distinguishing validity: contraction

Contraction `p → (p ⊗ p)` separates the two deciders. Under Gödel it is valid (`⊗` is idempotent `min`, so `p ⊗ p = p` and the implication is always `1`); under Łukasiewicz it fails (at `p = 0.5` the consequent `p ⊗ p = 0`, so the degree is only `0.5`):

```python
from unicode_logic_kit import MSFLParser, fuzzy_is_valid, fuzzy_evaluate

fl = MSFLParser(fuzzy=True)
contraction = fl.parse("P → (P ⊗ P)")

fuzzy_is_valid(contraction, tnorm="godel")        # → True
fuzzy_is_valid(contraction, tnorm="lukasiewicz")  # → False
fuzzy_evaluate(contraction, {"P": 0.5}, tnorm="lukasiewicz")  # → 0.5  (the counterexample)
```

## Quantifier grounding (0.9.0)

The Z3 deciders are propositional, but passing `domain=` (and `sort_universes=` for sorted quantifiers) **grounds** each quantifier over the finite universe first — `∀` folds into a weak-conjunction (min), `∃` into a weak-disjunction (max) — so quantified fuzzy validity and satisfiability become decidable:

```python
from unicode_logic_kit import MSFLParser, fuzzy_is_valid

fl = MSFLParser(fuzzy=True)

# Quantified contraction: Gödel-valid, Łukasiewicz-invalid, over a 2-element domain.
q = fl.parse("∀x (P(x) → (P(x) ⊗ P(x)))")
fuzzy_is_valid(q, domain={"a", "b"}, tnorm="godel")        # → True
fuzzy_is_valid(q, domain={"a", "b"}, tnorm="lukasiewicz")  # → False
```

Grounded satisfiability and models work the same way — the model keys are the keys (`atom_key`, every constant by its bare name) of the grounded atoms:

```python
from unicode_logic_kit import fuzzy_is_satisfiable, fuzzy_get_model

fl = MSFLParser(fuzzy=True)

# ∃ reaches a high degree iff some instance can:
fuzzy_is_satisfiable(fl.parse("∃x P(x)"), threshold=0.9, domain={"a", "b"})  # → True

# A model for ∀x (P(x) ⊕ ¬P(x)) at degree 1 — one degree per grounded atom:
m = fuzzy_get_model(fl.parse("∀x (P(x) ⊕ ¬P(x))"), threshold=1.0, domain={"a", "b"})
sorted(m)      # → ['P(a)', 'P(b)', 'degree']
m["degree"]    # → 1.0
```

Sorted quantifiers ground over `sort_universes` instead:

```python
ms = MSFLParser(many_sorted=True, fuzzy=True)
qs = ms.parse("∀x:Person (Tall(x) → (Tall(x) ⊗ Tall(x)))")

fuzzy_is_valid(qs, sort_universes={"Person": {"a", "b"}}, tnorm="godel")        # → True
fuzzy_is_valid(qs, sort_universes={"Person": {"a", "b"}}, tnorm="lukasiewicz")  # → False
```

Without the matching universe a quantifier raises `ValueError` (in the deciders) or, in `fuzzy_evaluate`, when `domain` is omitted:

```python
fuzzy_is_valid(fl.parse("∀x P(x)"), tnorm="lukasiewicz")
# raises ValueError: Grounding an unsorted Quantifier requires a non-empty 'domain'.
```

A variable that is free in a quantified formula is a parameter, one unknown element of the domain, and the deciders have no reading of it: they refuse it by name with `NotImplementedError` (bind the variable, or write a constant of the domain). `fuzzy_evaluate` takes the atom `P(x)` as one more key of the valuation. A comparison atom (`a = a`, `1 < 2`) has no degree and is refused with `TypeError` by the deciders and by `atp.z3_fuzzy.degree_expr`, exactly as by `fuzzy_evaluate`:

```python
fuzzy_is_valid(fl.parse("∀y P(y) → P(x)"), domain={"a", "b"})
# raises NotImplementedError: z3_fuzzy: the variable(s) ['x'] are free in a quantified formula. …
```

```python
fuzzy_is_valid(fl.parse("1 < 2"))
# raises TypeError: Comparison atom '1 < 2' has no Łukasiewicz truth degree; the fuzzy decider only handles propositional predicate atoms.
```

## Building fuzzy nodes directly

Every connective has a node class — `WeakConjunction`, `WeakDisjunction`, `StrongConjunction`, `StrongDisjunction`, `LukNegation`, `LukImplication`, `LukEquivalence` — that the evaluator and deciders accept without parsing. Each binary class takes `(left, right)`; `LukNegation` takes one operand; an atom is `Atom(predicate, args)`:

```python
from unicode_logic_kit import (
    StrongConjunction, StrongDisjunction, LukNegation, LukImplication,
    Atom, fuzzy_evaluate, fuzzy_is_valid,
)

node = StrongConjunction(Atom("P", []), LukNegation(Atom("P", [])))
node.to_unicode_str()             # → 'P ⊗ ¬P'
fuzzy_evaluate(node, {"P": 0.6})  # → 0.0

# Build excluded-middle and decide it without ever parsing a string:
em = StrongDisjunction(Atom("P", []), LukNegation(Atom("P", [])))
em.to_unicode_str()                       # → 'P ⊕ ¬P'
fuzzy_is_valid(em, tnorm="lukasiewicz")   # → True

# Predicate atoms carry their argument terms (use the constant name as the arg key):
impl = LukImplication(Atom("P", []), Atom("Q", []))
fuzzy_evaluate(impl, {"P": 0.9, "Q": 0.4})  # → 0.5
```

## Graded (fuzzy) Kripke semantics

`semantics.fuzzy_kripke` generalises `semantics.kripke`'s two-valued
possible-worlds evaluator the way this page's `fuzzy_evaluate` generalises
classical FOL: `FuzzyKripkeModel` is a Kripke frame whose accessibility
relations carry an edge **weight** in `[0, 1]` (instead of a crisp edge set)
and whose valuation carries an atom **degree** in `[0, 1]` (instead of a
crisp atom set), and `satisfies_fuzzy_modal` returns the truth **degree** of
a modal formula at a world, not a bool. This is the direct propositional
generalisation Fitting gave many-valued modal logic (M. Fitting, "Many-valued
modal logics", *Fundamenta Informaticae* 15(3-4), 1991, 235-254) using the
residuated □ / t-norm ◇ pair studied by Hájek (*Metamathematics of Fuzzy
Logic*, Kluwer, 1998, ch. 8) and by Bou, Esteva, Godo & Rodríguez ("On the
minimum many-valued modal logic over a finite residuated lattice", *Journal
of Logic and Computation* 21(5), 2011, 739-790):

- `Box φ` (□) is `inf` over accessible worlds of `tnorm.impl(R(w, w'), deg(φ, w'))`
  — a RESIDUATED universal reading, "every accessible world forces φ at
  least as much as it is accessible";
- `Diamond φ` (◇) is `sup` over accessible worlds of `tnorm.conj(R(w, w'), deg(φ, w'))`
  — a t-norm existential reading;
- `Knows`/`Believes`/`Says`/`Wants` get the same residuated-universal reading
  as `Box`, over their own agent-keyed relation, exactly like the crisp
  evaluator (`semantics.kripke`'s module docstring documents the relation-name
  convention both evaluators share: `"alethic"`, `"K:"+agent`, `"B:"+agent`,
  `"Say:"+agent`, `"Want:"+agent`).

A formula for the graded evaluator has **Łukasiewicz** connective
nodes under the modal operators (never classical `And`/`Or`/`Not`/…, exactly
this page's own discipline above). `MSFLParser(fuzzy=True, modal=True)` reads
it (`fm.parse("□(P ⊗ Q) → □P")`), and the nodes can be built directly:

```python
from unicode_logic_kit.semantics import FuzzyKripkeModel, satisfies_fuzzy_modal
from unicode_logic_kit.semantics import LUKASIEWICZ, GODEL
from unicode_logic_kit import Atom, Box, Diamond

P = Atom("P", [])

# Two worlds; the only edge is R(w0, w1) = 0.6 (w0 has no self-loop, so
# R(w0, w0) = 0.0 by the missing-edge convention); val_w1(P) = 0.5.
m = FuzzyKripkeModel(
    worlds={"w0", "w1"},
    relations={"alethic": {("w0", "w1"): 0.6}},
    valuation={"w1": {"P": 0.5}},
    tnorm=LUKASIEWICZ,
)

round(satisfies_fuzzy_modal(Diamond(P), m, "w0"), 10)  # → 0.1  max(0, 0.6+0.5−1)
satisfies_fuzzy_modal(Box(P), m, "w0")                 # → 0.9  min(1, 1−0.6+0.5)
```

A missing edge or atom reads as weight/degree `0.0`, and an edge of weight
`0.0` contributes the NEUTRAL element to both aggregates (`tnorm.impl(0, y)
= 1`, `tnorm.conj(0, y) = 0`, for all three t-norms), so "no accessible
worlds" gives `Box = 1.0` / `Diamond = 0.0` exactly, matching
`semantics.kripke`'s crisp vacuous-truth convention. On edge weights and atom
degrees restricted to `{0.0, 1.0}`, `satisfies_fuzzy_modal` agrees exactly
with `semantics.kripke.satisfies_modal` on the structurally matching crisp
formula, for every t-norm — the collapse `tests/test_fuzzy_kripke.py`
checks over hundreds of random frames. An atom with arguments is keyed in
a world's valuation as it is for `fuzzy_evaluate`: by `atom_key(atom)`
(`"Likes(a, b)"`), or by the text of the atom as a formula
(`"Likes('a', 'b')"`), which is read as the same key.

The Gödel t-norm's negation is not involutive, so the residuated duality
`◇φ = ¬□¬φ` — which DOES hold exactly under Łukasiewicz — can fail under
Gödel:

```python
mg = FuzzyKripkeModel(
    worlds={"w0", "w1"},
    relations={"alethic": {("w0", "w1"): 0.5}},
    valuation={"w1": {"P": 0.5}},
    tnorm=GODEL,
)
satisfies_fuzzy_modal(Diamond(P), mg, "w0")  # → 0.5   min(0.5, 0.5)
```

**Scope.** The modal operators read are graded `Box`/`Diamond`/`Knows`/
`Believes`/`Says`/`Wants`, each by one step of aggregation, with no fixpoints.
Temporal closure, hybrid logic, public announcement logic, group-epistemic
operators (`EverybodyKnows`/`DistributedKnowledge`/`CommonKnowledge`), and
Standard-Deontic-style serial-frame reasoning are refused BY NAME rather
than silently approximated — a graded fixpoint or model update over a
continuous t-norm is an open research question in its own right. The parser
reads the whole modal family, so such a formula parses and is refused here:

```python
from unicode_logic_kit import Next

satisfies_fuzzy_modal(Next(P), m, "w0")
# raises NotImplementedError: satisfies_fuzzy_modal: Next (temporal) is not
# supported by the graded (fuzzy) Kripke semantics, which reads
# Box/Diamond/Knows/Believes/Says/Wants with single-step aggregation and no fixpoints; …
```

### Quantifiers over a constant domain

An individual quantifier ranges over the constant names of the model's
`domain` (a sorted one over `sort_universes[sort]`), exactly as
`fuzzy_evaluate` reads it: `∀` is the infimum and `∃` the supremum of the
instances. The domain is ONE set for every world, the setting of Hájek's fuzzy
modal predicate logics, so the Barcan formula and its converse have degree 1.

```python
fm = MSFLParser(fuzzy=True, modal=True)
m = FuzzyKripkeModel(
    worlds={"w0", "w1"},
    relations={"alethic": {("w0", "w1"): 0.5}},
    valuation={"w1": {"Tall(alice)": 0.25, "Tall(bob)": 0.75}},
    domain={"alice", "bob"},
)
satisfies_fuzzy_modal(fm.parse("□∀x Tall(x)"), m, "w0")   # → 0.75  0.5 → min(0.25, 0.75)
satisfies_fuzzy_modal(fm.parse("∃x ◇Tall(x)"), m, "w0")   # → 0.25  0.5 ⊗ 0.75
satisfies_fuzzy_modal(fm.parse("∀x □Tall(x) → □∀x Tall(x)"), m, "w0")   # → 1.0
```

A model without a domain has nothing for a quantifier to range over:

```python
satisfies_fuzzy_modal(fm.parse("∀x Tall(x)"), FuzzyKripkeModel({"w0"}), "w0")
# raises ValueError: satisfies_fuzzy_modal: the quantifier ∀x ranges over the domain,
# and no domain (a set of constant names) was given.
```

### Searching for a countermodel

`fuzzy_modal_search` looks for a model in which a formula has a degree below 1
at world 0. For each size `n = 1 .. max_worlds` every edge weight and atom
degree of a model with `n` worlds is an unknown real in `[0, 1]`, and Z3
decides whether some choice gives a degree below 1 (Łukasiewicz and Gödel,
whose connectives are piecewise linear; the product t-norm is refused). A model
that is found has its degree computed again by `satisfies_fuzzy_modal`.

The axiom K separates the frames. Over a fuzzy accessibility relation it fails
under Łukasiewicz: one world that sees itself with weight 1/2, `P = 1/2`,
`Q = 0` gives `□(P → Q) = 1`, `□P = 1`, `□Q = 1/2`. Over a crisp relation it
holds, and under Gödel it holds over every relation:

```python
from unicode_logic_kit import fuzzy_modal_search

k = fm.parse("□(P → Q) → (□P → □Q)")
found = fuzzy_modal_search(k)
found.worlds                                  # → 1
found.degree < 1                              # → True
satisfies_fuzzy_modal(k, found.model, 0) == found.degree      # → True

fuzzy_modal_search(k, crisp_frame=True).exhausted            # → True
fuzzy_modal_search(k, tnorm="godel").exhausted               # → True
fuzzy_modal_search(k, tnorm="godel").detail
# → 'no countermodel with at most 3 world(s); not a proof of validity, larger models are not searched'
```

`frame=` names the frame of `□` / `◇`, and `systems=` that of the agents
(`{"epistemic": "S5"}`, `{"doxastic": "KD45"}`). The conditions are read in
their graded form, with `⊗` the t-norm: reflexive `R(w, w) = 1`, symmetric
`R(w, v) = R(v, w)`, transitive `R(w, v) ⊗ R(v, u) ≤ R(w, u)`, serial "some `v`
with `R(w, v) = 1`", euclidean `R(w, v) ⊗ R(w, u) ≤ R(v, u)`. Under them the
axioms T, B, 4, D and 5 have degree 1; a frame with another condition (`"GL"`)
is refused by name.

```python
t = fm.parse("□P → P")
fuzzy_modal_search(t).model is not None                   # → True   a world that does not see itself
fuzzy_modal_search(t, frame="T").exhausted                # → True
fuzzy_modal_search(fm.parse("K_alice P → P"), systems={"epistemic": "S5"}).exhausted   # → True
```

The result says which of four things happened: `model` (a countermodel, with
its `degree`), `exhausted` (every size up to the bound was decided, none has a
countermodel), `timed_out` (Z3 did not decide a size in `timeout` milliseconds)
and `unsupported` (the formula is outside the fragment, with the message of the
refusal). `result.to_dict()` is JSON, and `fuzzy_kripke_model_to_dict` /
`fuzzy_kripke_model_from_dict` carry a model across it.

```python
fuzzy_modal_search(fm.parse("ⒼP")).unsupported
# → 'NotImplementedError: fuzzy_modal_search: Always (temporal) is not supported by the graded (fuzzy) Kripke semantics, …'
```

### No countermodel up to a bound is not validity

`exhausted=True` means that no model with at most `max_worlds` worlds refutes
the formula, and nothing more. Under the Gödel t-norm it cannot become a proof
by raising the bound. `□¬¬P → ¬¬□P` has degree 1 in every FINITE model: if
`¬¬□P = 0` then `□P = 0`, so some world is seen with a weight above `P = 0`
there, and then `□¬¬P = 0` too. Over infinitely many worlds `w_1, w_2, …`, each
seen with weight 1 and with `P = 1/n` at `w_n`, it has degree 0: every `¬¬P` is
1, so `□¬¬P = 1`, while `□P` is the infimum 0. The logic of `□` over
`[0, 1]`-valued Gödel Kripke models has no finite model property (X. Caicedo
and R. O. Rodríguez, "Standard Gödel modal logics", *Studia Logica* 94(2), 2010,
189-214).

```python
fuzzy_modal_search(fm.parse("□¬¬P → ¬¬□P"), tnorm="godel", max_worlds=4).exhausted   # → True
```

## Predicate quantifiers

`MSFLParser(fuzzy=True, second_order=True)` reads `∀P` / `∃P` over the
Łukasiewicz connectives. A predicate quantifier ranges over the **fuzzy**
interpretations of its predicate: `∀P φ` is the infimum of `φ` over every
assignment of a degree in `[0, 1]` to each ground atom of `P` that `φ` reads,
and `∃P φ` the supremum. That is an optimum over a real cube, not an
enumeration; it is computed exactly as linear real arithmetic (Z3), also where
it is approached and not reached.

```python
so = MSFLParser(fuzzy=True, second_order=True)

fuzzy_evaluate(so.parse("∀P (P ∨ ¬P)"), {})                  # → 0.5   inf of max(p, 1 − p)
fuzzy_evaluate(so.parse("∀P (P ⊕ ¬P)"), {})                  # → 1.0   min(1, p + 1 − p)
# Gödel: ¬p is 1 at p = 0 and 0 above, so max(p, ¬p) comes as close to 0 as one likes
fuzzy_evaluate(so.parse("∀P (P ∨ ¬P)"), {}, tnorm="godel")   # → 0.0

tall = {"Tall(alice)": 0.25, "Tall(bob)": 0.75}
people = {"alice", "bob"}
fuzzy_evaluate(so.parse("∀P ∀x (P(x) → Tall(x))"), tall, domain=people)   # → 0.25  P = 1 everywhere
```

The interpretations are fuzzy and not crisp, and the choice shows in
comprehension: `∃P ∀x (P(x) ↔ Tall(x))` has degree 1 because `P` may take the
degrees of `Tall`. Over crisp sets `P` it would be 1/2 for a `Tall` of degree
1/2.

```python
fuzzy_evaluate(so.parse("∃P ∀x (P(x) ↔ Tall(x))"), tall, domain=people)   # → 1.0
```

The deciders read the quantifier the same way. `∀P P` is the bottom degree and
`∃P P` the top one, so ex falso is a second-order validity:

```python
fuzzy_is_valid(so.parse("∀P (P ⊕ ¬P)"))                          # → True
fuzzy_is_valid(so.parse("∀P (P ∨ ¬P)"))                          # → False
fuzzy_is_valid(so.parse("∃P ∀x (P(x) ↔ Q(x))"), domain=people)   # → True
fuzzy_is_valid(so.parse("(∀P P) → Q"))                           # → True

# the supremum 1/2 of P ∧ ¬P is reached and not exceeded
fuzzy_is_satisfiable(so.parse("∃P (P ∧ ¬P)"), threshold=0.5)                # → True
fuzzy_is_satisfiable(so.parse("∃P (P ∧ ¬P)"), threshold=0.5, strict=True)   # → False
```

The product t-norm is not linear and is refused by name for a predicate
quantifier (`fuzzy_evaluate` keeps it for every other formula):

```python
fuzzy_evaluate(so.parse("∀P (P ∨ ¬P)"), {}, tnorm="product")
# raises NotImplementedError: evaluate: a predicate quantifier is an infimum or supremum
# over every fuzzy interpretation of its predicate, computed as linear real arithmetic;
# the product t-norm is not linear. Use tnorm='lukasiewicz' or tnorm='godel'.
```

### Two terms and one individual

An individual is named by a term here: a quantifier ranges over the constant
names of a domain, and two names are two individuals. A predicate quantifier can
say that two terms differ, `∃P (P(alice) ⊗ ¬P(bob))`. One valuation is one
model, and in it the two names are two individuals, so the evaluator gives the
formula degree 1. A decider answers for ALL models, including those in which
both names denote one individual, so it refuses the formula unless the names are
declared as individuals of the domain:

```python
leibniz = so.parse("∃P (P(alice) ⊗ ¬P(bob))")
fuzzy_evaluate(leibniz, {})                  # → 1.0
fuzzy_is_valid(leibniz, domain=people)       # → True
```

```python
fuzzy_is_valid(leibniz)
# raises NotImplementedError: z3_fuzzy: predicate quantifiers of the formula apply their
# bound predicates to the different terms alice and bob, and alice is not a name of the
# declared domain. Two terms may name one individual, …
```

### Predicate quantifiers at worlds

With `modal=True` a bound predicate is an intension, as in the two-valued
Kripke evaluator: it has a degree of its own at each world. The frame
conditions of correspondence theory then have a DEGREE. `∀P (□P → P)` at a world
has exactly the weight with which the world sees itself:

```python
som = MSFLParser(fuzzy=True, second_order=True, modal=True)
loop = FuzzyKripkeModel({"w"}, {"alethic": {("w", "w"): 0.25}})
satisfies_fuzzy_modal(som.parse("∀P (□P → P)"), loop, "w")        # → 0.25

fuzzy_modal_search(som.parse("∀P (□P → P)")).model is not None    # → True
fuzzy_modal_search(som.parse("∀P (□P → P)"), frame="T").exhausted # → True
```

## Third-order atoms

`MSFLParser(fuzzy=True, third_order=True)` reads a predicate or a lambda term in
argument position, `Pos(G)`, `Pos(λx. ¬G(x))`. Such an atom is read in one of two
ways.

Without more it is a **letter** of its own, looked up by its written form: the
property is taken by name. The evaluator, the graded Kripke evaluator and the
deciders all read it so. A formula the deciders report valid is therefore valid
whatever `Pos` is; a model they report may give `Pos(G)` and `Pos(H)` different
degrees although `G` and `H` agree everywhere, since nothing ties the two
letters.

```python
to = MSFLParser(fuzzy=True, third_order=True)
fuzzy_evaluate(to.parse("Pos(G)"), {"Pos(G)": 0.5})                       # → 0.5
fuzzy_is_valid(to.parse("(Pos(G) ⊗ (Pos(G) → Pos(H))) → Pos(H)"))         # → True
```

With an entry in `functionals` the evaluator **computes** it: the function
receives each property argument as a function from constant names to degrees
(`G` as the degrees of the atoms `G(…)`, `λx. φ` as the degree of `φ` at each
name), and each individual argument as the name of its term.

```python
g = {"G(alice)": 0.25, "G(bob)": 0.75}
every = {"Pos": lambda prop: min(prop(d) for d in people)}

fuzzy_evaluate(to.parse("Pos(G)"), g, functionals=every)                  # → 0.25
fuzzy_evaluate(to.parse("Pos(λx. ¬G(x))"), g, functionals=every)          # → 0.25  complement: 0.75, 0.25
fuzzy_evaluate(to.parse("Pos(λx. G(x) ⊕ ¬G(x))"), g, functionals=every)   # → 1.0
```

A predicate quantifier that binds a predicate standing in argument position is
refused by name: the quantifier ranges over the degrees of the ground atoms of
its predicate, and an atom that takes the predicate itself as an argument is
none of them.

```python
fuzzy_evaluate(to.parse("∀G (Pos(G) → ∃x G(x))"), {}, domain=people)
# raises NotImplementedError: evaluate: the predicate G is bound by a predicate quantifier
# and stands in argument position in 'Pos(G)' (third order). …
```

## End-to-end: a small fuzzy rule base

Parse → evaluate → solve, in one scenario. A diagnostic rule says that strong *fever* together with a *cough* implies elevated *risk*; we both score it under a fixed reading and ask whether the antecedent can reach a target degree.

```python
from unicode_logic_kit import MSFLParser, fuzzy_evaluate, fuzzy_is_satisfiable, fuzzy_get_model

fl = MSFLParser(fuzzy=True)
rule = fl.parse("(Fever ⊗ Cough) → Risk")
rule.to_unicode_str()             # → 'Fever ⊗ Cough → Risk'

# Score the rule under one patient's degrees (Łukasiewicz default):
reading = {"Fever": 0.9, "Cough": 0.8, "Risk": 0.4}
round(fuzzy_evaluate(rule, reading), 10)   # → 0.7  antecedent = max(0, 1.7−1) = 0.7; min(1, 1−0.7+0.4)

# Can the antecedent Fever ⊗ Cough alone reach 0.7?
fuzzy_is_satisfiable(fl.parse("Fever ⊗ Cough"), threshold=0.7)  # → True

# Recover a witness valuation that attains it:
m = fuzzy_get_model(fl.parse("Fever ⊗ Cough"), threshold=0.7)
sorted(m)        # → ['Cough', 'Fever', 'degree']
m["degree"]      # → 0.7
```
