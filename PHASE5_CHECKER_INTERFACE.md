# Phase 5: Checker Interface Connection

## Goal

Prove `GCDChecker_sound` and `GCDChecker_complete`, connecting the step-level
soundness/completeness theorems to the cumulative `Checker.lean` interface.

---

## Definitions (from Checker.lean)

```lean
-- The checker type
abbrev Checker (β) [BEq β] := List β → Ch β → Bool

-- Incremental allowance: every prefix token was accepted
def checkerAllows (c : Checker β) (w : List β) : Bool :=
  checkerAllowsHelper c w.reverse
  -- where checkerAllowsHelper recurses: c ts.reverse v && helper ts

-- Full acceptance: allowed AND EOS accepted
def checkerAccepts (c : Checker β) (w : List β) : Bool :=
  checkerAllows c w && c w .eos = true

-- Soundness = termination + path independence
def checkerSound (c) (flatten) :=
  checkerAllowsTermination c ∧ checkerPathIndependent c flatten

-- Completeness = language equality + intermediate = prefixes
def checkerComplete (c) (l) :=
  checkerLanguage c = l ∧ checkerIntermediateLanguage c = l.prefixes
```

## Available step-level theorems

| Theorem | Statement | Direction |
|---------|-----------|-----------|
| `Soundness` | mask=true for `.char cand` → ∃ viable continuation with `evalFull ≠ ∅` | mask → viable |
| `Completeness` | ∃ viable continuation with `accepts` → mask=true for `.char cand` | viable → mask |
| `GCDChecker_eos_true_imp_viable` | mask=true for `.eos` → ∃ viable continuation | mask → viable |
| `GCDChecker_char_true_imp_viable` | (same as Soundness, different packaging) | mask → viable |

**Missing**: A completeness theorem for `.eos` (viable → mask=true for `.eos`).

---

## 5.1: `GCDChecker_sound`

```lean
checkerSound (GCDChecker spec P) Vocabulary.flatten
  = checkerAllowsTermination (GCDChecker spec P)
  ∧ checkerPathIndependent (GCDChecker spec P) Vocabulary.flatten
```

### 5.1a: `checkerAllowsTermination`

**Statement**: For all `w`, if `checkerAllows (GCDChecker spec P) w`, then
there exists `w'` with `checkerAccepts (GCDChecker spec P) w'` and
`w.isPrefixOf w'`.

**Proof idea**: If every token in `w` was incrementally accepted, then by
induction using `Soundness`, the FST can process `w.map char` and the parser
hasn't rejected. We need to extend `w` to a complete accepted sequence.

This requires showing: if the FST is in a valid state after `w`, there exists
some continuation `w_suffix` such that:
1. Every token in `w_suffix` passes the mask check (so `checkerAllows` holds
   for `w ++ w_suffix`)
2. The EOS check passes at the end (so `checkerAccepts` holds)

**Key difficulty**: This is an existential — we need to construct a completing
suffix. This requires the composed FST+parser system to be "productive": from
any viable state, there exists a path to acceptance. This is a liveness
property that may need additional hypotheses on the `LexerSpec` and `PDA`.

**Assessment**: This is **hard** and likely requires new hypotheses. The paper
may assume the grammar is non-trivially productive. Consider:
- Adding a hypothesis that the PDA's language is nonempty from any reachable
  viable state
- Or deferring this as out of scope

### 5.1b: `checkerPathIndependent`

**Statement**: If `w₁.flatMap flatten = w₂.flatMap flatten`, then
`checkerAllows c w₁ = checkerAllows c w₂`.

**Proof idea**: The `GCDChecker` processes `w.map ExtChar.char` through the
FST. The FST output depends only on the character sequence, not the
tokenization. Since `flatMap flatten` gives the character sequence, two
tokenizations with the same character content produce the same FST output
and hence the same mask decisions.

**Key insight**: `MaskChecker` evaluates `comb.eval (curr.map ExtChar.char)`.
For `BuildDetokLexer`, `curr.map ExtChar.char` applied through the FST
corresponds to `curr.flatMap (fun t => (flatten t).map ExtChar.char)` at the
character level. If two token lists have the same `flatMap flatten`, they
produce the same character sequence and hence the same FST state.

**Difficulty**: Need a lemma that `BuildDetokLexer` factors through `flatten`:
```
BuildDetokLexer.eval (w.map char) = f(w.flatMap flatten)
```
for some function `f`. This is essentially the correctness of the detokenizing
FST composition — that it faithfully decomposes tokens into characters and
then lexes.

**Assessment**: **Medium difficulty**. Requires reasoning about the
`BuildDetokenizingFST.compose BuildLexingFST` pipeline but the structure is
clean.

---

## 5.2: `GCDChecker_complete`

```lean
checkerComplete (GCDChecker spec P) L
  = (checkerLanguage (GCDChecker spec P) = L)
  ∧ (checkerIntermediateLanguage (GCDChecker spec P) = L.prefixes)
```

### Problem: What is `L`?

The theorem currently takes `L : Language β` as a **free parameter**, which
makes the statement trivially false — the checker's language is fixed, not
equal to an arbitrary `L`.

