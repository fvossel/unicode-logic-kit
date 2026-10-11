# Parsing and the AST

`MSFLParser` turns a Unicode formula string into a typed AST of Python dataclasses. One parser class covers classical first-, second- and third-order logic, each with or without sorts and with or without the modal family (modal/temporal/epistemic/deontic/hybrid/counterfactual/PAL), the two Łukasiewicz modes (FL and many-sorted MSFL), dependence/IF logic, intuitionistic linear logic, and the Lambek calculus — each selected by constructor flags.

## Parser modes

A classical mode is three independent choices: the **order** (first by default, `second_order=True`, `third_order=True`), the **modal family** (`modal=True`), and **sorts** on the individual binders and constants (`many_sorted=True`). Every one of the twelve combinations is a mode. `fuzzy=True` gives the Łukasiewicz connectives, with and without sorts; `dependence`, `linear` and `lambek` are standalone and combine with nothing.

```python
from unicode_logic_kit import MSFLParser

MSFLParser(many_sorted=False, fuzzy=False)   # FOL   (default)
MSFLParser(many_sorted=True,  fuzzy=False)   # MSFOL
MSFLParser(many_sorted=True,  fuzzy=True)    # MSFL
MSFLParser(many_sorted=False, fuzzy=True)    # FL
MSFLParser(modal=True)                       # modal / temporal / epistemic / deontic / hybrid / □→ / [φ!]ψ
MSFLParser(second_order=True)                # second-order (∀P / ∃P)
MSFLParser(third_order=True)                 # third-order (a predicate as an argument: Pos(G))
MSFLParser(second_order=True, modal=True)    # second-order modal: ∀P (□P → P)
MSFLParser(third_order=True, modal=True, many_sorted=True)   # all three classical choices at once
MSFLParser(dependence=True)                  # dependence/IF logic (=(x,y), ∃x/{y})
MSFLParser(linear=True)                      # intuitionistic linear logic (⊗ ⊸ & ⊕ ! 𝟙 ⊤ 𝟘)
MSFLParser(lambek=True)                      # Lambek calculus (• \ /)
```

| order | plain | `many_sorted=True` | `modal=True` | `modal=True, many_sorted=True` |
|---|---|---|---|---|
| first | FOL | MSFOL | modal | sorted modal |
| `second_order=True` | second-order | sorted second-order | second-order modal | sorted second-order modal |
| `third_order=True` | third-order | sorted third-order | third-order modal | sorted third-order modal |

A mode reads a formula of a mode it contains as the same formula: a modal formula is also a second-order modal one, and a second-order modal formula is also a third-order modal one. Two things do not carry over. The sort discipline: a sorted mode refuses an unsorted binder, and an unsorted mode has no sort annotation. And the typing of the third order, which reads a predicate name over the whole formula: two binders of one name at two arities, `(∀P P(a)) ∧ (∃P P(a, b))`, are two variables at second order and a conflict at third (see {doc}`third-order`).

| `many_sorted` | `fuzzy` | Mode | Quantifiers | Constants | Connectives |
|---|---|---|---|---|---|
| `False` | `False` | **FOL** | unsorted `∀x` | unsorted | classical ∧ ∨ ⊕ ¬ → ↔ |
| `True` | `False` | **MSFOL** | sorted `∀x:Sort` | sorted `alice:Sort` | classical ∧ ∨ ⊕ ¬ → ↔ |
| `True` | `True` | **MSFL** | sorted `∀x:Sort` | sorted `alice:Sort` | weak ∧ ∨, strong ⊗ ⊕, Łuk ¬ → ↔ |
| `False` | `True` | **FL** | unsorted `∀x` | unsorted | weak ∧ ∨, strong ⊗ ⊕, Łuk ¬ → ↔ |

The modal and higher-order modes are FOL plus their own operators, over unsorted quantifiers/constants by default or SORTED ones with `many_sorted=True`; the remaining three are standalone fragments with their own connective sets:

- **modal** (`modal=True`, optionally `many_sorted=True`) — adds `□ ◇` (alethic), `K_a B_a Say_a Want_a` (epistemic/doxastic/assertive/bouletic), `Ⓖ Ⓕ Ⓝ Ⓤ ⒣ ⒫ ⒴ ⒮` (temporal, future and past), `Ⓞ Ⓟ` (deontic), nominals and `@i` (hybrid), the counterfactuals `□→ ◇→`, and the public announcements `[φ!]ψ / ⟨φ!⟩ψ`. The agent of `K_a`/`B_a` is a first-class term, so a bound `K_x` quantifies over agents (sorted or not). With `many_sorted=True`, every `∀x`/`∃x` — including one nested under a modal operator, e.g. `□∀x:Human (Mortal(x))` — needs a `:Sort` annotation, exactly as in plain MSFOL; see {doc}`modal`'s "Many-sorted modal logic" section for the semantics (a sort's guard is world-relative, not rigid, while a sorted constant is a rigid designator whose membership in its sort holds at every world; non-emptiness and that membership are assumed by `qml_is_valid`/the HOL exporters, not by the bare Kripke evaluator, which reads the model it is given).
- **second-order** (`second_order=True`, optionally `modal=True` and `many_sorted=True`) — adds `∀P / ∃P` over predicate variables (arity inferred from use). The predicate quantifier itself stays unsorted; `many_sorted=True` sorts only the individual `∀x`/`∃x` binders and bare constants. With `modal=True` the quantifier stands next to the modal family, `∀P (□P → P)`; see {doc}`second-order`'s "Second-order modal logic" section for what a bound predicate ranges over there.
- **third-order** (`third_order=True`, optionally `modal=True` and `many_sorted=True`) — second-order syntax plus a predicate or a λ-abstraction in ARGUMENT position, `Pos(G)`, `Pos(λx. ¬G(x))`. It contains second-order syntax, so it is not asked for together with `second_order`. See {doc}`third-order`.
- **dependence** (`dependence=True`) — the team-semantic fragment `¬ ∧ ∨ ∀ ∃` with dependence atoms `=(x, y)` and slashed existentials `∃x/{y}`.
- **linear** (`linear=True`) — intuitionistic linear logic `⊗ ⊸ & ⊕ !` with the units `𝟙 ⊤ 𝟘`.
- **lambek** (`lambek=True`) — the Lambek calculus `• \ /` over atomic categories.

`fuzzy=True` combines with the same three choices. Next to each of the twelve classical modes stands a fuzzy one, with the Łukasiewicz connectives in place of the two-valued ones; FL and MSFL are the two of the first order without the modal family:

| order | `fuzzy=True` | + `many_sorted=True` | + `modal=True` | + `modal=True, many_sorted=True` |
|---|---|---|---|---|
| first | FL | MSFL | fuzzy modal | sorted fuzzy modal |
| `second_order=True` | fuzzy second-order | sorted fuzzy second-order | fuzzy second-order modal | sorted fuzzy second-order modal |
| `third_order=True` | fuzzy third-order | sorted fuzzy third-order | fuzzy third-order modal | sorted fuzzy third-order modal |

A fuzzy mode reads a formula over `¬ ∧ ∨ → ↔` as the classical mode of the same choices reads it, with the fuzzy node at each connective (`WeakConjunction` for `∧`, `LukImplication` for `→`, …). `⊕` is the strong disjunction there, not exclusive or, and `⊗` the strong conjunction. The forms whose reading is two-valued are in no fuzzy mode: the counting quantifier `∃≥n`, `but`, the measure term `μ(…)` and the cardinality term `|{x : φ}|`. {doc}`fuzzy` says what evaluates and decides these formulas.

The constructor rejects an unsupported combination with a clear `ValueError`: `third_order` already contains second-order syntax, and a standalone logic takes no other flag.

```python
from unicode_logic_kit import MSFLParser

for kwargs in [dict(third_order=True, second_order=True),
               dict(linear=True, fuzzy=True)]:
    try:
        MSFLParser(**kwargs)            # raises
    except ValueError as e:
        print(str(e)[:46])
# → third_order=True cannot be combined with secon
# → linear=True cannot be combined with any other 

# The order, modal, many_sorted and fuzzy combine freely:
MSFLParser(modal=True, many_sorted=True).parse("□∀x:Human (Mortal(x))")
MSFLParser(second_order=True, many_sorted=True).parse("∀P (∀x:Human P(x) → ∃x:Human P(x))")
MSFLParser(second_order=True, modal=True).parse("∀P (□P → P)")
MSFLParser(third_order=True, many_sorted=True).parse("∀x:Human ∃P (Pos(P) ∧ P(x))")
MSFLParser(third_order=True, modal=True, many_sorted=True).parse("∀P (Pos(P) → □∀x:Being (P(x) → Pos(P)))")
MSFLParser(fuzzy=True, modal=True).parse("□(P ⊗ Q) → □P")
MSFLParser(fuzzy=True, second_order=True).parse("∀P (P ⊕ ¬P)")
MSFLParser(fuzzy=True, third_order=True, modal=True, many_sorted=True).parse("∀x:Being (Pos(G) → □G(x))")
```

## Unicode surface syntax

Formulas are written with natural symbols — `∀ ∃ ∧ ∨ ¬ → ↔ ⊕ ⊗ = ≠ ≤ ≥` — with no ASCII fallbacks required. An identifier's own first character decides whether it is predicate-valued or term-valued: an uppercase-initial identifier is a predicate, applied with parentheses; anything else is term-valued, and the term-level identifier rules below decide whether a bare token is a variable or a constant.

```python
parser = MSFLParser()
parser.parse("∀x (Human(x) → Mortal(x))")
# → Quantifier(type='∀', variable=Variable(name='x'),
#              formula=Implies(left=Atom(predicate='Human', args=(Variable(name='x'),)),
#                              right=Atom(predicate='Mortal', args=(Variable(name='x'),))))
```

### The three term-valued identifier classes

A bare term-valued token resolves to one of three terminal classes — and therefore one of three node types — purely by its spelling:

- **`VARIABLE`** — a single term-valued letter, optionally followed by digits (`x`, `y`, `x2`). It becomes a `Variable`.
- **`NAME`** — a multi-character term-valued identifier with a non-leading letter (`alice`, `socrates`). It becomes a `Constant` (and, when applied with parentheses, the head of a `Function`).
- **`CONSTANT`** — the explicit `c_`-prefix form (`c_7`, `c_alice`). It becomes a `Constant` too, and the mark stays part of the name: `c_alice` is the constant named `c_alice`, not the one named `alice`.

```python
parser = MSFLParser()

parser.parse("P(x)")          # → Atom(predicate='P', args=(Variable(name='x'),))
parser.parse("P(x2)")         # → Atom(predicate='P', args=(Variable(name='x2'),))
parser.parse("P(alice)")      # → Atom(predicate='P', args=(Constant(name='alice'),))
parser.parse("P(c_7)")        # → Atom(predicate='P', args=(Constant(name='c_7'),))
parser.parse("P(c_alice)")    # → Atom(predicate='P', args=(Constant(name='c_alice'),))
```

A fourth spelling, a **quoted constant**, writes a constant of any name, including the names no bare token can spell: a single letter (`'a'`), a variable-shaped name (`'k2'`), an upper-case name (`'Alice'`), a name with a hyphen or a space (`'G-910'`, `'John Doe'`). The text between the single quotes is the name, exactly, and the printer writes a constant in quotes whenever its bare word would read as something else, so printed text reads back. See "Quoted constants" in the {doc}`syntax-reference` for the escapes, the sorted form and the limits.

```python
parser.parse("P('a', x)")     # → Atom(predicate='P', args=(Constant(name='a'), Variable(name='x')))
parser.parse("P('Alice')")    # → Atom(predicate='P', args=(Constant(name='Alice'),))
```

A single term-valued letter standing alone is a *variable*, but followed by an argument list it is a function symbol, like a multi-character `NAME`: `father(x)` and `f(x)` are both a `Function`:

```python
parser = MSFLParser()
parser.parse("father(x) = bob")
# → Atom(predicate='=',
#        args=(Function(name='father', args=(Variable(name='x'),)),
#              Constant(name='bob')))

parser.parse("P(f(x))")
# → Atom(predicate='P', args=(Function(name='f', args=(Variable(name='x'),)),))
```

### Non-ASCII letters, underscores, and digit-leading names

`PREDICATE`/`CONSTANT`/`NAME`/`VARIABLE` are not ASCII-only: any Unicode
letter is accepted (Greek is the one exception — see below), a `NAME` may
contain underscores anywhere past its first character, and a `NAME` may
also start with one or more digits, as long as a letter follows. Which
class a token belongs to is still decided the same way as the plain-ASCII
case above — by its first character, never by a special case for "this is
non-ASCII" — so the rule to keep in mind is just: **`str.isupper()` on the
first character means predicate, anything else means term-valued.**

```python
parser = MSFLParser()

parser.parse("LostTo(x, świątek)")
# → Atom(predicate='LostTo', args=(Variable(name='x'), Constant(name='świątek')))
parser.parse("Sibling(dani_Shapiro, family_History)")
# → Atom(predicate='Sibling', args=(Constant(name='dani_Shapiro'), Constant(name='family_History')))
parser.parse("Hosted(beijing, 2008SummerOlympics)")
# → Atom(predicate='Hosted', args=(Constant(name='beijing'), Constant(name='2008SummerOlympics')))
```