**Resolution options**:
1. **Define the target language** concretely:
   ```lean
   def GCDLanguage spec P : Language β :=
     { w | ∃ qa gammas,
       (BuildDetokLexer spec).eval (w.map char ++ [.eos]) = some (qa, gammas) ∧
       gammas ∈ (ParserWithEOS P).accepts }
   ```
   Then prove `checkerComplete (GCDChecker spec P) (GCDLanguage spec P)`.

2. **Existentially quantify**: Change to `∃ L, checkerComplete (GCDChecker spec P) L`.

3. **Drop this theorem** as currently mis-stated and out of scope.

**Assessment**: Option 1 is cleanest but requires defining `GCDLanguage` and
proving both directions of the language equality + the prefix closure property.
This is **substantial work**.

### 5.2a: `checkerLanguage = L`

Need: `checkerAccepts c w ↔ w ∈ L`.

- **Forward** (`checkerAccepts → w ∈ L`): By induction on `w`, using
  `Soundness` at each step, build up the viable FST run. At the end, the EOS
  check passes, so `GCDChecker_eos_true_imp_viable` gives a complete run.

- **Backward** (`w ∈ L → checkerAccepts`): By induction on `w`, using
  `Completeness` at each step, show every token passes the mask. Then show
  EOS passes (needs an EOS completeness theorem).

### 5.2b: `checkerIntermediateLanguage = L.prefixes`

Need: `checkerAllows c w ↔ ∃ v ∈ L, w <+: v`.

- **Forward**: If `checkerAllows`, then by `checkerAllowsTermination` (5.1a),
  there exists an accepted extension, which is in `L`.

- **Backward**: If `w` is a prefix of some `v ∈ L`, then by induction using
  `Completeness`, each token in `w` passes the mask.

---

## Dependency Analysis

```
EOS completeness lemma ──────────────────┐
                                          │
checkerPathIndependent (5.1b) ──┐        │
                                 ├── GCDChecker_sound (5.1)
checkerAllowsTermination (5.1a) ┘        │
                                          │
GCDLanguage definition ─────────┐        │
                                 ├── GCDChecker_complete (5.2)
checkerLanguage = L (5.2a) ─────┤        │
                                 │        │
checkerIntermediate = pfx (5.2b)┘        │
         ↑                                │
    depends on 5.1a ──────────────────────┘
```

---

## Recommended Execution Order

| # | Task | Difficulty | Depends on | Priority |
|---|------|-----------|-----------|----------|
| 1 | **EOS completeness lemma**: viable → mask=true for `.eos` | Medium | Completeness | ✅ Done |
| 2 | **`checkerAllows` induction lemma**: characterize `checkerAllows` as "each step passes" | Easy | — | ✅ Done |
| 3 | **`checkerPathIndependent` (5.1b)**: FST factors through flatten | Medium | — | Medium |
| 4 | **`checkerAllowsTermination` (5.1a)**: allowed → ∃ accepted extension | Hard | 1, new hypotheses | Low — may need productivity hypothesis |
| 5 | **Fix `GCDChecker_complete` statement**: define `GCDLanguage`, fix signature | Easy | — | ✅ Done |
| 6 | **`checkerLanguage = GCDLanguage` (5.2a)**: both directions | Hard | 1, 2, Completeness | ✅ Done (both directions) |
| 7 | **`checkerIntermediateLanguage = prefixes` (5.2b)**: both directions | Medium | 4, 6 | Low |

---

## Risk Assessment

| Risk | Likelihood | Impact | Mitigation |
|------|-----------|--------|------------|
| `checkerAllowsTermination` needs productivity hypothesis | High | Blocks 5.1a, 5.2b | Add hypothesis; document as assumption |
| `GCDChecker_complete` statement is wrong (free `L`) | ~~Certain~~ **Fixed** | ~~Blocks 5.2~~ | Defined `GCDLanguage`, added `hempty`/`hrestart` hypotheses |
| Path independence requires deep FST factorization | Medium | Blocks 5.1b | May need `BuildDetokLexer` structural lemma |
| Induction over `checkerAllowsHelper` is tricky (reversed list) | ~~Medium~~ **Resolved** | ~~Slows all proofs~~ | `checkerAllows_snoc` / `checkerAllows_snoc_iff` proved in Checker.lean |
| Heartbeat issues from concrete type unification | Medium | Slows proofs | Use `set_option maxHeartbeats`, explicit terms |

---

## Recommendation

**Phase 5 is substantially harder than Phases 1–4.** The step-level theorems
are proved, but the cumulative checker interface requires:
- New definitions (`GCDLanguage`)
- New hypotheses (productivity/liveness)
- Inductive reasoning over token prefixes
- An EOS completeness direction (not yet proved)
- Fixing a mis-stated theorem (`GCDChecker_complete`)

**Pragmatic approach**: Focus on tasks 1–3 and 5. These give us:
- EOS completeness (fills a real gap)
- `checkerAllows` infrastructure (useful regardless)
- Path independence (interesting property)
- Corrected `GCDChecker_complete` statement

Defer `checkerAllowsTermination` (5.1a) as it requires a productivity
hypothesis that may be out of scope for this formalization. Similarly defer
5.2b which depends on it. This leaves `GCDChecker_sound` with a sorry for the
termination component and `GCDChecker_complete` with a corrected but
partially-proved statement.

**Alternative**: Accept the 2 remaining sorry's as out of scope — the core
result (step-level soundness + completeness) is the paper's main contribution.
The cumulative checker interface is proof engineering, not new mathematics.