A script with no upper/lower distinction — Chinese, Arabic, Hebrew,
Devanagari, and most others — never satisfies `str.isupper()`, so a bare
identifier from such a script is always term-valued and can never head an
atom by itself:

```python
parser.parse("P(中文)")   # → Atom(predicate='P', args=(Constant(name='中文'),))
parser.parse("中文(x)")   # raises ParsingError — 中文(x) parses as a term (a Function), and a
                          #   bare term is not a complete formula; a caseless-script
                          #   identifier can never head an atom on its own
```

Seven characters are excluded even though Unicode calls them uppercase letters: `Ⓒ Ⓕ Ⓖ Ⓝ Ⓞ Ⓟ Ⓤ`. Each is a registered operator symbol — Contrast, Eventually, Always, Next, Obligatory, Permitted, Until — and letting them open an identifier gave `ⓄP` two readings at once. The rule is the same one `λ` and `μ` follow: a glyph that is an operator anywhere is not an identifier character anywhere. Only these seven; `Ⓐ`, the other circled capitals and the Roman numerals stay writable.

A digit-leading identifier (`2008SummerOlympics`) is a `NAME`, never a
number and never a predicate: `NUMBER` itself is unchanged (`2008` and
`2.5` still lex as plain numbers), and nothing lets an atom's head start
with a digit. Underscore is a continuation character only — never legal as
the first character of any identifier (`_foo` is a `NamingError`) — and it
is legal inside `NAME`, `PREDICATE` and the sort annotation, so
`Family_History(x)` is an atom and `a_b:Has_bond` a sorted constant; a
`VARIABLE` and the tail of a `c_` constant take no underscore.

Greek letters are excluded from every one of these widened classes,
because they are already spoken for: `λ` opens a lambda term (see "Lambda
syntax" below), `μ` opens a measure term (see "Measure term
`μ(entity, dimension)`" below), and the plain lowercase Greek run
(`αβγδεζηθικνξοπρστυφχψω`) is `CONSTANT`'s other alternative alongside
`c_...` — widening the letter classes without this exclusion would have
turned those operators into ordinary identifier characters instead.

```python
parser.parse("λx. P(x)")   # → still a Lambda, not P applied to a NAME "λx"
parser.parse("P(α)")       # → Atom(predicate='P', args=(Constant(name='α'),)) — via the Greek CONSTANT form
```

This widening is purely additive: every formula this kit's grammar
accepted before still parses to the structurally identical AST (see
`CHANGELOG.md`'s entry for the change, and
`tests/test_identifier_widening.py`).

The two shapes only this widening lets through — a non-ASCII predicate or
function name, and a digit-leading term — are not automatically legal
wherever a parsed formula is *exported* to next: TPTP, Prover9, SMT-LIB2,
THF, Isabelle, and MiniZinc are each ASCII-only formats with their own
legality rules that a raw `świątek` or `2008SummerOlympics` can violate.
Every one of those export routes now sanitises for its own target format
before rendering — an injective, whole-problem-consistent ASCII rewrite,
with the original names translated back into anything a prover's answer
echoes — see {doc}`transforms` for the mechanism and examples, and
`CHANGELOG.md`'s entry for the full account. This is a *different*
mechanism from `fol.sanitize`: that module rewrites a name to a token
THIS parser's own grammar can re-parse (the case an import from outside
the kit runs into — an IRI-derived TPTP predicate name, say — not a name
this parser already accepts), and stays untouched by the export-format
fix.

### Comparisons and arithmetic

The six infix comparison glyphs `= ≠ < > ≤ ≥` build a binary `Atom` whose predicate is the glyph itself; the four arithmetic operators `+ - * /` build a `Function` whose name is the glyph, with the usual precedence (`*`/`/` bind tighter than `+`/`-`):

```python
parser = MSFLParser()

parser.parse("x ≤ y")
# → Atom(predicate='≤', args=(Variable(name='x'), Variable(name='y')))

parser.parse("x ≠ y")
# → Atom(predicate='≠', args=(Variable(name='x'), Variable(name='y')))

parser.parse("x + y * 2 < z")
# → Atom(predicate='<',
#        args=(Function(name='+',
#                       args=(Variable(name='x'),
#                             Function(name='*', args=(Variable(name='y'), Number(value=2))))),
#              Variable(name='z')))
```

A numeral has one spelling per value: a float with a whole value is stored as the integer it equals, so `1`, `1.0`, `01` and `1.00` all parse to `Number(value=1)` and `-0.0` to `Number(value=0)`, while `2.5` stays `Number(value=2.5)`. Two numerals are equal exactly when their values are, and they print alike in every syntax.

A decimal text is read exactly or refused, in every reader of the kit (this one, LaTeX, TPTP, QMLTP, Prolog, Prover9, Twee, an SMT-LIB numeral, the `real(...)` of an ACE DRS and an OWL `xsd:decimal`). A text with no point is the integer. A text with a point and an all-zero fraction is the integer of its whole part: `100000000000000000000000.0` is `10**23`, where the nearest float would be `99999999999999991611392`. Any other decimal is the float it spells when it has at most 15 significant digits (the sign, the leading zeros and the trailing zeros of the fraction do not count, so `0.1` and `0.10` are one numeral), and is refused by name when it has more, because two different decimals of 16 or more digits can be one float (`0.30000000000000004` and `0.30000000000000005` are) and a numeral is identified by its value. A decimal nearer to zero than `2.2250738585072014e-308` is refused too. The text the kit prints for a float of 16 or 17 digits is therefore refused when read back, except as the name of a Z3 or SMT-LIB symbol, which is read by its exact text (see {doc}`transforms`). `1e3` is no numeral in any reader: this one and the LaTeX reader read it as a constant of that name, and the TPTP, QMLTP, Prolog, Prover9, Twee and OWL readers refuse it.

```python
parser.parse("P(1.0)") == parser.parse("P(01)") == parser.parse("P(1)")   # → True
parser.parse("P(-0.0)")    # → Atom(predicate='P', args=(Number(value=0),))
parser.parse("P(2.5)")     # → Atom(predicate='P', args=(Number(value=2.5),))
parser.parse("P(1.00)").to_tptp()   # → 'p(1)'
parser.parse("P(0.10)") == parser.parse("P(0.1)")   # → True
parser.parse("P(100000000000000000000000.0)")   # → Atom(predicate='P', args=(Number(value=100000000000000000000000),))
parser.parse("P(1e3)")     # → Atom(predicate='P', args=(Constant(name='1e3'),))

from unicode_logic_kit import ParsingError
try:
    parser.parse("P(0.30000000000000004)")    # raises
except ParsingError as e:
    print(str(e)[:55])
# → SYNTAX_ERROR: the numeral 0.30000000000000004 has 17 si
```

### Tight quantifier scope

A quantifier binds only the immediately following prefix-level formula, not the rest of the line: `∀x P(x) ∧ Q(x)` is `(∀x P(x)) ∧ Q(x)`, with the second `Q(x)` *outside* the quantifier. Add parentheses to extend the scope.

```python
parser = MSFLParser()

parser.parse("∀x P(x) ∧ Q(x)")
# → And(left=Quantifier(type='∀', variable=Variable(name='x'),
#                       formula=Atom(predicate='P', args=(Variable(name='x'),))),
#       right=Atom(predicate='Q', args=(Variable(name='x'),)))

parser.parse("∀x (P(x) ∧ Q(x))")
# → Quantifier(type='∀', variable=Variable(name='x'),
#              formula=And(left=Atom(predicate='P', args=(Variable(name='x'),)),
#                          right=Atom(predicate='Q', args=(Variable(name='x'),))))
```

Both parentheses `( … )` and square brackets `[ … ]` group identically:

```python
parser = MSFLParser()
parser.parse("[P(x) ∧ Q(x)]") == parser.parse("(P(x) ∧ Q(x))")   # → True
```

### MSFOL — sorted quantifiers and constants, and `to_fol` lowering

In many-sorted mode quantifiers and ground constants must carry a sort annotation. The colon may be written with or without a space before it.

```python
parser = MSFLParser(many_sorted=True)

parser.parse("∀x:Human (Mortal(x) ∧ ¬Immortal(x))")
# → SortedQuantifier(type='∀', variable=Variable(name='x'), sort='Human',
#                    formula=And(left=Atom(predicate='Mortal', args=(Variable(name='x'),)),
#                                right=Not(formula=Atom(predicate='Immortal', args=(Variable(name='x'),)))))

parser.parse("P(alice:Human)") == parser.parse("P(alice :Human)")  # both spacings parse → True
parser.parse("P(alice:Human)")
# → Atom(predicate='P', args=(SortedConstant(name='alice', sort='Human'),))
```

`to_fol` *relativises* a sorted formula to plain FOL: a `∀x:S` becomes a guarded `∀x (S(x) → …)`, a `∃x:S` becomes `∃x (S(x) ∧ …)`, and a `SortedConstant` drops to a plain `Constant`.

```python
from unicode_logic_kit import MSFLParser, to_fol

m = MSFLParser(many_sorted=True)

to_fol(m.parse("∀x:Human Mortal(x)"))
# → Quantifier(type='∀', variable=Variable(name='x'),
#              formula=Implies(left=Atom(predicate='Human', args=(Variable(name='x'),)),
#                              right=Atom(predicate='Mortal', args=(Variable(name='x'),))))

to_fol(m.parse("∃x:Human Happy(x)"))
# → Quantifier(type='∃', variable=Variable(name='x'),
#              formula=And(left=Atom(predicate='Human', args=(Variable(name='x'),)),
#                          right=Atom(predicate='Happy', args=(Variable(name='x'),))))

to_fol(m.parse("Mortal(socrates:Human)"))
# → Atom(predicate='Mortal', args=(Constant(name='socrates'),))
```

Passing `include_sort_facts=True` conjoins the collected sort-membership atoms (e.g. `Human(socrates)`) onto the result:

```python
to_fol(m.parse("Mortal(socrates:Human)"), include_sort_facts=True)
# → And(left=Atom(predicate='Human', args=(Constant(name='socrates'),)),
#       right=Atom(predicate='Mortal', args=(Constant(name='socrates'),)))
```

The conjunct form is right for a formula that is asserted and wrong for a goal: `Human(socrates) ∧ φ` cannot be proved from nothing, even when φ is a tautology. For a goal the facts go in as premises. `sort_axioms(...)` returns the membership atoms together with one non-emptiness statement per sort (`to_fol` itself never states non-emptiness):

```python
from unicode_logic_kit import api, sort_axioms

phi = m.parse("Mortal(socrates:Human) → Mortal(socrates:Human)")
api.prove(to_fol(phi, include_sort_facts=True)).status   # → 'refuted'
api.prove(to_fol(phi), list(sort_axioms(phi))).status    # → 'proved'
```

The higher-order exporters `to_thf_msfol`, `to_isabelle_msfol` and `to_lean_msfol` do the same for a conjecture: membership and non-emptiness are axioms, lemma premises or hypotheses outside the goal. The conjunct form remains only for an asserted formula (`conjecture=False` in the THF and Lean exporters).

### MSFL / FL — Łukasiewicz operators

In the fuzzy modes `∧`/`∨` are the weak (min/max) connectives, `⊗`/`⊕` the strong (t-norm/t-conorm) connectives, and `¬`/`→`/`↔` their Łukasiewicz counterparts. Each glyph maps to a distinct node class — the same `∧` glyph is `And` in FOL but `WeakConjunction` here.

```python
parser = MSFLParser(many_sorted=True, fuzzy=True)   # MSFL

type(parser.parse("P(x) ∧ Q(x)")).__name__   # → 'WeakConjunction'    (min)
type(parser.parse("P(x) ∨ Q(x)")).__name__   # → 'WeakDisjunction'    (max)
type(parser.parse("P(x) ⊗ Q(x)")).__name__   # → 'StrongConjunction'  (t-norm: max{0, x+y−1})
type(parser.parse("P(x) ⊕ Q(x)")).__name__   # → 'StrongDisjunction'  (t-conorm: min{1, x+y})
type(parser.parse("¬P(x)")).__name__          # → 'LukNegation'        (1−x)
type(parser.parse("P(x) → Q(x)")).__name__   # → 'LukImplication'     (min{1, 1−x+y})
type(parser.parse("P(x) ↔ Q(x)")).__name__   # → 'LukEquivalence'
type(parser.parse("∀x:Human P(x)")).__name__  # → 'SortedQuantifier'
```

`to_msfol()` lowers every Łukasiewicz node to its classical counterpart (this is the first half of what `to_fol` does), leaving the structure otherwise unchanged:

```python
parser = MSFLParser(many_sorted=True, fuzzy=True)
luk = parser.parse("¬P(x) → Q(x)")
type(luk).__name__               # → 'LukImplication'
type(luk.to_msfol()).__name__    # → 'Implies'
# → Implies(left=Not(formula=Atom(predicate='P', args=(Variable(name='x'),))),
#           right=Atom(predicate='Q', args=(Variable(name='x'),)))
```

FL is the same connectives with unsorted quantifiers and plain constants:

```python
parser = MSFLParser(fuzzy=True)        # FL
parser.parse("∀x P(x)")                # → unsorted Quantifier (no sort annotation)
type(parser.parse("P(x) ⊗ Q(x)")).__name__   # → 'StrongConjunction'
parser.parse("P(alice)")               # → Atom(predicate='P', args=(Constant(name='alice'),))
```

### Modal, temporal, epistemic, deontic

Modal mode is classical unsorted FOL plus the prefix operators `□ ◇` (alethic), `Ⓖ Ⓕ Ⓝ` (temporal future), `Ⓞ Ⓟ` (deontic), the agent operators `K_a B_a`, and the infix temporal `Ⓤ` (until).

```python
modal = MSFLParser(modal=True)

modal.parse("□P → ◇Q")
# → Implies(left=Box(formula=Atom(predicate='P', args=())),
#           right=Diamond(formula=Atom(predicate='Q', args=())))

type(modal.parse("Ⓖ P(a)")).__name__       # → 'Always'
type(modal.parse("Ⓞ P(a)")).__name__       # → 'Obligatory'
type(modal.parse("P(a) Ⓤ Q(a)")).__name__  # → 'Until'
```

The agent of `K_a`/`B_a` is a **term**, not a bare string. A *free* agent denotes a named individual (a `Constant`), while an agent bound by an enclosing quantifier stays a `Variable` — so `K_x` genuinely quantifies over agents:

```python
modal = MSFLParser(modal=True)

modal.parse("K_a P(a)")
# → Knows(agent=Constant(name='a'), formula=Atom(predicate='P', args=(Variable(name='a'),)))

modal.parse("∀x (Student(x) → K_x Smart(x))")
# → Quantifier(type='∀', variable=Variable(name='x'),
#              formula=Implies(left=Atom(predicate='Student', args=(Variable(name='x'),)),
#                              right=Knows(agent=Variable(name='x'),
#                                          formula=Atom(predicate='Smart', args=(Variable(name='x'),)))))
```

(The free `K_a P(a)` resolves the agent `a` to a `Constant` even though the same letter `a` *inside* `P(a)` stays a `Variable` — agent position and term position are resolved independently.)

### Second-order — arity inference and `ConflictingArityError`

Second-order mode adds `∀P / ∃P` over a predicate variable. The bound predicate's arity is **inferred** from its applications in the body and recorded on the node (it is not part of the surface syntax):

```python
so = MSFLParser(second_order=True)

so.parse("∀P (P(a) ∨ ¬P(a))")
# → SecondOrderQuantifier(type='∀', predicate='P', arity=1, formula=Or(...))

so.parse("∃R ∀x R(x,x)")
# → SecondOrderQuantifier(type='∃', predicate='R', arity=2, formula=Quantifier(...))

so.parse("∀P (P ∨ ¬P)")
# → SecondOrderQuantifier(type='∀', predicate='P', arity=0, formula=Or(...))   (never applied ⇒ arity 0)
```

If the same bound predicate is applied at two different arities the inference fails with `ConflictingArityError` (a subclass of `ParsingError`, so a caller catching the parser's error type also catches this):

```python
from unicode_logic_kit import MSFLParser, ParsingError
from unicode_logic_kit.fol.msflparser import ConflictingArityError

so = MSFLParser(second_order=True)
try:
    so.parse("∀P (P(a) ∧ P(a,b))")    # raises
except ConflictingArityError as e:
    print(str(e)[:78])
# → SYNTAX_ERROR: Second-order predicate variable 'P' is applied at conflicting

issubclass(ConflictingArityError, ParsingError)   # → True
```

## Natural-language constructs

Classical FOL mode (`many_sorted=False, fuzzy=False`) carries four extra surface forms used by natural-language → logic front-ends. The modal, second-order and third-order modes and their combinations read them too (with `many_sorted=True` they read `Ⓒ` and the sort-annotated counting quantifier, but not `μ` or the cardinality term), and many-sorted FOL reads `Ⓒ` and `μ` as they are, with sort-annotated counting and cardinality forms (see {doc}`natural-language`); the fuzzy modes have none of them.

### Counting quantifier `∃≥n / ∃≤n / ∃=n`

The counting quantifier binds a variable and carries its bound `n` **symbolically** (a `Number`, not expanded), so an arbitrarily large `n` round-trips exactly:

```python
parser = MSFLParser()

parser.parse("∃≥2 x P(x)")
# → Count(op='ge', n=Number(value=2), variable=Variable(name='x'),
#         formula=Atom(predicate='P', args=(Variable(name='x'),)))

parser.parse("∃≤3 x P(x)")    # → Count(op='le', n=Number(value=3), …)
parser.parse("∃=1 x P(x)")    # → Count(op='eq', n=Number(value=1), …)
```

The bound is a whole number written without a sign or a decimal point (`∃≥02` reads as 2). A sign or a fraction is a `CountBoundError`, which is a `ParsingError`: `∃=-0 x P(x)` and `∃≥2.5 x P(x)` raise it, and `∃≥+3 x P(x)` never gets that far, because the lexer refuses the `+` as a `NamingError`.

It is first-order expressible; the first-order exporters lower it to the distinct-witnesses encoding on demand (the AST keeps `n` symbolic):

```python
parser = MSFLParser()
print(parser.parse("∃≥2 x P(x)").to_tptp())
# → (?[X0]: (?[X1]: ((p(X0) & p(X1)) & (X0 != X1))))
```

### Measure term `μ(entity, dimension)`

A degree/measure term for bare comparatives (`taller`, `more water`) — an uninterpreted binary function on export. Both children are terms; the result is typically compared with `>`/`<`:

```python
parser = MSFLParser()
parser.parse("μ(x, height) > μ(y, height)")
# → Atom(predicate='>',
#        args=(Measure(entity=Variable(name='x'), dimension=Constant(name='height')),
#              Measure(entity=Variable(name='y'), dimension=Constant(name='height'))))
```

### Set-cardinality term `|{v : φ}|`

A set-cardinality term for faithful counting comparisons (`more votes than`). It *binds* its variable over the matrix. Set cardinality is genuinely second-order, so it has no first-order export:

```python
parser = MSFLParser()
parser.parse("|{v : Votes(x, v)}| > |{v : Votes(y, v)}|")
# → Atom(predicate='>',
#        args=(Cardinality(variable=Variable(name='v'),
#                          formula=Atom(predicate='Votes', args=(Variable(name='x'), Variable(name='v')))),
#              Cardinality(variable=Variable(name='v'),
#                          formula=Atom(predicate='Votes', args=(Variable(name='y'), Variable(name='v'))))))
```

Exporting a `Cardinality` to a first-order back-end raises — it is not first-order definable:

```python
parser = MSFLParser()
card = parser.parse("|{v : P(v)}| > |{v : Q(v)}|")
try:
    card.to_tptp()    # raises
except NotImplementedError as e:
    print(str(e)[:55])
# → Cardinality terms (|{v : φ}|) denote set cardinalit
```

### Concessive connective `Ⓒ`

A concessive (contrastive) connective — *whereas / although / but*. It is truth-functionally identical to `∧`, but kept as a distinct node so a front-end can preserve the concession rather than flattening it:

```python
parser = MSFLParser()
parser.parse("P(x) Ⓒ Q(x)")
# → Contrast(left=Atom(predicate='P', args=(Variable(name='x'),)),
#            right=Atom(predicate='Q', args=(Variable(name='x'),)))
```

## Lambda syntax

Every mode supports lambda abstraction with `λx. φ`. The parameter can be a variable (`λx.`), a named constant (`λfoo.`), or a predicate symbol (`λP.`); the body extends rightward through all connectives. `parse()` applies scope resolution automatically, so the returned AST is fully resolved.

```python
parser = MSFLParser()

parser.parse("λx. P(x)")
# → Lambda(param=LambdaVar(name='x'), body=Atom(predicate='P', args=(LambdaVar(name='x'),)))

parser.parse("λfoo. P(foo)")
# → Lambda(param=LambdaVar(name='foo'), body=Atom(predicate='P', args=(Constant(name='foo'),)))

parser.parse("λP. P(x)")   # P used in predicate position
# → Lambda(param=LambdaVar(name='P'), body=Application(func=LambdaVar(name='P'), arg=Variable(name='x')))
```

It works in the fuzzy and extension modes too:

```python
type(MSFLParser(fuzzy=True).parse("λx. P(x) ⊗ Q(x)").body).__name__   # → 'StrongConjunction'

MSFLParser(modal=True).parse("λx. □P(x)")
# → Lambda(param=LambdaVar(name='x'), body=Box(formula=Atom(predicate='P', args=(LambdaVar(name='x'),))))

MSFLParser(second_order=True).parse("λP. P(x)")
# → Lambda(param=LambdaVar(name='P'), body=Application(func=LambdaVar(name='P'), arg=Variable(name='x')))
```

## ASCII tree view

`tree_str()` renders any node as a readable ASCII tree; `print` it to display. (A quantifier folds its bound variable — and, in MSFOL/MSFL, its sort — into the node label.)

```python
formula = MSFLParser().parse("∀x (Human(x) → Mortal(x))")
print(formula.tree_str())
# ∀ x
# └── →
#     ├── Atom: Human
#     │   └── Variable: x
#     └── Atom: Mortal
#         └── Variable: x

print(MSFLParser(many_sorted=True).parse("∀x:Human (Mortal(x) ∧ ¬Immortal(x))").tree_str())
# ∀ x:Human
# └── ∧
#     ├── Atom: Mortal
#     │   └── Variable: x
#     └── ¬
#         └── Atom: Immortal
#             └── Variable: x
```

The label format is node-specific — a counting quantifier shows `∃≥n`, a `Knows` shows its agent, and a second-order quantifier shows the bound predicate with its inferred arity:

```python
print(MSFLParser().parse("∃≥2 x P(x)").tree_str())
# ∃≥2 x
# └── Atom: P
#     └── Variable: x

print(MSFLParser(modal=True).parse("K_alice Smart(alice)").tree_str())
# K_alice
# └── Atom: Smart
#     └── Constant: alice

print(MSFLParser(second_order=True).parse("∃R ∀x R(x,x)").tree_str())
# ∃ R/2
# └── ∀ x
#     └── Atom: R
#         ├── Variable: x
#         └── Variable: x
```

## Graphviz DOT view

`to_dot()` renders the same label/child view as a Graphviz `digraph` source string (no external dependency — it returns the source, which you can pipe to `dot`):

```python
print(MSFLParser().parse("P(x) ∧ Q(x)").to_dot())
# digraph AST {
#   node [shape=box];
#   n0 [label="∧"];
#   n1 [label="Atom: P"];
#   n2 [label="Variable: x"];
#   n1 -> n2;
#   n0 -> n1;
#   n3 [label="Atom: Q"];
#   n4 [label="Variable: x"];
#   n3 -> n4;
#   n0 -> n3;
# }
```

## Inspection API

Every node exposes a small structural-inspection API. `walk()` yields the node and every descendant in pre-order; `subformulas()` is the same but excludes atomic terms; `atoms()` / `variables()` collect those leaf families; `count()` and `depth()` give size and height; a leaf has depth 1.

```python
from unicode_logic_kit import Atom

phi = MSFLParser().parse("∀x (Human(x) → Mortal(x))")

phi.depth()                                    # → 4
phi.count()                                    # → 7   (all nodes)
phi.count(Atom)                                # → 2   (only Atoms)
[a.predicate for a in phi.atoms()]             # → ['Human', 'Mortal']
sorted(v.name for v in phi.variables())        # → ['x']
[type(n).__name__ for n in phi.subformulas()]  # → ['Quantifier', 'Implies', 'Atom', 'Atom']
[type(n).__name__ for n in phi.walk()]
# → ['Quantifier', 'Variable', 'Implies', 'Atom', 'Variable', 'Atom', 'Variable']
```

`count` takes an optional class to filter by, and `Atom` is importable from the top level:

```python
from unicode_logic_kit import MSFLParser, Atom, Variable

phi = MSFLParser().parse("∀x (Human(x) → Mortal(x))")
phi.count(Variable)   # → 3   (one bound + two occurrences)
```

## Unicode round-trip

`to_unicode_str()` is the inverse of parsing: it renders any node back to a Unicode formula string, and for every node that has a text form, re-parsing that string in the same mode reproduces a structurally equal AST (the exception is a float that the reader refuses, as described above, such as one of 16 or 17 significant digits: it prints, and is not read back). The renderer is precedence-aware and inserts only the parentheses the grammar requires — including the no-mixing rule for same-level connectives and the tight-binding rule for quantifiers, so the reconstructed parenthesisation reflects the AST rather than the original spelling.

```python
parser = MSFLParser()

ast = parser.parse("∀x P(x) ∧ Q(x)")
ast.to_unicode_str()                          # → '∀x P(x) ∧ Q(x)'
parser.parse(ast.to_unicode_str()) == ast     # → True

parser.parse("((P(x) ∧ Q(x)))").to_unicode_str()        # → 'P(x) ∧ Q(x)'  (redundant parens dropped)
parser.parse("P(x) ∧ (Q(x) ∨ R(x))").to_unicode_str()   # → 'P(x) ∧ (Q(x) ∨ R(x))'  (required paren kept)
parser.parse("∀x (P(x) ∧ Q(x))").to_unicode_str()       # → '∀x (P(x) ∧ Q(x))'  (scope paren kept)
```

The round-trip holds in every mode (each re-parsed in its matching parser):

```python
MSFLParser(modal=True).parse("□P → ◇Q").to_unicode_str()                  # → '□P → ◇Q'
MSFLParser(modal=True).parse("∀x (Student(x) → K_x Smart(x))").to_unicode_str()
# → '∀x (Student(x) → K_x Smart(x))'
MSFLParser(second_order=True).parse("∃R ∀x R(x,x)").to_unicode_str()      # → '∃R ∀x R(x, x)'
MSFLParser(many_sorted=True, fuzzy=True).parse("∀x:Human (P(x) ⊗ Q(x))").to_unicode_str()
# → '∀x:Human (P(x) ⊗ Q(x))'
```

The natural-language constructs round-trip too:

```python
parser = MSFLParser()
parser.parse("∃≥2 x P(x)").to_unicode_str()                            # → '∃≥2 x P(x)'
parser.parse("P(x) Ⓒ Q(x)").to_unicode_str()                          # → 'P(x) Ⓒ Q(x)'
parser.parse("μ(x, height) > μ(y, height)").to_unicode_str()          # → 'μ(x, height) > μ(y, height)'
parser.parse("|{v : Votes(x, v)}| > |{v : Votes(y, v)}|").to_unicode_str()
# → '|{v : Votes(x, v)}| > |{v : Votes(y, v)}|'
```

A node that mixes sorted and unsorted occurrences has no text form: a sorted quantifier over an unsorted one, a constant written `carl:A` in one place and plain `carl` in another, or an unsorted quantifier around a sorted constant. A many-sorted grammar needs a sort on every binder and constant and a classical one allows none, so the printed text is refused with `NamingError` in every parser mode and is never read back as a different formula. State the sort on every occurrence, or on none, before printing.

```python
from unicode_logic_kit import And, Atom, Constant, SortedConstant, NamingError

mixed = And(Atom("P", (SortedConstant("carl", "A"),)), Atom("Q", (Constant("carl"),)))
mixed.to_unicode_str()                            # → 'P(carl:A) ∧ Q(carl)'
for kwargs in [dict(), dict(many_sorted=True), dict(modal=True)]:
    try:
        MSFLParser(**kwargs).parse(mixed.to_unicode_str())    # raises
    except NamingError:
        print("refused")
# → refused
# → refused
# → refused
```

`to_unicode_str()` is available on every node, so subformulas render too. The output targets parseable ASTs: the variables a reduction introduces (alpha-renamed binders, the witnesses of a counting expansion) are minted in the kit's own variable shape — one letter and digits, e.g. `x0` — so what `to_unicode_str()` prints for them reads back.

```python
phi = MSFLParser().parse("∀x (Human(x) → Mortal(x))")
phi.formula.to_unicode_str()    # → 'Human(x) → Mortal(x)'  (the body subformula alone)
```

## JSON round-trip

`to_dict()` produces a JSON-serialisable dict keyed by a `_type` discriminator; `Node.from_dict()` rebuilds the AST. The round-trip is structure-preserving across all node families (including modal and second-order nodes that the TPTP/Prover9 exporters cannot represent).

```python
from unicode_logic_kit import MSFLParser, Node
import json

formula = MSFLParser().parse("P(x) ∧ Q(x)")
d = formula.to_dict()
# {'_type': 'And',
#  'left':  {'_type': 'Atom', 'predicate': 'P', 'args': [{'_type': 'Variable', 'name': 'x'}]},
#  'right': {'_type': 'Atom', 'predicate': 'Q', 'args': [{'_type': 'Variable', 'name': 'x'}]}}

Node.from_dict(d) == formula                       # → True
Node.from_dict(json.loads(json.dumps(d))) == formula   # → True  (survives a JSON string)
```

It holds for the extension and natural-language nodes too — including the inferred arity on a second-order quantifier and the symbolic `n` on a counting quantifier:

```python
from unicode_logic_kit import MSFLParser, Node

m = MSFLParser(modal=True).parse("□P → ◇Q")
Node.from_dict(m.to_dict()) == m                   # → True

soq = MSFLParser(second_order=True).parse("∃R ∀x R(x,x)")
soq.to_dict()["arity"]                             # → 2  (inferred arity is serialised)
Node.from_dict(soq.to_dict()) == soq               # → True

cnt = MSFLParser().parse("∃=1 x P(x)")
Node.from_dict(cnt.to_dict()) == cnt               # → True
```

## The error model: `NamingError` vs `ParsingError`

`parse()` raises one of two errors. `NamingError` is a **lexer-level** failure — an unrecognised character, a malformed identifier, or a token that cannot start where it appears. `ParsingError` is a **parser-level** failure — a structurally incomplete formula (unexpected token or end of input). They are distinct classes (`NamingError` is *not* a subclass of `ParsingError`), so catch both if you want to handle any malformed input.

```python
from unicode_logic_kit import MSFLParser, NamingError, ParsingError

parser = MSFLParser()

try:
    parser.parse("P(x) % Q(x)")      # raises — stray character
except NamingError as e:
    print("NamingError :", str(e)[:52])
# → NamingError : SYNTAX_ERROR: Unexpected character '%' at positi

try:
    parser.parse("∀x")               # raises — quantifier with no body
except ParsingError as e:
    print("ParsingError:", str(e)[:52])
# → ParsingError: SYNTAX_ERROR: Incomplete formula - the input end
```

The **no-mixing rule** — same-level connectives `∧ ∨ ⊕` cannot be combined without explicit parentheses — surfaces as a `NamingError`, because the offending connective is rejected by the lexer at the point where mixing would begin. The message carries a hint naming the rule:

```python
from unicode_logic_kit import MSFLParser, NamingError

parser = MSFLParser()
try:
    parser.parse("P(x) ∧ Q(x) ∨ R(x)")    # raises — ∧ and ∨ mixed without parens
except NamingError as e:
    print(str(e))
# → SYNTAX_ERROR: Unexpected character '∨' at position 13 after closing parenthesis ')'. Hint: Cannot mix conjunction (∧), disjunction (∨), and exclusive or (⊕) without parentheses
```

Parenthesising the mixed group resolves it; the resulting AST reflects the chosen grouping:

```python
parser = MSFLParser()
parser.parse("(P(x) ∧ Q(x)) ∨ R(x)")
# → Or(left=And(left=Atom(predicate='P', args=(Variable(name='x'),)),
#               right=Atom(predicate='Q', args=(Variable(name='x'),))),
#      right=Atom(predicate='R', args=(Variable(name='x'),)))
```

### Which parser is behind each mode

The non-modal modes are parsed with lark's **LALR** parser alone; the modal modes (every mode built with `modal=True`, at any order and with or without sorts) try LALR first and fall back to **Earley** when LALR refuses the input. This is an implementation detail in the sense that it changes nothing you can observe — identical ASTs, identical accept/reject sets, identical source spans — but it is worth knowing, because it is why parsing is fast.

Earley exists to handle ambiguous grammars. This grammar is not ambiguous: asked for every derivation (`ambiguity="explicit"`), it produces exactly one for all 1260 parsable lines of the 1310-line FOLIO fixture. Since 0.23.2 the modes that do not need Earley no longer pay for it — measured 30× to 50× inside lark, and 200 → 6513 formulas/second end to end through `parse()` (4.99 ms → 0.154 ms per formula), median of seven runs with the garbage collector disabled.

The modal modes keep Earley as the fallback because eight shapes in the kit's own corpus are legal modal syntax the LALR table refuses — a bare lowercase propositional atom or a nominal standing as a whole formula, `p→(q→p)`, `@i (P ∧ ◇j)`. Narrowing the language is not a speedup.

The error model is unchanged by the swap. A table lexer tokenises first and refuses afterwards, where Earley's dynamic lexer refused the character, so the same bad input reaches the kit as a different lark exception; `MSFLParser` maps it back. The split turned out to be exact rather than approximate: every input Earley rejected with `UnexpectedEOF` becomes an unshiftable `$END`, and every input it rejected with `UnexpectedCharacters` becomes an unshiftable token that is not `$END`. So `NamingError` and `ParsingError` still mean what this section says they mean, and no error changed class. Of the 58 rejected inputs in the measured corpus, 26 messages are byte-identical; the 32 that changed all say `Expected:` more precisely, because LALR knows exactly which tokens could continue the formula.

### What a failed parse costs

A `NamingError` names the token in front of the offending character (`Invalid predicate 'Foo' — unexpected character …`), which means the failing text is tokenised a second time to find that token. Lark's own exception cannot supply it: the Earley scanner records the character and the position and nothing about what came before.

That second tokenisation used to be routed through `Lark.lex()`, and on this grammar that was a trap. Formulas were parsed with `parser="earley"`, which lexes dynamically and keeps no standing lexer, so `Lark.lex()` built a fresh one on *every* call — and lark runs a terminal-collision check when it constructs one, whenever the package `interegular` merely happens to be importable. The kit's identifier terminals are generated at import from the running interpreter's Unicode tables, and comparing every pair of same-priority ones took **minutes** — not because the patterns are long (the largest, `NAME`, is 4856 characters) but because `interegular` compares them by intersecting one finite automaton per pattern, and these range over most of the Unicode letter repertoire: one failed parse measured at 185 s with `interegular` present against 13 ms without it, same kit, same lark, same Python.

Nobody installs `interegular` deliberately — it arrives as a transitive dependency of vLLM (via `outlines`), so any environment that evaluates model-generated formulas has it. And failed parses are the normal case for model output, not the exception.

Since 0.23.2 the kit builds that lexer **once per parser** and **without lark's validation**, so the check never runs on the error path. A failed parse now costs about the same as a successful one — about 4 ms for the formula above, in either kind of environment. Nothing is lost by skipping validation: it checks that the *grammar* is well formed (terminal regexes compile, no zero-width terminal, every `%ignore` name defined), which lark already established when it built the parser; it only ever raises or stays silent, and never influences which tokens come out. `tests/test_error_path_speed.py` holds that line, and compares the two routes token for token across every grammar the kit builds.

If you were working around this with a separate `interegular`-free environment for parsing, you no longer need to.

## Source spans: pointing a node back at its own text

`parse()` builds an AST but keeps no record of where in the input each node
came from. `parse_with_spans()` does: it parses exactly like `parse()`, then
also returns a `SpanMap` — each node of the returned formula maps back to
the exact character range(s) of `text` it was parsed from.

```python
parser = MSFLParser()

spanned = parser.parse_with_spans("∀x (Human(x) → Mortal(x))")
spanned.formula == parser.parse("∀x (Human(x) → Mortal(x))")   # → True — same AST parse() builds

human = spanned.formula.formula.left        # the Human(x) atom
spanned.spans.for_node(human)
# → NodeSpans(extent=Span(start=4, end=12, ..., text='Human(x)'),
#              head=Span(start=4, end=9, ..., text='Human'))
```

A span never has to be re-derived: `Span.text` is already the slice, and
`start`/`end` index straight into the original `text` passed to
`parse_with_spans`. Every node gets TWO spans, bundled as `NodeSpans`:
`extent` is the minimal text the whole node covers (redundant outer
parentheses excluded), `head` is just its own head token — a connective's
occurrence, an atom's predicate name, a quantifier's symbol together with
its bound variable (`"∀x"`, whitespace included). A leaf term
(`Variable`/`Constant`/`Number`) has `head == extent`: it IS its one token.

The spans are returned as a table alongside the AST, keyed by PATH — a tuple
of child indices from the root — not as a field on each node, and not by the
node object's own identity or value. Every node class is a frozen dataclass
with structural equality (`P(x) == P(x)` even from two different formulas,
or two occurrences in the SAME formula, as in `P(x) ∧ P(x)`), which a
per-node span field — or a table keyed by the node's value — would break:
two textually-distinct occurrences of the same subformula would collapse
onto one span. `spans.get(path)` is the primary lookup; `spans.for_node(node)`
above is the convenience form for when you already have a node object in
hand (resolved by identity against whichever tree the map is currently bound
to — `parse_with_spans`'s own result is already bound to `spanned.formula`).
Walk every `(path, node)` pair with `unicode_logic_kit.traverse(spanned.formula)`.

Either half of a `NodeSpans` may independently report `UNKNOWN` — a sentinel
distinct from every real `Span`, and falsy, so `if span:` and `if span is
UNKNOWN:` both work. This happens in narrow, specific situations, never as a
silent guess: an operator outside the classical FOL fragment this feature
targets (`∀ ∃ ¬ ∧ ∨ → ↔ ⊕`, predicates over constants/variables/function
terms — those get BOTH spans exactly, always), a higher-order application of
a lambda-bound predicate (rewritten during scope resolution into nodes the
original parse never produced), and an agent variable sliced out of a
combined `K_a`-style token in modal mode — the enclosing `Knows`/`Believes`/…
node itself still has an exact EXTENT, only its bare agent sub-node does not:

```python
from unicode_logic_kit import UNKNOWN

modal = MSFLParser(modal=True)
ms = modal.parse_with_spans("K_alice P(alice)")

ms.spans.get(()).extent                  # the whole Knows node — known
# → Span(start=0, end=16, line=1, column=1, end_line=1, end_column=17, text='K_alice P(alice)')
ms.spans.get((0,)).extent is UNKNOWN     # → True — the agent, sliced out of one combined token
```

`unicode_logic_kit.replace_at(root, path, new_node)` is the matching
path-addressed edit: it rebuilds only the spine from `root` down to `path`,
so every node reachable via a path that does not run through the edit is the
exact same object in the result — including under a span table built before
the edit, which stays valid for every path outside it.
