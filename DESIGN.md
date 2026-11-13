# Exact controlled point addition for `secp256k1-controlled-exact-v1`

## Current mux contract

The merged path now uses the paired-tick contract D1-D4 in [the mux proof](docs/mux-proof.md), superseding the older unrestricted canonical per-symbol Bézout-cell claims below. Logical T and R are canonical and scratch starts clean, but after a non-final B1 the physical word stores H = 2T + R in S4's encoded form, borrowing the next cell's g0 for its high bit. A semantic subtract follows B1; next.g0 must be 1 before holding; a final B1 requires R = 0. The held tick restores the borrowed symbol. Fallback primes retain the old step.

The additional sweep rotates each no-subtract run so B1 is last in Bézout order.
It runs in Euclid's tail, one cell behind the offset sweep, with which it commutes: the offset sweep's swap acts only on b of g0 = 1 cells, and each B1 step only on b of two g0 = 0 cells.
So Euclid hands Bézout the B1-swept tape, and inverse Euclid unsweeps it before undoing its steps; this supersedes the placement in S2's last sentence and S17's last sentence of the mux proof, not the maps they state.
With a raw tape that placement has moved again: "The B1 sweep inside the Bézout ticks", at the end of this file, runs the sweep in the Bézout pass and the unsweep in `_body`, and the Euclid pass leaves the tape unswept.
The tape at rest is block-coded, two wires freed per 15 ticks by `qec/tape_block.py`; on the swept tape every B1 follows a subtract cell in tape order, so the code reads each block's cells last first and relies on the same clause.
Cells read previous-symbol wires and can write the next g0 across a block edge, so Bézout decodes a block one tick before its first tick and codes it again one tick after its last, and two blocks are decoded across each edge for two ticks.
The gate's toy primes have at most one block, so the edge path is covered by `scripts/block_check.py` at 20 bits and above and by the secp256k1 rows, not by a toy instance.
The four-symbol alphabet, 384-tick bound and width schedule are unchanged. M and its inverse use clean states in their respective input/output layouts; top-level R remains on-curve or infinity with canonical encoding and zero scratch.

The corrected S13 distinguishes logical carries from physical borrowed first-probe wires: only on P = 1 do those wires equal the carries; on P = 0 their junk is unobserved except through P and reversed. Exported e and the second chain remain zero on the inert lane. Credit arXiv:2609.05625 section VI for the offset representation.

The exact-source independent review covers this pair contract; it does not grant upstream checker acceptance. The local held secp BDD probe stopped at the production 4,194,304-node budget. The earlier cell's cap-transfer proof does not automatically transfer. I7.charge, qualification, and the flat-upload operation cap remain open limits.

## Clean wires in the mux tick

Before these changes the mux tick held the circuit's peak at 1,275 wires, with 26 clean, while Euclid, the code calls and the B1 step peaked at 1,249.
So each clean wire the tick gives up lowers Q by one, until another stage binds.
A wire is worth T / (768 × 7 × Q) CCX per tick, counting 768 tick uses and 7 T per CCX, which is 3.40 on this tree.

Two changes lower the tick to 19 clean wires at secp256k1, for 1,268 wires × 23,151,240 T on this tree, against 1,275 × 23,075,976 before them.
Their statements are C1–C4 and R1–R4 in `INVARIANTS.md`.

- **Kept low carries.** The second chain no longer keeps every low carry through its top.
  It keeps c2, c6, c9 and c11 on wires and c12 on bit 11's selector, clears each other one once the next kept carry is built, and rebuilds them on the way down, at 2 CCX per dropped carry.
  The mux cell already drops c1 to pay for k2, so this saves 6 more wires, at +12 CCX per tick.
  At secp256k1 a pebble search over these carries, whose up pass may clear and rebuild any carry many times, finds this peak at the same cost, one wire lower at +6 CCX more, which is above a wire's worth, and nothing two wires lower.
- **The quiet run's prefix top.** M's top below its last is read only by `M.write`, so it is cleared right after M is built and recomputed on a new wire just before the write.
  That is 1 wire at +2 CCX per tick.

Three other wire trades were priced and set aside:

- `l0` cannot be recomputed across the second chain from g0 and R₀.
  On a non-last B1 it holds H's bit n, parked there by the hide, and that bit is on no other wire.
- Moving `Prefix` tops onto lower wires costs about +6 CCX per wire.
  Each intermediate top is also the next block's `a`, read once when the prefix is built and twice in `write`.
  A conditionally clean copy needs a true control beside it at every read, as in arXiv:2407.17966, so every read pays a gate.
- Releasing P's top below its last saves nothing, because `P.write` runs at the second chain's top, which is the tick's peak.


## What the challenge actually requires

Read from a checkout of the ecdsafail-v2 benchmark repository (read-only), which is not public until the benchmark is published.

- Profile `profiles/secp256k1-controlled-exact-v1.json` sets `arithmetic_contract: EXACT_UNITARY`, `approximate_arithmetic: DISABLED`, `measurement_cleanup: DISABLED`, target `CLIFFORD_PLUS_T`.
- SPEC (`ecdsa specs/synthesized-v2/SPEC.md`) DEF-01 requires complete controlled addition of fixed public points. QNT-03 requires identity on control 0 and exact addition on control 1. QNT-05 requires the default exact profile to handle every reachable case, including infinity and R in {A, -A, -2A}. QNT-04 requires correctness on superpositions and with entangled references. SEM-03 rejects `R` and `Hmr`.
- Encoding (QNT-01) is little-endian affine coordinates with `(0,0)` as infinity.
- A submission is a `SubmittedMethod` JSON (`assurance/qualification/src/bundle.rs`) whose `circuit` is an `ArithmeticCircuit` of `X`, `CX`, `CCX`, `SWAP`, `Z`, `CZ`, `CCZ`, `NEG`, `CONTROLLED_NEG` (`contracts/ir/src/arithmetic.rs`).
- Service caps (`service/src/controller.rs`, `capacity/`, `contracts/api/src/quota.rs`) are 4096 wires, 10,000,000 operations, and a 100 MiB upload. The upload is parsed as plain JSON with no compression.
- `limits.json` caps compiled T at 3.25e9 for the whole attack. `compiler/lowering` lowers each CCX to the 7-T Toffoli.
- Qualification (`assurance/qualification/src/graph.rs`) needs a universal certificate checked by a `SoundTheoremChecker`. The production registry holds none, and `qcb diagnostic check` executes nothing. No artifact can be `is_qualified` in this repository today.

So Schrottenloher's published circuits (arXiv 2606.02235) cannot pass as published. They use MSB-only comparisons, pseudo-Mersenne shortcuts that skip rare carries, a fixed iteration count tuned for random inputs (failure up to 2^-13.3), measurement-based uncomputation, and they ignore doubling and infinity. Each of these violates one of the clauses above. What carries over is the exact structure underneath: the dialog Euclid algorithm and the out-of-band Bezout reconstruction that turns an inverse into an in-place multiplication.

## Designs compared

Costs are Toffoli estimates at n = 256 before implementation. Every design here is exact and uses only X, CX, CCX, SWAP.

**A. Exact dialog multiplier (chosen).** Point addition follows the paper's Algorithm 1. It uses an in-place multiplier M(x, y) = (x, xy) and its reverse, plus one out-of-place lambda-squared subtraction. M runs Euclid forward to turn x into a dialog bit-vector, then runs Bezout on (y, 0), then runs Euclid backward. Making it exact means three changes. The iteration count becomes the proven bound bitlen(q(q-1)) = 2n. Comparisons and modular reductions become full width. Uncomputation uses reverse circuits instead of measurement. Euclid widths still shrink, because u*v at least halves each iteration, so the width can be min(n, bitlen(q(q-1) >> i)). Estimated cost is about 58n^2 per M and about 136n^2, roughly 9M Toffolis, per addition. Qubits are about 9n.

**B. Kaliski or binary-EEA inversion plus schoolbook multiplications (Roetteler et al. 2017, Haner et al. 2020).** This design computes lambda with an explicit inverse, then uncomputes the inverse. That costs two inversion passes plus at least three multiply-and-uncompute pairs. Published exact counts are about 2.5e8 Toffolis per addition for Roetteler. Haner's improvements remain several times above design A. Rejected because it costs more on every axis that binds.

**C. Projective complete formulas (Renes, Costello, Batina).** These need no inversion and are complete. They are rejected because projective coordinates are not canonical. An in-place R -> R + A on the declared affine encoding still needs a normalizing inversion to uncompute the old point. That adds design A's cost on top of the formulas.

## Completeness on the fixed addend

For a fixed public A = (a, b), the generic kernel fails only on R in {inf, A, -A, -2A}. On those inputs x - a = 0 or a - x' = 0, and M is not a bijection there. All four inputs and their sums {A, 2A, inf, -A} are public constants. The circuit therefore:

1. computes flags f_k = c AND [R == E_k] for the four exceptional inputs, and gen = c AND NOT(f1 xor f2 xor f3 xor f4);
2. XORs E_k xor O_k into the accumulator under f_k;
3. runs the generic kernel controlled only through gen, using M^-1 ... M. With gen = 0, every gen-controlled step is the identity, and M^-1 followed by M cancels exactly at the circuit level when M's entries are in [1, q), which the kernel's flag code ensures;
4. uncomputes gen, then uncomputes each f_k from the output as c AND [R' == O_k]. This works because R -> R + A is a bijection.

M's standalone contract is narrowed to canonical x in [1, q); x != 0 at M's entries rests on the kernel's flag code.
The build refuses curves with a finite point at x = 0 and addends with x(A) = 0 or x(2A) = 0.
The kernel codes both the -A exception and the c = 0, R = inf marker as f0 = f1 = 1, while keeping gen zero.
It flips X's low bit under f0 AND f1 before M inverse and restores it after M, holding no extra wire during M.
The direct evidence is the instrumented observation that the indicator equals [X = 0] before the remap and X != 0 at both M entries, on all 25,800 toy lanes and the secp256k1 special points.
The guarantee's control of record removes both remaps with every flag intact; the existing point gates then fail on 72 lanes, c = 0 with R = inf and c = 1 with R = -A, across all 36 toy instances.
The marker-removal, one-remap and old-gen-fold mutants are sensitivity controls; they do not test the nonzero-X guarantee.
This named limit accompanies I2.model's narrowed zero-caller row.

## Reusing the Euclid pass's zero words

These arguments apply to every odd prime q of n >= 2 bits and every canonical x and y in [0, q).
Let P = q(q - 1), T = bitlen(P), and x' = x XOR [x = 0].
Then 1 <= x' < q, including x = 0 and x = 1, whose distinct original values are retained by z.

**F1: the terminal state is (1, 0).**
Initially u = q is positive and odd, v = x' is nonnegative, and gcd(u, v) = 1 by primality.
If v is even, halving v halves the product and preserves the gcd because u is odd.
If v is odd, the conditional swap makes the subtracted operand no larger than v, and (v - u)/2 is nonnegative.
That step preserves the gcd and makes the product at most half its preceding value, with u still positive and odd.
Thus u_i * v_i <= floor(P / 2^i), and at i = T the product is zero.
Since u_T is positive, v_T = 0; the preserved gcd then forces u_T = 1.
This is an argument using the existing iteration bound, not a sampled reduction of that bound.

**F2: the zero remap is reversible.**
The flag z stays allocated while x' is used, and the inverse pass restores x' before the remap is undone.
The resulting x is the original input, so the repeated zero test clears z exactly.
The x' = 1 path multiplies by one and therefore implements the specified identity on y for original x = 0.

**F3: V supplies S.**
V is zero after the pass, even without remapping zero, so its wires can hold the initially zero Bezout word S.
The existing exact Bezout recurrence on canonical R = y and S = 0 ends at R = 0 and S = x' * y mod q.
No arithmetic cell, modular reduction or transcript alphabet changes.

**F4: only U's upper wires are lent.**
With the remap, U = 1, so U[1:] are zero and U[0] must remain allocated.
The allocator can lend those n - 1 zero wires to Bezout scratch; the unchanged exact cells restore that scratch to zero.
Reclaiming n - 1 zero wires afterwards need not return the original wires or their order.
The reclaimed word consists of the still-live U[0] followed by these zero wires, disjoint from the live x and y words.

**F5: restore the terminal state on a new layout.**
X on U[0] zeros the reclaimed word, and swapping it with S moves the product onto the word that becomes out while zeroing V again.
R on y's wires is zero, so X on its low wire recreates one there.
The triple (y wires, V wires, tape) now contains (1, 0, tape), the terminal state required by the inverse Euclid block.
Block replay on that matching layout restores (q, x', zero tape), and loading q again clears y's wires.
The cleared y word and tape are freed before the final equality test, allowing its AND chain to reuse their wires without increasing the peak.
The remap is then undone, z is cleared and freed, and the product word becomes the logical y output.
Every other wire is returned clean; reversing this same block gives M inverse, including its identity at x = 0.

This change relies on the existing proven bound and width schedule and changes neither, nor any modular reduction.
For nonzero remapped inputs, active operands fit the existing schedule, and the idle state (1, 0) also fits every emitted step.
The gate-level small-prime checks and 256-bit boundary components exercise the implementation; they do not replace the all-input argument or constitute acceptance by the separate benchmark proof checker.

## Shared-chain Euclid pass with a held offset

For every odd prime q, put n = bitlen(q), P = q(q - 1), T = bitlen(P), and use the unchanged width_schedule.
Let (u_i, v_i) be the reference Euclid state and (b_i, s_i) its parity and conditional-swap bits.
The following describes the step and sweep introduced with this proof; the existing F1-F5 and C1-C10 arguments remain its external boundaries.

**E1: the physical step, before wire rotation.**
For w >= 1, take a w-bit odd word a, a w-bit word B, prior offset bit e (zero for the first step), two zero tape bits and a zero carry-in.
Let vhat = B XOR e on the low bit, S = a + NOT(vhat) modulo 2^w, and c = [a > vhat], its carry out.
The physical output before interpreting the rotation as halving is:

| Condition | a output | B output | g0 | g1 |
|---|---|---|---|---|
| vhat even | a | vhat | 0 | e |
| vhat odd, c = 0 | a | vhat - a | 1 | 0 |
| vhat odd, c = 1 | vhat | a - vhat - 2 | 1 | 1 |

The upward majority chain stores c_(i+1) on a[i], NOT(vhat_i) XOR a_i on B[i], and c_i XOR a_i on the preceding carry wire.
On descent, one CCX restores a_i and a second adds g0*(c_i XOR a_i) to B[i].
Two CX gates restore the preceding carry and remove a_i from B[i], leaving S_i when g0=1 and NOT(vhat_i) otherwise.
The identity S_i XOR c_i XOR 1 = a_i XOR vhat_i lets an X-conjugated CCX controlled by g1 exchange the selected a bit without a second ripple.
Complementing B gives NOT(S) when g0=1 and vhat otherwise.
A CX from g1 to each upper B bit selects S on those bits in the swap case, while retaining NOT(S_0) on the low bit.
Odd a and odd vhat imply S_0=1, so B's low bit is zero in both odd branches; it is also zero in the even branch.
The final controlled copy adds (NOT(g0))*e to g1; it preserves e, and the carry-in returns to zero.
Thus the low-bit rotation of the full V word is exact halving, and E1's table must not be confused with the logical post-rotation word.
The first variant costs 4w+1 CCX and later variants cost 4w+2, including the offset copy.

**E2: held-state induction.**
For 1 <= x < q, before each step U=u_i and V+e_i=v_i with V>=0, e_0=0, and e_i the preceding cell's second bit for i>=1.
If e=0 the absorb leaves V=v; if e=1 and v is odd it changes the even V=v-1 to v; if e=1 and v is even it changes the odd V=v-1 to v-2.
Therefore vhat has v's parity and is at most v.
For odd v with u>v, the gate outputs after rotation are (U,V,e')=(v,(u-v)/2-1,1); u-v>=2 makes V nonnegative.
For odd v with u<=v they are (u,(v-u)/2,0).
For even v they are (u,v/2,0) if e=0, and (u,v/2-1,1) if e=1.
Each case preserves V+e'=v_(i+1) and U=u_(i+1), with e' the current second tape bit.
During active steps u and v fit the existing window, so vhat<=v and V<=v make this chain exact in that window.
This uses the existing product-halving bound proved in F1; it is not Bernstein-Yang's different divsteps bound.

**E3: zero tail and terminal offset.**
When v_i=0, nonnegative V and e force V=e=0.
Then g0=g1=0 and the upward/downward chain restores U and V for every window, including one narrower than U.
F1 gives u_T=1 and v_T=0 for nonzero canonical x over prime q, hence U=1,V=e=0 at the end.
Primality is used here through F1's gcd argument.
The last odd step has u=v=1, since reaching zero requires equal operands and their gcd is 1, so that step leaves no offset.

**E4: descending tape sweep.**
Write z_i for the unswept second bit: z_i=s_i on odd cells, z_i=z_(i-1) on later even cells, and z_0=s_0.
For i=T-1 down to 1, XOR (NOT(b_i))*z_(i-1) into z_i.
Descending order reads the predecessor before it is changed, so even cells become zero and odd cells keep s_i.
The swept tape is exactly the reference dialog, allowing the unchanged Bezout cell, reduction proof and F1-F5 cleanup to apply.
The first and last offset exchanges now use CX-only endpoint identities, and the merged sweep skips the terminal B1 step and its mark transition.
The sweep remains inline in the pass body so tape blocks can be decoded and coded between steps.

**E5: zero inputs and generic callers.**
The multiplier remaps original x=0 to x'=1, covered by E2; the retained flag distinguishes it from original x=1.
The pass's domain is therefore V != 0, which E7 needs.
A generic caller with V=0 would keep U=q, whose high wires are not zero, so E7's lent wires would not start clean; the pass no longer supports that caller.

**E7: late tape on U's vacated wires.**
For V != 0, the proven bound gives max(u_t, v_t) < 2^(w_t) at every boundary t, or (u_t, v_t) = (1, 0), so U < 2^(w_t).
A step at width w touches only U[:w], and widths never grow, so U's wires from w_t up are zero from boundary t to the end of the pass.
When the width drops, the pass adds those wires to the tape's supply, the highest first, as it already does with V's.
It lends as many as it ends with zero wires: V's tail and two free wires per coded block, 52 at secp256k1.
At the end U takes those zero wires back as its upper wires, so U is again (1, 0, ..., 0) and S reuses the whole word.
The boundary is a permutation of U and the pool together, so replaying the pass block in reverse gives inverse Euclid the mirror layout with no extra gate.
Euclid's pool is smaller by the lent wires, which puts Euclid's peak below Bezout's, so no block is coded during the pass any more.

**E6: reversal and unchanged surfaces.**
Reversing the pass reverses its sweep and then its step calls, including their layout permutations.
F5 restores precisely the terminal words and swept tape needed by that inverse, so no additional garbage or cleanup assumption is introduced.
The external pass relation, iteration bound, width schedule and modular reduction are unchanged; EuclidStep's physical relation and internal second-bit meaning change as E1 states.

At G, sum(W)=98432 and T=512, so each pass costs 4*98432+2*512-1+511=395262 CCX instead of 591104.
Four passes save 783368 CCX, or 5483576 T; these are formulas to check against emitted counts.
This change leaves _bezout and qec/arith.py unchanged.
Finite gate checks and the separate leaf lift probe do not establish acceptance by the benchmark checker or compose this proof automatically.

## Exact merged Bézout reduction

For every odd q >= 3 and canonical R, S, `Mod.dbl_add` computes (2S + g0 R) mod q with clean scratch. The Bézout step then applies the existing g1-controlled swap; its contract and [2, n, n] layout are unchanged.

q is odd with n = bitlen(q), and f = 2^n − q, so f is odd and 2^n < 2q.
m is any integer with bitlen(2f) ≤ m ≤ n, so 2f < 2^m, and the generator takes the smallest.
That range is never empty, because 2f < 2^n.
At secp256k1, m = 34 and h = n − m = 222.

R, S < q and g0 is a bit.
s = 2S + g0·R, so s ≤ 3q − 3.
t = s >> n, low = s mod 2^n, L = low mod 2^m, H = low >> m, and A = [H = 2^h − 1], with A = 1 when h = 0.
For j in {0, 1, 2}, c_j is the carry out of L + j·f on m bits, so c_0 = 0 and c_1 ≤ c_2 ≤ 1.
e = A·c_(t+1) for t ≤ 1, e = 0 for t = 2, and k = t + e.

### Gate order

Every wire below is a named position in `s`'s bits: bit 0 is a fresh wire `l0`, bits 1 to n are S's wires, and bit n + 1 is a fresh wire `top`.
So `low` is `[l0] + S[:n-1]`, t0 is `S[n-1]`, and t1 is `top`.

| # | Action | CCX at n = 256 |
|---:|---|---:|
| 1 | `add(R[1:] + [l0], S, top, ctrl=g0)`, with `l0` still zero as a's top bit | 3n + 1 = 769 |
| 2 | l0 ^= g0·R[0] | 1 |
| 3 | Prefix-AND chain over H, the carries of H + 1, giving A_i and A_h = A | h − 1 = 221 |
| 4 | Set selectors in place: X t1, CX t0 → t1, so t1's wire is [t = 0] and t0's wire is [t = 1] | 0 |
| 5 | Carry chain up on L + [t = 0]·f + [t = 1]·2f, giving c at the top | m = 34 |
| 6 | Fresh `e` ^= A·c, a CX when h = 0 | 1 |
| 7 | The same chain down, then undo step 4 | m = 34 |
| 8 | t += e in place: CCX(t0, e, t1), CX e → t0. The wires now hold k0 and k1 | 1 |
| 9 | Carry chain up on L + k0·f + k1·2f, giving c_k at the top | m = 34 |
| 10 | e ^= A·c_k, which clears `e`, a CX when h = 0 | 1 |
| 11 | For i from h − 1 down to 1: clear A_(i+1) from A_i and the old H_i, then H_i ^= c_k·A_i. Then H_0 ^= c_k, a CX | 2(h − 1) = 442 |
| 12 | For i from m − 1 down to 1: clear c_(i+1) from the old L_i and c_i, then L_i ^= addend_i xor c_i. Then clear c_1 from `l0` and the bit-0 addend, leaving `l0` alone | m = 34 |
| 13 | Fresh z = g0·¬k0 | 1 |
| 14 | `gt_into(R[1:], low[1:], t1, ctrl=z)`, which clears k1 | 2(n − 1) + 1 = 511 |
| 15 | Clear z | 1 |
| 16 | CX l0 → t0, so t0's wire holds S'[0], then l0 ^= g0·R[0], which clears `l0` | 1 |
| 17 | Free `l0`, `top`, `z`, then rotate `S` by one wire, as `moddbl` does | 0 |
| 18 | `cswap(g1, R, S)`, in `_bezout` | n = 256 |

A low chain has one AND per position, with the addend bit at position i being one of 0, the first selector, the second selector, or their XOR.
That is MAJ(L_i, addend, carry), and CX conjugation gives it with one CCX.
`_carries(C, H, 1)` already builds step 3, up to A_(h−1), and A_h is one more carry on top of it, so reuse what fits.
`_reduce`'s down loop has step 11's order: it uncarries position i + 1 before it writes position i.

**Cleanup order in steps 11 and 12.** A stored wire reads the old bit below it, so each one clears before that bit is written.
A_h goes first, right after step 10, because it is used only by steps 6 and 10 and writing H_(h−1) first would leave it dirty. With h = 2, H = 11 and c_k = 1, A_2 would stay 1.
A_1 is an alias of H_0 and has no wire to clear.
With h = 1, A is H_0, step 3 is empty, steps 6 and 10 read H_0, and step 11 is the single CX.
With h = 0, A is the constant 1, step 3 is empty, steps 6 and 10 are CX from c and c_k, and step 11 is empty.
Step 7 runs step 5 in reverse with nothing written, so it has no such order to get wrong.

The cell is inline, with no `C.apply` or `C.record` inside, because `lift` refuses a leaf with calls.

### Correctness and cleanup

**C1.** t is 0, 1 or 2, because s < 3q < 3·2^n.

**C2.** For j ≤ 2, low + j·f ≥ 2^n exactly when A·c_j = 1.
This holds because low + j·f = (H + c_j)·2^m + ((L + j·f) mod 2^m), and H + c_j reaches 2^h only from H = 2^h − 1 with c_j = 1.
The carry is one bit because 2f < 2^m.

**C3.** k = floor(s/q), and S' = s − kq = low + k·f − e·2^n.
With e = 0 and t ≤ 1, C2 gives low + (t + 1)f < 2^n, so 0 ≤ low + t·f < q.
With e = 1, C2 gives low + (t + 1)f ≥ 2^n, so S' ≥ 0, and S' < q is the same as s < (t + 2)q, which holds for t = 0 because s < 2^n < 2q, and for t = 1 because s < 3q.
With t = 2, S' = low + 2f < q is the same as s < 3q.

**C4.** Step 5's addend is (t + 1)·f below 2^m for t ≤ 1 and 0 for t = 2, so step 6 computes the e above.
Step 7 finds the selectors as step 5 left them, because step 6 touches only `e`.

**C5.** e = A·c_k, on every reachable state.
If e = 1 then c_k = c_(t+1) and A = 1.
If e = 0 and t ≤ 1 then c_k = c_t ≤ c_(t+1), so A·c_k ≤ A·c_(t+1) = 0.
If t = 2 then low + 2f < q < 2^n, so A·c_2 = 0 by C2.
So step 10 clears `e` while A and c_k are still live.
This is the sketch's trap: `e` is the overflow out of H as well as k − t, so it needs no clear of its own from the final state.

**C6.** S' = ((H + c_k) mod 2^h)·2^m + ((L + k·f) mod 2^m), which follows from C3, and S' < 2^n.
Steps 11 and 12 write exactly that, and k0, k1 are exclusive because k ≤ 2.
Every stored A_(i+1) and c_(i+1) reads 0 after its clear, because each clear runs on the same inputs that set the wire: the old bit, and a lower chain wire that has not been cleared yet.

**C7.** k1 = 1 needs g0 = 1, because g0 = 0 gives s = 2S < 2q.

**C8.** Step 14 clears k1.
If z = 1 then k is even, so S' and R have the same parity and [R > S'] = [R >> 1 > S' >> 1].
With k = 0, S' = 2S + R ≥ R.
With k = 2, S' = R − 2(q − S) ≤ R − 2.
So the compare equals k1.
If z = 0 then k1 = 0, by C7 or because k0 = 1.
k = 1 can have R > S', so the compare needs z and not g0 alone.

**C9.** S'[0] = k0 xor g0·R[0], because 2S is even and q is odd.
So step 16 leaves S' on the rotated wires and clears `l0`.

**C10.** For each g, S → 2S + g0·R mod q is a bijection on [0, q), because q is odd.
The circuit is a permutation that takes canonical states with zero scratch onto canonical states with zero scratch, so the reversed cell that M⁻¹ runs is exact on canonical inputs too.

Nothing here uses primality, n = 256, or a run of ones.
The run of ones only makes m small.

## Data shape

- **Wire.** An integer index. **Register.** A Python list of wires, least significant bit first. Shifts are relabels, implemented as list rotations with no gates.
- **Circuit.** A flat `array('i')` of (opcode, a, b, c), a free-list wire allocator that requires ancillas to be returned clean, and a high-water mark that becomes `num_wires`.
- **Block.** A recorded op range with input layout, output layout and internal wires. It can be instantiated forward or reversed onto any matching layout. That is how M^-1, Euclid-backward and every compute/uncompute pair are emitted without hand-written inverse code.
- **Simulator.** A bit-sliced simulator in which each wire is a Python int and bit j is test lane j. It shares no code with the generator's arithmetic.

## Why the permutation is enough for QNT-04

The circuit contains only X, CX, CCX and SWAP. It is therefore a permutation matrix with no phases. The point-addition promise is R on the curve or infinity, with canonical encoding and zero scratch. On this domain, x and y parity identify each finite point; the x=0 guard retains a full y comparison when required to distinguish infinity. Both flag computations use this same domain before and after the controlled translation. If every promise basis state |c, R, 0> maps to |c, R + cA, 0>, the same matrix acts exactly on any superposition of promise states and on any extension with a reference system. Basis exactness plus clean scratch is the whole unitary contract. Outside the promise, the circuit is still a permutation, so QNT-06's valid-channel requirement holds by construction.

## Last-cell lend

The merged pass lends the uncoded final tape cell's b after its last read, using its proved complement relation with g0.
Restoration allocates fresh zero storage and updates the tape boundary before inverse Euclid.
The codec and tick schedule do not change.
See `docs/tail-lend-proof.md`.

## Seven-tick whole-block capacity codec

The seven-cell block codes W[0..12], whose six inner windows (g_i, b_i, g_(i+1)) exclude 000, while W[13] remains raw.
The existing block reading order reads cells last first on the B1-swept tape.
There are 4,021 coded words and 8,042 inputs including both raw-b values.
The primitive list is pinned by canonical-JSON SHA256 8a43178163d443fa37f9f9e8da3431e876f476d8f1d4c87b0710760106813ed2.
Its 326 primitives include 36 CCX: the five-cell part costs 15, the re-tag costs 11, and the U1 hand pack costs 10.
Two clean ancillas at indices 14 and 15 return zero, and FREE = (10,) names the block wire returned zero.
W[13] is absent from every primitive operand.

The generic encode/decode plumbing and sweep order are unchanged.
Each decode supplies one fresh zero wire and each encode returns one wire to the allocator.
At secp256k1, 54 blocks code 378 cells and leave six uncoded, preserving the last-cell lend.
Euclid lends 56 wires: its two tail zeros plus one zero per coded block.
Two decoded blocks still overlap across each edge.
Item 4's borrowed tape storage must be checked on this layout at its four borrow boundaries; later physical reuse is distinct from a live FREE or codec-ancilla role.

This section supersedes the earlier fifteen-tick codec summaries and their 25-block, two-free-wire and 52-wire lending figures.
The whole-block domain requires all six inner windows, including the boundaries the previous three-part codec did not code.
Checks cover the emitted list exhaustively, both sweep states at every gate prime with coded blocks, M and its inverse with every wire compared, the merged block edges, and directed secp256k1 lanes.
The ordinary toy mutation row is finite-domain evidence; separate codec deletion controls test codec sensitivity.
Every figure retains the limit: **`I2.model`'s zero-caller row narrowed from the reference's gate**.
No checker admission or qualification is implied.

### Euclid tick 0 on its initial boundary

The initial U is q, V is the nonzero-remapped x, E is zero, and the cell and remaining tape are clean.
The first step alone uses `_euclid_tick0` when the width is n and k = n - 1 - lsb(2^n - q + 1) unwritten tape wires are available.
For odd v its output is U=v, V=(q-v)/2-1, E=1, cell=(1,0).
For v=2 mod4 it leaves U=q, E=0 and cell=(0,0), with V=v/2; for v=0 mod4, V=v/4 and cell=(0,1).
The V list rotates exactly as in the general step.
Controlled addition of 2^n-q+1 uses the borrowed wires as carries; it uncomputes them before returning.
Its first carry uses the preceding select identity through the optional low callback rather than another controlled gate.
The recorded block's input/output wire sets agree and contain every used wire.
If width, supply or that shape contract fails, the first step falls back to `_euclid_step`; later steps always use the general block.
The borrowed wires are zero at tick 0's entry/exit and the mirror points in the inverse pass.
They may hold nonzero tape at E's exit, so they are not generally clean scratch there.

### Inline kernel constants and reflection

For cmodadd_const, k=c*[b>=q-v].
The control temporarily holds c XOR k, so selectors (c XOR k,k) exclusively select v or v+2^n-q.
The selected carry chain starts at the lowest set bit of either mask and uncomputes each carry before overwriting its old input bit.
After restoring c, [b'<v] clears k.
For creflect, k=c*[b>a].
Complement b under c and add a+1 or (a+1+q) mod2^n under the same exclusive selectors.
The output remains canonical and lies above a exactly when k, so CX(c,k) followed by comparison a+1>b' clears the flag.
This reflection is valid at b=0 as well.
It replaces kernel cneg and the final constant addition; the intervening subtraction acts on Yr and commutes.
All gates are inline: addend-dependent constants introduce no new recorded definitions.
Existing standalone cneg behavior and its tests remain.

### Kernel flag recode across M

At either M boundary, (c, f0, f1, gen) is one of 0000, 0110, 1000, 1100, 1010, 1110 and 1001.
With c = 0 the word is 0000, or 0110 with the zero marker; with c = 1 it is 1001 on the generic path and 1000, 1100, 1010 or 1110 on an exception.
CX(gen, c) and CX(gen, f0) move 1001 to 0101, then gen XOR= NOT c AND (f0 XOR f1) clears gen using one CCX and no temporary wire.
The equivalent XOR form relies on the absence of a c = 0 word with f0 = 0 and f1 = 1.
The other six words are unchanged, and the seven remaining (c, f0, f1) words are distinct.
The kernel releases zero gen before each M apply and allocates a zero wire before reversing the recode, restoring c, f0, f1 and gen before any subsequent reader.
The released physical wire may become M scratch or an output register; the reallocated wire carries the restored logical gen and is returned to build.
Four recodes cost four CCX in total and free one live wire throughout both M applies.
Direct observation checks both boundaries on all 25,800 toy lanes and twelve secp256k1 special-point lanes, including zero at release and reallocation, word restoration and final data/control/scratch.
Removing gen's clearing CCX is the freed-wire control of record; removing CX(gen, f0) is a sensitivity control, each checked over the full toy population.
The inherited narrowed zero-caller row and standalone M domain x in [1, q) remain unchanged.

## Five-cell tail code

The merged Bezout pass codes five raw tail cells when the tail lend applies, at least five cells are uncoded, and the width at tick T - 5 is at most six.
The code applies after tick T - 6 and its block encode check. On the default pass it reverses after block zero is encoded and before the lend restore; on M's held path, where block0_raw skips that encode, it reverses at the same point with block zero still raw.
Its 168 primitives cost 19 CCX per apply, return FREE = (2,) zero, and restore three clean ancillas.
The domain is all 230 L6 words on nine live wires; the exhaustive tail_code component row checks distinct images, zero FREE and ancillas, and exact reverse restoration.
A real-tape corpus reaches 84 of those words; the remaining words are covered by the exhaustive component row, not claimed as reached tape states.
The new row adds one component and 230 lanes, changing the census from 50 / 9,615 to 51 / 9,845 without changing any other row.
Both existing named limits remain: I2.model's narrowed zero-caller row, and standalone M restricted to x in [1, q) with nonzero entries resting on kernel flags and the non-full build refusal.
The tail code additionally requires T >= CELLS + 1 so its forward tick exists; the inverse asserts that the forward apply ran.

## Block-zero code

For canonical x < q, strips before the first subtract leave U = q > V, so that subtract swaps and the swept block-zero word lies in the 4,022-word D1 subset of the L6 domain.
On the merged path with a block, a 21-CCX pre-map followed by the existing codec frees W10 and W13, with seven pre-map ancillas returned before the codec allocates its two.
The extra free wire joins the clean pool that U borrows at the pass boundary, reducing external tape by one; with_free_slots restores both positions for later passes.
A one-CCX HOLD frees b0 while ticks 7 through 2 run and restores it before tick 1, without touching the g1 next-cell lend.
Nonmerged paths keep the original codec, and no new per-prime domain refusal is needed.
The exhaustive D1 component row checks encode and HOLD both ways, clean FREE and ancillas, and distinct images, increasing the census only to 52 rows and 13,867 lanes.

### Holding block zero across the inverse pass

The merged multiplier records the Euclid pass with block zero raw and codes that block immediately after the recorded call.
The default pass remains the raw variant followed by the same block-zero encode, with identical operations and output wire lists.
The Bezout pass leaves block zero decoded at its end only when the multiplier requests this variant.
Before the inverse Euclid pass, the multiplier places the block's two free-slot wires in the raw pass's output positions and releases the zero wires previously occupying them.
The default pass and every existing gate-script caller retain their encoded boundary.
This removes the adjacent encode and inverse decode in both multiplier calls, saving 204 CCX and one listed call without increasing the 1,246-wire peak.
The existing breakdown script still measures default passes; its rows include the removed encode/decode work and therefore do not sum to the optimized multiplier's cost.

## Pooled tick schedule

Selected merged ticks use a cap-four reversible pebble search on the second chain's unperched prefix, derived from that shape's length and quiet-run top wire.
The construction applies when the sole low perch is at a-1 and a cap-four schedule exists; otherwise that shape keeps the original kept-carry schedule.
At secp256k1 the 106 block-edge ticks, tail-code edge 378, and ticks 1 and 0 use the schedule, adding six CCX each.
At the other measured merged primes below 20,000 where this schedule runs, CCX changes by zero to minus two per use, with no wire change or scratch increase.
The uncoded terminal cell is never B1, so when the existing tail lend applies, tick T - 2 uses the no-prev shape and the terminal b release moves before that tick.
That released b is unread until the existing end-of-pass X and CX restore it.
These changes leave the nonmerged path and no-tail-lend instances unchanged.

The codec's primitives 4, 128, 145, 162, 188 and 197 use the six checked CX substitutions, giving a 30-CCX reversible code.
Its contract holds on all 8,042 window words and all 4,022 pre-map images; 6,254 window words have changed codewords, and each block uses the same shape for encoding and decoding.
Each of the six wrong-control substitutions fails the domain contract.

The merged Euclid sweep starts at mark(T - 2) and carries one mark equal to NOT g_k AND NOT g_(k-1), updating it before the next block encode and clearing it before block zero is encoded.
Each update toggles the mark by NOT g_(k-1) AND (g_k XOR g_(k-2)), so every g read is still raw.
The original carried-mark construction saved 382 CCX per Euclid pass at 384 ticks.
The endpoint identities and skipped terminal transition now remove four further CCX per pass, sixteen per point addition; nonmerged sweeps use the endpoint identities without the merged terminal skip.

## Uncontrolled top add bit

Without carry output or control, the top majority and unmajority reduce to b XOR a XOR the incoming carry.
Two CX gates replace that pair while every lower bit retains the original chain.
Controlled and carry-output calls keep their existing implementation.
The full circuit loses 44 CCX.

## Bounded square digit adds

Each digit bounds the accumulator before and after its addition using the corners of the caller's input box.
A subtract bounds the complemented value, -v - 1.
Above the first bit containing every bounded value, the remaining bits hold the sign.
A known zero sign allows truncation; a variable sign uses the add's carry output and copies it above that bit before and after the add.
A positive digit added to an initially zero accumulator with no carry input copies its source.
The first fold accepts arbitrary n-bit source and accumulator values, and the second accepts a source at most f and a zero accumulator.
This saves 984 CCX after the top-bit edit; 20 CCX overlap that edit's standalone saving.

## Repeated-width strip boundary

A Euclid tick leaves V below the top bit of that tick's width.
When the preceding tick used the same width and the current width is at least three, the second strip's final swap exchanges two zero bits.
The pass marks precisely those calls with top_clear, and recorded shapes cache both width and that flag.
Unflagged callers retain the full swap sequence.
The full circuit loses 516 CCX.

## Sweep endpoint identities

The first cell has U = q greater than x, so a subtract swaps and g0 implies E XOR b equals one.
At the last cell, no subtract implies E XOR b equals one, giving the other CX-only offset exchange.
For a merged sweep with at least three cells, the last two no-subtract cells have equal b bits.
Their B1 transition never swaps, so the sweep starts its carried mark at T - 2 and skips that terminal B1 step and mark transition.
Together the endpoint and terminal changes remove four CCX per Euclid pass and sixteen per point addition.

## First carry in tick zero

The tick-zero select leaves U[j] = q_j XOR g0 times (v_j XOR q_j).
For the lowest set bit j of the following constant, the first carry g0 times v_j is U[j], complemented with g0 and one when q_j is one.
An optional low callback supplies that carry during computation and uncomputation; every other adder caller retains the default carry primitive.
The full circuit loses eight CCX and keeps the same clean-wire contract.

## Tail-code control substitutions

On the checked tail-code domain, primitives 103 and 109 use their single remaining controls.
The two CCX-to-CX substitutions preserve the code's complete forward and inverse domain contract.
The primitive list retains its length, and its header digest records the substituted list.
The full circuit loses eight CCX.

## Single-Toffoli kernel recode

After the initial flag CX gates, the c = 0 words are 0000, 0110 and 0101.
None has f0 = 0 and f1 = 1, so f0 XOR f1 equals f0 AND NOT f1 on that domain.
The recode toggles gen with NOT c AND (f0 XOR f1), temporarily forming and restoring the XOR.
This uses one CCX without a temporary, saving eight CCX across the four recodes.

## The B1 sweep inside the Bézout ticks

On the merged path with a raw tape (`DialogMultiplier.inline_sweep`), the Euclid pass no longer sweeps B1.
It hands the Bézout pass the tape as its ticks wrote it, the Bézout pass sweeps each cell as it reads it, and `_body` unsweeps the tape after the pass, before the inverse Euclid pass.
The map the Bézout pass applies to a swept tape is unchanged.
The construction is PR #28's (`lowt-depth`, ab-godder), fitted here to the rank-one start, the tick after the terminal cell and the cut at cell 0, none of which PR #28 has.

**The sweep as a chain.**
Sweep step k swaps b_k and b_(k-1) when g0_k = g0_(k-1) = 0, for k from T - 2 down to 1, which is the Bézout pass's order.
A single strip (B1) is followed by a subtract, so of two adjacent no-subtract cells the lower one is a double strip (J) and has b_(k-1) = 1.
Step k therefore toggles both bits by t_k = NOT g0_k AND NOT g0_(k-1) AND NOT x_k, where x_k = b_k XOR t_(k+1) is b_k after step k + 1.
When t_(k+1) = 1, x_k = 0; and when g0_(k+1) = g0_k = 0, b_k = 1. So t_(k+1) = NOT g0_(k+1) AND B1_k with B1_k = NOT g0_k AND NOT x_k, and

    t_k = t_(k+1) XOR B1_k AND (g0_(k-1) XOR g0_(k+1)).

A wire `tog` carries t_(k+1) into tick k (`TwoBitMod._sweep_in`).
The tick XORs it into b, which makes x_k, and takes sw = g0 AND x_k.
Then sw XOR g0 XOR b XOR 1 is B1_k, formed on the sw wire by X and CX, and one CCX against g0_(k+1) XOR g0_(k-1), formed on the next cell's g0 wire by CX, moves `tog` to t_k.
`tog` XORs into b again, which leaves the swept bit x_k XOR t_k.
sw is still g0 AND b, because t_k implies NOT g0_k.
The rest of the tick reads the swept cell as before, and step k's toggle of b_(k-1) is the next tick's first XOR.
At cell 0, g0 implies b, so B1_0 = NOT x_0, t_0 = 0, and one CCX, `tog` ^= NOT g0_1 AND NOT x_0, clears the wire.

**Where the chain starts.**
Where no step above has left a toggle on a cell, `tog` is 0 and the tick takes g0_(k+1) as 1; the CCX is then t_k = B1_k AND NOT g0_(k-1), which is t_k's definition.
That is the first general tick in both start shapes.
Without a rank-one start it is cell T - 2: step T - 1 never swaps, by "Sweep endpoint identities".
With a rank-one start of J cells, the start reads cells T - 1 to T - J swept, so `_bezout_pass` first runs steps T - 2 down to T - J in the old form (`_b1_sweep` with `lo = T - J`: a controlled swap and a mark transition a step, and one CCX to clear the mark at the end).
Step T - J swaps b_(T-J) and b_(T-J-1), so cell T - J - 1 enters its tick as x_(T-J-1), with `tog` = 0.
The first general tick has no previous cell in both shapes, so the tick reads g0_(k+1) from `prev` and needs no extra argument.

**The unsweep.**
The ticks' other gates leave every g0 and b wire as they found it, so the tape the pass leaves is the swept one, cell by cell.
`_body` then applies the inverse of the sweep and the tape is the one the inverse Euclid pass expects.
Without swap wires that inverse is `_b1_sweep` reversed, 2 CCX a step.

Per M this removes the sweep from both Euclid passes and adds one CCX to each general tick, the explicit steps of the rank-one cells, and one wire that is live through the Bézout pass.
At G: 2,961,008 -> 2,960,272 CCX (-736), T 20,727,056 -> 20,721,904, 4,096 wires, `CARRY_JUNK` unchanged at 1,161 because the Bézout pass is not the wire peak.
The Euclid pass keeps a `sweep` flag, on by default, so `model_check.py` and `utape_check.py` still check the swept pass; `_bezout_pass` takes `inline`, off by default, for the same reason.

## Swap bits on tape wires

With the inline sweep, each cell that a general Bézout tick reads, except cell 0, has one more wire, zero when M starts, that holds the cell's swap bit s = g0 AND b from its Euclid step to the inverse pass (`DialogMultiplier.SWAP_WIRES`, `swap_width` wires for cells 1 to `sweep_top`).
This too is PR #28's construction.

The Euclid step writes it with one CX from g1, right after g1 goes to b: g1 is the swap on a subtract and 0 elsewhere, so it is g0 AND b.
The inverse step, the same block reversed, clears it with that CX.
The rank-one cells need none, because their ticks are not the general tick; cell 0 needs none, because tick 0 always swaps and the cell-0 tick uses g0 for sw.

In the Bézout pass, tick k reads the wire where it used to compute sw = g0 AND x_k onto a fresh wire.
The two are equal: x_k = b_k XOR t_(k+1), and t_(k+1) implies NOT g0_k, so the sweep never changes a subtract cell's bit.
The tick forms [cell k is B1] = 1 XOR g0 XOR b XOR sw on that wire, as it did on the fresh one, and tick k - 1 reads it as its held mark.
Where tick k - 1 used to clear the mark with a CCX and free the wire, it now applies X, CX from g0_k and CX from b_k, which return the wire to s_k.
Tick k - 1 writes neither g0_k nor b_k, and b_k is the swept bit both times, so the wire is exact; cell 0's tick restores cell 1's.
The register the ticks hand on is then H's two top bits alone.

The unsweep is the inverse of `_sweep_sw`, which applies to the tape and `tog` the gates the pass applied to them: the rank-one start's explicit steps, then for each cell from `sweep_top` down, b_k ^= `tog`, `_sweep_in` with the swap wire, and cell 0's clearing CCX.
With s on a wire, B1_k = 1 XOR g0 XOR x XOR s is linear, so this sweep is one CCX a cell where `_b1_sweep` is two.

Per M and cell this removes the tick's sw CCX, its mark-clearing CCX and one unsweep CCX: 3 CCX, or 6 a point addition, against 4 CCX for the wire at the junk rate.
The 369 swap wires at n = 256 take `CARRY_JUNK` from 1,161 to 792.
At G: 2,960,272 -> 2,959,536 CCX (-736), T 20,721,904 -> 20,716,752, 4,096 wires.

The trade is at the junk rate's edge by construction, and the variants that reuse an existing wire come out equal, not better.
The retired-offset wire of each Euclid step holds g0 AND (the swap of the subtract before), so the swap bits are already on wires, one subtract late.
Bringing each to its own cell takes a running offset and a controlled swap a cell on the way down and another on the way back: 2 CCX a cell and M, 4 a point addition, which is the price of the wire it saves.
Writing the offset onto a fresh wire each tick instead of retiring it gives the same count.

`scripts/sweep_check.py` (accept's `I2.sweep`) checks both sections at gate level on ten primes from 7 to 4,093, with and without a rank-one start, over every x: the unswept pass against `tick_tape`, both sweeps against a model that shares no code with the circuit, the swap wires before and after, and M and its inverse.
Four mutants must each fail it: `_sweep_in` without its CCX, without its last CX, the mark restore without its X, and no unsweep.
`DialogMultiplier.INLINE_SWEEP = False` and `SWAP_WIRES = False` restore the previous constructions.
## Square leaves write row 0 without an adder

Ported from 2elliot's square branch (6b1f34d, on Mike's lowt-depth). In `_rows`, after row 0's Gray step Y[j] holds y_j XOR y_0 for j >= 1, and row 0 adds those bits onto Q[1:].

- Uncopied (T leaves), Q is still 0 there, so the add is a copy: Q[1:n] ^= Y[1:n], and there's no carry.
- Copied (R leaves), Q holds Y, and Y + 2*(row 0) is 2Y when y_0 = 0 and 2^w - 1 when y_0 = 1. So Q[0] = Q[1] = y_0, Q[k] = y_0 OR y_(k-1) for 1 < k < w, and Q[w] = NOT y_0 AND y_(k-1). Each NOT y_0 AND y_(k-1) equals NOT y_0 AND (y_(k-1) XOR y_0), which is one CCX from the Gray wire under X(y_0), and the ORs follow by CX from y_0. Bits at len(Q) and above are dropped, as the adder's would be mod 2^len(Q).
- So row 0 costs w - 1 CCX copied and 0 uncopied, in place of an adder of w - 1 bits. A leaf of width 1 is a copy or nothing.

Check: `scripts/rows_check.py . 11` builds `_rows` for every leaf width 1 to 11, every output length 1 to 2w, copied and uncopied, with and without a kept-carry list. On every Y it checks Q = Y(2^w - Y) or Y(2^w - 1 - Y) mod 2^len(Q) and that Y comes back: 528 configurations, 0 failing. Without kept carries, its outputs equal 0f5514b's bit for bit on every input.

At G: 2,961,008 -> 2,958,220 CCX (-2,788), at 4,096 wires.

## The second fold's loaded constant as a constant add

With 3a absorbed, the second fold starts from T = klo, loaded by X gates, and its first digit added E onto it with the ripple adder: 2 CCX a bit from bit 0, whatever klo's bits are.
Now `_multiple(..., load=True)` takes T clean, copies E onto it and adds klo with `add_const`: T = E + klo either way, and E + klo ≤ f + kE + klo < 2^top for top = bitlen(f + kE + klo), so the add on T[:top] carries nothing out and the wires above stay 0, as the bound the adder used already said.
`add_const`'s chain reads the constant, so the 0 bits below klo's lowest 1 cost nothing. At G klo has two of them, which is 4 CCX each way.
The later digits see the same T, and the chain's wires come from the ladder's lent wires, so the peak stays where it was.
`load` is only set when klo is nonzero; a fold with no absorbed constant still copies.

`scripts/fold_check.py` builds `compute` with every absorbed constant c at every fold prime of 4 to 8 bits, and 97 of them at 9 to 11 bits, runs every Y, and checks J[:n] = (Y² - c) mod q, Y unchanged, and every junk wire 0 after the reverse; it counts the builds that load a constant. At secp256k1 it samples Y, with the edges, for c = 3a and two random c.
Its controls make the constant's add one bit short, and drop the constant's lowest set bit; each fails thousands of lanes.
A BDD run of the second fold alone over every E ≤ f + kE at G (33 inputs) finds no CCX left there that never fires or has equal or constant controls; before this change it found exactly the four that the trailing 0 bits of klo account for.

At G: 2,958,220 -> 2,958,212 CCX (-8), 4,096 wires.

## S = A + B out of place

A Karatsuba node copied A onto S's clean wires and rippled B onto the copy, 2h - 1 CCX for halves of h bits, because an in-place adder builds each carry and takes it down again.
S is clean, so no carry needs taking down. `_sum` walks up from bit 0: while S[i] still holds the carry into bit i, it writes the carry into bit i + 1, MAJ(a_i, b_i, c_i) = c_i ⊕ (a_i ⊕ c_i)(b_i ⊕ c_i), onto S[i+1] with one CCX, and then S[i] takes a_i and b_i by CX and holds the sum bit.
Above B's top the carry is a_i ∧ c_i, still one CCX. That is h CCX, A and B are as they were, and S holds A + B on the same wires as before, so nothing after it changes; the pad wire the ripple took for an odd width is gone and the peak is where it was.

`scripts/sum_check.py` runs every (A, B) for h = 1 to 8 with B of h and of h - 1 bits, and every CCX dropped or turned into a CX from either control fails: 213 mutants, none unnoticed.
`scripts/fold_check.py` runs the whole fold on every Y at the small fold primes, where leaves of 3 wires put nodes at every level.

At G the 13 nodes save h - 1 each, both ways: 2,958,212 -> 2,957,012 CCX (-1,200), 4,096 wires.

The same holds for any sum written onto clean wires: a copy and an in-place add cost two CCX a bit, an out-of-place sum one.

## Rows 0 and 1 of an uncopied leaf as one out-of-place sum

An uncopied leaf copied row 0 onto its clean Q and then rippled row 1 onto it in place: 2w - 5 CCX for a leaf of w wires, or w - 2 with w - 3 kept-carry wires.
Q is clean when both rows arrive, so Q = 2 r_0 + 8 r_1 is an out-of-place sum, like S above: places 1 and 2 take r_0's bits alone, and from place 3 up the carry into place p + 1 is written onto Q[p+1] while Q[p] still holds the carry into p, then Q[p] takes its two bits. Place w has r_1's top bit and the carry only, and the carry out lands on Q[w+1].
That is w - 2 CCX and no kept wire.

Both rows' bits must be on wires at once. After the Gray steps of rows 0 and 1, Y[j] holds r_1's bit y_j ⊕ y_1 for j ≥ 2 and Y[1] holds y_1 ⊕ y_0, which is r_0's bit 1. r_0's bit j is y_j ⊕ y_0 = Y[j] ⊕ Y[1], so a CX from Y[1] puts it on Y[j] for the one step that reads it and a second CX takes it off; the step's other operand is Y[p-1], a different wire.
Writes at or above len(Q) are dropped, as the adder's were mod 2^len(Q). Q after the two rows is the number it was, so rows 2 on, their bounds and their kept carries are unchanged; KEEP's wires that row 1 used go to later rows at the same 1 CCX each way.
Leaves of fewer than 3 wires and copied leaves are as they were: a copied leaf's row 0 is not linear in Y, so it cannot be an operand of such a sum.

`scripts/rows_check.py . 11` checks `_rows` against Y (2^w - 1 - Y) mod 2^len(Q) on every Y for every width to 11, every output length, with and without kept wires, and now ends with controls: each of the 120 single-CCX mutants of the uncopied leaves of 3 to 7 wires breaks the contract.
`scripts/fold_check.py` and the toy curves run the leaves inside the fold on every input.

At G: 2,957,012 -> 2,955,952 CCX (-1,060), 4,096 wires.

## Fold digits onto a target that is 0 from some bit up

`_multiple` bounds the accumulator before each digit. Where that value is at least 0 and the digit adds, the target is 0 from bit z = bitlen(the largest bound) up, and the digit's ripple ran over those wires at 2 CCX a bit all the same.
Now the digit ripples in place below z only, with its carry out on target[z], which is clean. From z up the sum is out of place: the carry into bit p + 1 is a_p ∧ c_p, written onto the clean target[p+1] while target[p] holds c_p, and then target[p] takes a_p. That is one CCX a bit, and the last carry is dropped where the old bound already said the sum fits.
Past the digit's top wire the carry just stays where it landed. Digits that subtract, or that meet a value that may be negative, are as they were.
The first fold's low digit also takes this path with z at the digit's own top: its carry out lands on E[0] as a carry out, not through a padded ripple bit.

At G the first fold's digits at 2^0, 2^4 and 2^32 have 1, 4 and 23 such bits and the second fold's at 2^4 and 2^32 have 3 and 22.
`scripts/fold_check.py` has a third control: taking the target as clean one bit below the bound fails 5,966 lanes.

At G: 2,955,952 -> 2,955,844 CCX (-108), 4,096 wires.

## Two chain bits on one junk wire

A junk wire of the Euclid chain now takes two bits at 6 CCX, where it took one at 3 and the bit beside it ran in place at 4.
So each carry-junk wire saves 2 CCX a pass instead of 1, and a junk wire in M is worth 8 CCX instead of 4.
Nothing here depends on q; the cell is exact on every input of its domain, which is the single cells' domain: the junk wire 0 on entry, and g1 implies g0 on the way down.

**The cell.** `_pair_up` and `_pair_down` in `qec/point_add.py`, on wires A_0, B_0 (the lower bit's U and V), A_1, B_1 (the upper bit's), Cw (the carry into the lower bit, which the cell only reads) and J (the junk wire).
Write a_i, b_i for the bits (b is NOT vhat, as everywhere in the chain), c for the carry in, e_0 = a_0 ^ c, f_0 = b_0 ^ c, x_i = a_i ^ b_i, c_1 = MAJ(a_0, b_0, c) = c ^ e_0 f_0 and c_2 = MAJ(a_1, b_1, c_1).

**P1: the way up, 2 CCX.**
J takes p = e_0 (f_0 ^ x_1), then a_0, so J = k with k = a_0 ^ p = c ^ e_0 ^ e_0 f_0 ^ e_0 x_1 = c_1 ^ e_0 (1 ^ x_1).
So k is c_1 unless e_0 = 1 and a_1 = b_1, and MAJ(a_1, b_1, .) does not read its third input when a_1 = b_1.
A_1 and B_1 take k, and J ^= A_1 B_1 gives k ^ (a_1 ^ k)(b_1 ^ k) = MAJ(a_1, b_1, k) = c_2.
The lower bit's wires and Cw are as found, J holds the carry out for the bits above, and c_1 is on no wire.

**P2: the way down, 4 CCX.** Write P = g0 e_0.
- A_1 and B_1 take b_0; then B_0 ^= g0 e_0 ^ e_0, so B_0 = b_0 ^ e_0 ^ P.
- W = A_1 ^ B_0 ^ e_0 = a_1 ^ k ^ P = (a_1 ^ c_1) ^ e_0 (1 ^ x_1 ^ g0), and (x_1 ^ g0) W = (x_1 ^ g0)(a_1 ^ c_1), because y (1 ^ y) = 0 for y = x_1 ^ g0.
  J ^= (x_1 ^ g0) W turns c_2 = a_1 ^ x_1 (a_1 ^ c_1) into a_1 ^ g0 (a_1 ^ c_1), and J ^= x_1 makes it b_1 ^ g0 (a_1 ^ c_1), the upper bit's B output.
  This one product is the upper bit's unwind and its g0 select together.
- B_0 ^= e_0 leaves b_0 ^ g0 e_0, the lower bit's B output, written V_0 below.
- B_1 takes G = x_1 ^ V_0 ^ a_0 ^ g1, and A_1 ^= (e_0 ^ g1) G.
  With e_0 P = P and g1 P = g1 e_0 (g1 implies g0), (e_0 ^ g1) G = e_0 x_1 ^ e_0 x_0 ^ P ^ g1 x_1 ^ g1 x_0 ^ g1, and p ^ e_0 x_1 ^ e_0 x_0 = e_0.
  After the CX from B_0, Cw, A_0 (twice, around the next step) and g1, A_1 = a_1 ^ k ^ b_0 ^ (e_0 ^ g1) G ^ V_0 ^ c ^ g1 x_0 = a_1 ^ g1 (x_1 ^ 1), the upper bit's A output.
- A_0 ^= g1 (V_0 ^ c ^ 1): on g1, V_0 ^ c = b_0 ^ e_0 ^ c = x_0, so A_0 = a_0 ^ g1 (x_0 ^ 1), the lower bit's A output.
- Two CX leave B_1 = b_1 ^ g0 (a_1 ^ c_1) and J = B_1 ^ G, a function of the step's input, which the inverse pass, the same gates reversed, clears like any other junk.

So the four outputs are those of `_shared_difference`'s single cells, Cw, g0 and g1 are untouched, and the cell is 6 CCX.

**Layout and plan.** `_junk_split` gives a tick's m junk wires to its chain's bits from 1 up: singles first, then pairs, each pair's wire being the carry wire of the bit above it.
`_tick_plan` gives wires to pairs first, from the last tick back, and only then to the bit a tick of odd length has left; at n = 256 all 1,161 wires hold pairs, 2,322 bits.
`CARRY_JUNK` stays 1161: the pass's junk width and M's peak do not move. `JUNK_PAIRS = False` restores one bit a wire.

**How it was found, and what the search closes.**
`cell.c` and its variants (in the work directory, not the tree) search every circuit of a given CCX count on a cell's wires, with CX and X free: the state is the affine span of the wire functions on the cell's domain, and a CCX replaces one direction t by t ^ xy for x, y in a hyperplane that misses t.
It finds the single cells' known costs (in place 4, junk 3) and proves, for two bits: in place there is no 7-CCX cell with 2 or 3 CCX before g1 is known (S2's 2+5 and 3+4 splits), also with one clean wire borrowed and returned for 2+5; with one junk wire 6 CCX exists and 5 does not with two.
A plain adder gets nothing from the same idea: two bits on one junk wire cost 3, not 2.

At G: 2,961,008 -> 2,956,364 CCX (-4,644), T 20,727,056 -> 20,694,548, 4,096 wires.

**Checks.** `scripts/pair_check.py`: the cell on all 96 inputs (c_2 at the top, the four outputs, Cw, g0 and g1 restored, the reversed halves restoring the input); 61 mutants, each gate dropped and each CCX turned into a CX from either control, all caught; then M and its inverse as gates on every x at every odd prime from 11 to 257 and every junk budget from 0 to the full plan, 919 builds with 0 bad lanes, 868 with a pair, 133 with a single beside pairs, 764 with a pair under an in-place bit; `JUNK_PAIRS = False` agrees; dropping `_pair_down`'s last CCX gives 162 bad lanes.
`scripts/model_check.py`'s junk model now computes a pair's wire, b_0 ^ a_0 ^ a_1 ^ g1 ^ g0 (a_0 ^ c_0 ^ a_1 ^ c_1), independently of the gates, and its pass rows match it on every x at its primes and on the secp256k1 rows.
`schedule_check.py` and the full `accept.py` pass: 13 pass, 0 fail, 1 pending.

### The lazy run and the lag blocks at the new junk price

A lazy or lag tick leaves junk wires, and each is now a carry-junk wire's 2 CCX a pass forgone, not 1.
Re-run at a fixed junk width of 2,718, `LAZY_END` = 11 (from 9) and `LAG_BLOCK` = (15, 7, 5, 3) (from (15, 7, 3)) give the least pass: 272,459 CCX against 272,481, with `CARRY_JUNK` = 1169 filling the 4,096 wires.
Other ends (None, 5, 7, 8, 10, 12, 13, 16, 24), `HIGH_MIN` 2, 4 and 5, other length sets (with 2, 4, 6, 9, 11, 13, 31) and shorter `LAG_SPAN`s are no better; a junk term in the lag planner's own cost does not help either.
Both knobs only choose among plans the tree already builds: `schedule_check.py` now runs its forced-length rows at 5 as well, and it, `model_check.py` and the full `accept.py` pass on the new plan.
At G: 2,956,364 -> 2,956,276 CCX (-88), 4,096 wires.

### Counted strips cleared where the threshold stays

A lag tick used to leave its counted strip x = two AND NOT flag as junk for the block's realign and the inverse pass.
On a tick that keeps its threshold (fmode same) the wire is now a clean one borrowed to the block's end, where `_lag_clear` clears it with one CCX after the realign; the tick itself and the realign are unchanged.

After such a tick the cell's b holds two ^ g1, and g1 implies g0.
The flag update left zg = g0 * flag on its junk wire and flag ^ zg = flag AND NOT g0 on the flag's, so NOT g0 AND NOT flag = 1 ^ g0 ^ flag ^ zg = 1 ^ g0 ^ (the flag the tick left).
The flag a tick left is linear in what the block's end still holds: the XOR of the g0 * flag wires of the same ticks after it up to the next drop tick's kept flag, or the live flag, exactly the chain `_lag_tally` already reads.
So b AND NOT (g0 ^ flag left) = (two ^ g1) AND NOT g0 AND NOT flag = two AND NOT flag = x, since g1 AND NOT g0 = 0 and two implies NOT g0, and one CCX on a clean wire that takes g0 ^ flag left clears x.
Nothing between the tick and the block's end writes the cell, the flag wires or the strip.
On a tick whose threshold drops, g0 * flag is not kept, the same clear would take 2 CCX, and the wire is worth 2 a pass, so those strips stay junk.

At n = 256 this frees 106 junk wires at +106 CCX a pass; `CARRY_JUNK` goes from 1169 to 1275 and the 106 wires take 212 more chain bits as pairs. `LAG_CLEAR = False` restores the junk strips.
At G: 2,951,112 -> 2,950,688 CCX (-424), 4,096 wires; the Euclid pass borrows at most 15 more clean wires at a time (4,004 against M's 4,093).

**Checks.** `scripts/lag_check.py` runs M and its inverse as gates with forced block lengths, where toy plans have lag ticks that keep their threshold: every x at q = 4093, 8191 and 65521 (blocks of 1 and 2), and powers of two, values near q and q/k and 3,000 random x at 22, 28, 40 and 61 bits (blocks of 3, 5 and 7): 24 cleared strips, 52,958 inputs with a strip set at one of them, 0 bad lanes, and the same with `LAG_CLEAR` off.
Its controls, the clearing CCX dropped and the flag left out of it, give bad lanes in all 8 builds; at secp256k1 with the plan as built, 500 inputs give 0 bad lanes and the dropped-CCX control fails.
`model_check.py`'s junk model drops the strip of those ticks; it, `schedule_check.py`, `pair_check.py` and the full `accept.py` pass.

### The lazy run's clean wires are borrowed, not junk

The first lazy tick used to bring V's extra wire, the pending borrow's wire and the whole counter as junk wires.
V's extra wire is 0 again when the run ends (the last tick clears it), and so is every counter wire above the last tick's width m_out: the counter is sign-extended, and each tick whose width shrinks clears the copies it drops.
Where the run ends at LAZY_WINDOW + 1 bits the last tick clears the whole counter.
So the pass now takes V's extra wire and the counter's wires above `_lazy_kept` from the allocator at the first lazy tick and frees them after the last; only p's wire and the `_lazy_kept` counter wires that still hold rho stay in the junk register.
No gate changes: the same wires are 0 at the same point, they just stop being held through the Bezout pass.

At n = 256 the counter is 8 wide and ends 5 wide, so 4 wires leave the junk register and `CARRY_JUNK` goes from 1275 to 1279.
At G: 2,950,688 -> 2,950,656 CCX (-32), 4,096 wires.

**Checks.** `model_check.py`'s junk model no longer lists those wires, and its gate rows require every wire outside the registers to end 0, which covers a borrowed wire given back dirty.
`scripts/lag_check.py` adds rows for the run: every x at q = 1021, 4093 and 8191 with `LAZY_END` None, 4 and 5, and sampled x at 20 and 32 bits where the run keeps fewer counter wires than the counter has: 11 builds, 0 bad lanes; keeping one counter wire fewer than `_lazy_kept` says, the control, fails in all 4 builds that keep any.
`schedule_check.py` and the full `accept.py` pass.

### The high word's top borrow goes straight to its target

`_high_word` ran its borrow ladder E_0 .. E_R on scratch, copied the top borrow E_R out, and unwound the whole ladder, so E_R cost two CCX and a third in the lazy window, where E_R s goes to g1 and the rest of E_R to p.
With `TOP_BORROW_DIRECT` the ladder's last CCX writes E_R onto the wire that wants it, and that step is not unwound.

A whole high word (not a lazy window) wants g1 ^= E_R: the last CCX targets g1. Nothing reads g1 between that CCX and the old CX, so the map is the same, one CCX less.

A lazy window wants g1 ^= E_R s and p ^= E_R AND NOT s, with s the sign of rho (no 1 from cut up in U or in physical V) and p the pending borrow.
The last CCX now targets p, which then holds p ^ E_R, and g1 takes (p ^ E_R) s with one CCX; the two CX that follow are the old ones and leave p ^ E_R ^ E_R s on p.
(p ^ E_R) s = E_R s because p s = 0 whenever a tick reaches its high word: by then the raw bit and the second strip have met p, so physical V is the true V plus p 2^cut, the invariant `schedule_check.py` follows (`phys - (p << cut) == V`). The true V is not negative, so a set p puts physical V at 2^cut or more, which is a 1 from cut up, rho >= 0 and s = 0.
If p s were 1 at some tick, g1 would be flipped there, so M as gates is the test of this.
That is one CCX less a lazy tick, and one less a whole high word.

At G: 24 whole high words and 349 lazy ticks a pass, 373 CCX a pass: 2,950,656 -> 2,949,164 CCX (-1,492), 4,096 wires; `CARRY_JUNK` stays 1279. `TOP_BORROW_DIRECT = False` restores the old gates.

**Checks.** `scripts/window_check.py` runs M and its inverse as gates with `TOP_BORROW_DIRECT` on and off, every x at q = 1021, 4093, 4099, 8209, 16411, 32771, 65537 and 65539 and sampled x at 20, 32 and 61 bits, with `LAZY_END` varied so that whole high words appear: 16 builds, 0 bad lanes either way.
A pending borrow is rare: no x sets p at the primes just under a power of two (the toy primes of the other checks, and none of 6,861 inputs at secp256k1 did in the junk model), but at a prime just above one hundreds do. At the six such primes here 2,268 inputs set p and 424 reach a later high word with it set, counted from `model_check.py`'s arithmetic model of p.
Controls: the lazy ladder's last CCX dropped fails in 16 of 16 builds, g1 taking p ^ E_R without s in the 10 of 10 where p is set, and a whole word's last CCX dropped in 7 of 7; at secp256k1 with the plan as built, 519 inputs give 0 bad lanes and the first control 456.
`lag_check.py`, `schedule_check.py`, `model_check.py` and the full `accept.py` pass.

### The lazy window as one cell of 6 CCX

A lazy tick's high word is always the same small map: the two window bits of U and V, the carry in cw, g0, z and zg, g1, and the lazy s and p. As a ladder it took 8 CCX (9 before the top borrow went straight onto p).
With `LAZY_CELL` it is a fixed gate list, `_LAZY_CELL`, with 6 CCX and no scratch wire, found by an exhaustive search over circuits on the window's domain. 6 is the floor for this map on this domain: its outputs need six products that are independent of each other and of the inputs.

The cell equals the ladder on the domain, not everywhere, so the domain is the proof's content. At a lazy tick's high word:

1. U's two window bits or V's are 0, z = 1 beside bits of U's and z = 0 beside bits of V's, zg = g0 z, g1 = 0. This is `_high_word`'s own contract: the tick's threshold kappa is the joint one, so U and V are not both at 2^kappa or more, and z is the flag [U >= 2^kappa]. With p = 0 the physical V is the true one.
2. p s = 0 (the section above).
3. A set p finds z = 0, U's window bits 0 and V's both 1. The carry cw and g0 are left free.

For 3, follow a pending borrow from the subtract that set it, at threshold k0 and cut c0 = k0 + 2. The larger register was H 2^c0 + L with H >= 1, window 0 and L below the smaller one, m; the tick left U = m and the true V = ((H - 1) 2^c0 + 2^c0 - (m - L)) / 2.
Claim: while p stays set, at each later lazy tick with threshold k and cut c = k + 2, once the tick's crossing bits have met p, physical V = P 2^c + 2^c - d - e with P >= 1, 1 <= d <= u, e the held offset bit, and u = m unchanged with u < 2^k / 9.
It holds after the setting tick with P = H and d = (m - L) / 2. Each tick halves V once, or twice with a second strip, and the cut drops by one or stays. A strip halves d; a subtract has V > U, so it does not swap, and takes d to (d + u) / 2 <= u; d stays at least 1 because each halving is of an even number. A halving that the cut follows keeps P. One that it does not follow, at a tick that keeps its threshold or strips twice, brings P's low bit to p: a 1 clears p and ends the run, a 0 leaves P / 2 >= 1.
The true V is at least 2^c - d - 1 >= 3 * 2^k, and the pass's potential bound max^2 min 4^t <= 2 q^2 x < 2^(3 k + 2 t) at a high tick gives u < 2^k / 9.
So under p: U < 2^k, which is z = 0 and U's window bits 0; V's bits below c are 2^c - d - e > 2^c - 2^k, so its window bits are both 1; and P >= 1 is a 1 from cut up, s = 0 again.
These are the lazy run's own invariants: `_lazy_plan` states them and `schedule_check.py`'s `lazy_states_ok` asserts them at every lazy tick of the recurrence (`z and (hi or p)`, `p and hi & mask != mask`).

On that domain, 68 points, the cell and the ladder agree on every wire. Outside it they differ (26 of the 28 further points with p s = 0), so the domain is used.

At G: 349 lazy ticks a pass, 2 CCX each: 2,949,164 -> 2,946,372 CCX (-2,792), 4,096 wires; `CARRY_JUNK` stays 1279. `LAZY_CELL = False` restores the ladder.

**Checks.** `scripts/window_check.py`, in four parts.
The cell against the ladder with both switches off, on all 68 points: 0 wrong; the cell has 6 CCX in 115 gates, none on a scratch wire, and dropping any one gate gives a wrong point.
The domain as the gates see it: M with a marker in front of each lazy window, every x at q = 4099, 8209, 16411, 32771, 65537 and 65539, all 3,166,842 tuples the windows find on the forward pass: none outside the domain, 827 with p set.
M and its inverse as gates on the same 16 builds as before, with the cell, with the direct ladder and with both off: 0 bad lanes. Controls: the cell without each one of its CCX fails wherever some x sets p (one of the six only acts where a borrow stays pending, and fails nowhere else), and the three ladder controls fail as before.
secp256k1 with the plan as built, 519 inputs: 0 bad lanes, and the cell without its first CCX fails.
`lag_check.py`, `schedule_check.py`, `model_check.py`, `pair_check.py` and the full `accept.py` pass.

### A lazy tick's junk is the bit its second strip brought

A lazy tick made spare = b r on a scratch wire, r = V[cut] the bit its second strip brings to the window's top, counted with it, and took it back after the strip against the bit's new place. Then it made t = b p on its junk wire, gave the bit t, and took t AND NOT (the new bit) off p. That is 4 CCX and a junk wire holding b p.
With `STRIP_BIT_JUNK` the spare is made on the junk wire and never taken back. The bit takes b p with one CCX from b and p, and p loses (b r) AND NOT (the new bit) with one more: 3 CCX, and the junk wire holds b r.

The map on V and p is the same. The bit takes b p either way. Off b nothing happens in either. On b the new bit is r ^ p, and p lost p AND NOT (r ^ p) = p r before; now it loses r AND NOT (r ^ p) = r p.
The junk only has to make the meeting reversible, and the inverse pass, the same gates backwards, is its only reader: (r, p) -> (r ^ p, p AND NOT r) sends (0, 0) and (1, 1) to (0, 0), and r tells them apart as well as p does.
The counting between is unchanged, the same wire values on another wire. No condition on the inputs is used.

At G: one CCX less in each of the 349 lazy ticks of a pass: 2,946,372 -> 2,944,976 CCX (-1,396), 4,096 wires; `CARRY_JUNK` stays 1279. `STRIP_BIT_JUNK = False` restores the old gates.

**Checks.** `model_check.py`'s junk model has b r on that wire (`_lazy_pending` hands it the bit) and its pass rows compare every junk wire; but no x sets b r at the primes it runs the pass on, so `scripts/window_check.py` runs the same comparison, the pass alone as gates against the model's U, tape and junk, on every x at q = 4099, 8209, 16411, 32771 and 65537: 0 bad bits, 137 inputs with b r set, and the model with b p on that wire fails at all five.
Its M rows run with the switch on and off, 0 bad lanes, and two more controls, the CCX onto the bit dropped and the CCX onto p dropped, fail on all 8 builds where some x strips twice under a pending p (129 inputs; they only act there).
`lag_check.py`, `schedule_check.py`, `pair_check.py` and the full `accept.py` pass.

### The lazy counter's step: last carry straight onto the top bit, two bits by a majority

`_count` adds a bit to the lazy counter through a ladder of carries on scratch, a_(i+1) = a_i reg_i, XORs each carry into its bit from the top down and takes each one back: 2 (n - 1) CCX on n bits.
With `COUNT_SHORT` the last carry, the one into the top bit, is written onto that bit by the CCX that would have made it: reg_(n-1) ^= a_(n-2) reg_(n-2). Nothing else reads that carry, the CCX's controls are not its target, and the rest of the ladder is as before, so the map is the same in 2 n - 3 CCX.

A raw tick steps the counter down by two bits at once, the bit at cut - 1 and the spare b r. It made both = bit AND spare on scratch (one CCX), counted with ctl = bit ^ spare and both XORed into the carry out of bit 0, and took both back (one more).
That carry, ctl reg_0 ^ both, is the majority of bit, spare and reg_0. `_count` now takes the second bit as `also` and makes the carry as bit ^ (bit ^ spare)(bit ^ reg_0), one CCX between CX pairs that restore spare and reg_0; bit 0 then takes bit ^ spare as before. The same carry, without the wire for both and its two CCX.

At G: 349 counter steps a pass lose one CCX and the 116 raw ones two more: 2,944,976 -> 2,942,652 CCX (-2,324), 4,096 wires; `CARRY_JUNK` stays 1279. `COUNT_SHORT = False` restores the old gates.

**Checks.** `scripts/window_check.py` runs `_count` alone as gates on 1 to 8 bits, up and down, with one bit and with two: all 6,104 pairs of a register value and a step give the sum with the step bits kept and the scratch clean, each counter has 2 n - 3 CCX, and up to 6 bits no gate can be dropped without a wrong case.
Its M rows run every build with the switch on and off: 0 bad lanes. `lag_check.py`, whose lazy-run rows end the run with the counter in every state, `schedule_check.py`, `model_check.py`, `pair_check.py` and the full `accept.py` pass.

### The lazy run's end at the lazy tick's new cost

A lazy tick is now 6 CCX cheaper than when `LAZY_END` was set (the window cell, the strip's junk bit, the counter step), and a whole high word only 1. Re-run at the fixed junk width of 2,718, the pass is least with the run ending at 8 bits: 270,317 CCX against 270,344 at 11 (270,318 at 7, 270,322 at 9); the lag blocks (15, 7, 5, 3) stay the best of the sets tried.
Ending earlier leaves 11 fewer junk wires to the run's ticks, so `CARRY_JUNK` goes from 1279 to 1268 to keep 4,096 wires. No gate is new: the plan's lazy run is 9 ticks longer and 9 whole high words become lazy ticks.

At G: 2,942,652 -> 2,942,544 CCX (-108), 4,096 wires.

**Checks.** `schedule_check.py` checks the plan's lazy fields and states for every `LAZY_END` it is given and for the built plan; `lag_check.py`, `model_check.py`, `pair_check.py` and the full `accept.py` pass.
`scripts/window_check.py` runs as before and gains a secp256k1 part that does exercise the pending borrow there: none of the sampled or hard inputs sets p at secp256k1, but x = q - 2^j - r with a small r often does. The run draws such x from a seed and keeps the 48 that the model says set p (17 reach a later high word with it set, 10 strip twice under it): 0 bad lanes for M and its inverse on them and on the 519 sampled inputs, and on those 48 all ten controls fail (the cell without each of its six CCX, the two strip controls, and the ladder's no write and no s).

## One carry chain for a compare and its conditional subtract (rank_one.sub_if_ge)

The rank-one start reduces by U in four places with the same pair: `greater` makes flag = [b ≥ a], 2 CCX a bit, and `sub` under the flag takes a off b, 3 CCX a bit. Both ripple the same carries, those of a + ~b.
`sub_if_ge(C, a, b, flag, ctl)` ripples them once. The majority sweep of a controlled adder does not read its control, so it runs first on a + ~b; its top carry is [a > b], which a CX and an X (or a CCX and a CX under ctl) turn into the flag; and the sweep back down, `_cuma` under the flag, restores a and writes ~b + flag·a, which the X gates around make b - flag·a.
That is 3 CCX a bit and the same wires: one carry-in wire and a's zero extension.

It replaces the pair in `_mod_double` (both forms), in `_mod_add`, and in `residue`'s quotient loop; nothing else in those functions changes, and no other function of rank_one.py is touched.

`scripts/subge_check.py` builds the helper and the old pair for len(b) = 1 to 7, len(a) = len(b) and len(b) - 1, with and without ctl, and runs every (a, b, ctl): both leave flag = ctl·[b ≥ a], b - flag·a, a and ctl as found and every other wire 0. Each of the helper's CCX dropped, or turned into a CX from either control, fails: 549 mutants, none unnoticed.

At G: 2,942,652 -> 2,939,472 CCX (-3,180), 4,096 wires; the Bézout pass goes from 888,721 to 887,131.
`scripts/m_check.py` runs the multiplier itself, M(x, y) = (x, x·y mod q) with every other wire 0, where the rank-one start is on: every (x, y) at q = 61 (J = 3) and 251 (J = 4), and 40,000 sampled pairs with the edges at 4093 (J = 9) and 8191 (J = 12); a flipped bit after each `sub_if_ge` fails 12,750 lanes.

## The last row of the convert's clearing product as a copy (rank_one.mul_acc)

`convert` ends by clearing D: D·q - U·s + V·r is 0 mod 2^(w+1), as three products added onto D, each row a controlled add at 3 CCX a bit.
The adds commute, so the subtraction of U·s now comes last, and inside it row 0 comes last. D is 0 after that row, which is the tree's own claim when it frees D, so before it D holds U_0·s: the row is a controlled copy off D, `ccx(U_0, s_i, D_i)`, one CCX a bit. This is the out-of-place rule run backwards: a sum that ends on clean wires needs no carries either.
`mul_acc(..., sign=-1, clears=True)` does this; without `clears` it is as it was. On every input where the old order left D at 0, the new one leaves the same wires, since each differs from the old only by that last row's form.

`scripts/mulacc_check.py` runs every (a, b) for 1 to 5 wires with acc = a·b: acc ends 0, a and b as found, and all 165 single-CCX mutants fail. `scripts/m_check.py` runs M with the start on.

Changes `rank_one.mul_acc` and the order of two calls in `RankOne.convert`. At G: 2,939,472 -> 2,939,412 CCX (-60), 4,096 wires.

## The residue's nonzero test read once (RankOne._and_nonzero)

`residue` twice needs ctl ^= sigma·[N ≠ 0]. It made a copy of [N ≠ 0] on a fresh wire, which builds the zero chain and takes it down, used it in one CCX, and cleared the copy, which builds and takes down the chain again: 4(w - 1) CCX for one product.
`_and_nonzero(C, x, ctl, t)` builds the chain once, does t ^= ctl·[x ≠ 0] as a CX and a CCX from the chain's top, and takes it down: 2(w - 1) + 1, and one wire fewer. N does not change between the old copy and its clear, so the product is the same.

`scripts/nonzero_check.py` runs every (x, ctl, t) for 1 to 8 wires, and all 192 single-CCX mutants fail; `scripts/m_check.py` runs M with the start on.

Adds `RankOne._and_nonzero` and changes two three-line stretches of `RankOne.residue`. At G: 2,939,412 -> 2,939,188 CCX (-224), 4,096 wires.

## The fold's probe read off the carry sweep (RankOne.fold)

The fold's probe needs e ^= top·[prod + lo ≥ 2^W], with top the Prefix's AND of the high bits. It copied the carry onto a fresh wire c1 with `carry_into`, a sweep up and a sweep down, did `ccx(top, c1, e)`, and cleared c1 with a second `carry_into`: 4W CCX.
`carry_into` already takes a control for its one write, so `carry_into(C, prod, lo[:W], e, ctl=top)` writes the product straight from the sweep's top wire: 2W + 1 CCX and no c1. prod, lo and top do not change between the old copy and its clear, and the sweep reads only prod and lo[:W], which the Prefix's wires are not among, so e takes the same value.
Without high bits the write is the plain CX, as before.

The toy primes' folds have no high bits, so they run only the uncontrolled write, before and after this change. `scripts/probe_check.py` therefore builds the old stretch and the new call on the same wires for W = 1 to 6 and runs every (prod, lo, top, e): both leave e ⊕ top·carry and everything else as found; the call without its control and all its single-CCX mutants differ, 150 in all. `scripts/m_check.py` runs M with the start on at q = 61, 251, 4093 and 8191, and `accept.py` samples secp256k1.

Changes eight lines of `RankOne.fold` (the c1 stretch) and nothing else; the fold holds one wire fewer there. At G: 2,939,188 -> 2,938,804 CCX (-384), 4,096 wires.

## The residue's U - N with the 1 as a carry in (rank_one.add cin)

`residue` maps N to U - N under ctl as ~N + 1 + U: a complement by CX, an increment under ctl at 2 CCX a bit, and an add of U under ctl at 3.
The increment is the add's carry in. `rank_one.add` gains `cin`: the wire's bit is copied onto the adder's own carry-in wire by a CX before the ripple and taken off after, and the ripple restores that wire as it does any carry. Under a control only the writes onto b are gated, so with cin = ctl the add writes ~N + U + 1 when ctl is 1 and nothing when it is 0.
The increment is gone: 2(w - 1) CCX each time.

`scripts/addcin_check.py` builds the old stretch and the new one for 1 to 6 wires and runs every (U, N, ctl): both leave (U - N) mod 2^n under ctl, N otherwise. It also checks the uncontrolled add with a carry in against b + a + c. The stretch without its carry in and all its single-CCX mutants fail: 158, none unnoticed. `scripts/m_check.py` runs M with the start on.

Changes `rank_one.add` (new optional argument, no change without it) and one stretch of `RankOne.residue`. At G: 2,938,804 -> 2,938,692 CCX (-112), 4,096 wires.

## Five wires off M's peak in the rank-one start

M's widest moment is the rank-one start's conversion, not a tick: at `CARRY_JUNK` = 1279 the fold's corrected product, the residue and the small pass all stood within six wires of M's 4,093.
Three changes in `qec/rank_one.py` take 5 wires off all of them, and `CARRY_JUNK` goes from 1279 to 1284 at the same 4,096 wires. None changes the map of any block, and none depends on q.

**The fold lends its zero wires.** With f = 2^t + c, the product's own wires are c*(hi + 1) on `low` and zero wires from there up to t, 6 at n = 256.
Those wires are only places for a ripple's carries to pass: `_times` writes `low` alone, and the probe's `carry_into` and the final MAJ/UMA ladder leave their a wires as found.
So `product()` takes them just before each ripple and the fold frees them after it, and the corrections between the probe and the write, `dec` on hi and the controlled constant add on `low`, the fold's widest steps, run on them.

**The small pass runs before the residue.** `small_pass` acts on (cells, U, mR, sp) and `residue` on (U, D, Q). They share only U, and each leaves U as found on every input, so as permutations of basis states they commute.
The pass maps (mR, 0) to (0, V*mR mod U), which the tree already relied on when it freed mR and sp's top wire at the end. Run first, it gives mR's w wires and sp's top back before Q is taken, so the pass no longer holds Q and the residue holds sp's w wires in place of mR's.
The residue, the XOR that clears sp against D mod U and the residue's inverse follow unchanged.

**An incrementer on its own carries.** `inc(x, ctl)` was an adder with a one-wire addend, zero-extended: k - 1 zero wires, a carry-in and a copy of ctl. It is now the chain c_1 = ctl x_0, c_(i+1) = c_i x_i on k - 1 wires.
From the top down, x_i takes c_i and then c_i is cleared by the AND that made it, whose inputs c_(i-1) and x_(i-1) are still as found; x_0 takes ctl last. 2(k - 1) CCX as before, two wires fewer. `dec` is `inc` between complements, since ~(~x + c) = x - c.
With no control it adds the constant 1, which the fold's hi + 1 and the conversion's -x = ~x + 1 did with a wire set to 1: x_0 itself is the carry into bit 1, so the chain is one AND shorter, 2 CCX less at each of three places a start.

At G: M's peak 4,093 -> 4,088 wires at `CARRY_JUNK` 1279; at 1284 the build is 4,096 wires again (1285 gives 4,097).
2,938,692 -> 2,938,640 CCX (-52): -40 from the five junk wires, -12 from the constant increments. The residue's steps (4,088 and 4,087 at 1279) and the fold's constant add (4,087) now sit together, and the small pass is 10 below, so a sixth wire needs the residue's chain of 14 `small` wires, its zero test and the fold's 24 carries all cut.

**Checks.** `scripts/start_wires_check.py`: `inc` (with and without a control) and `dec` on every input of 1 to 7 bits with every other wire 0 after; `residue` on every U in [1, 2^w) and D in (-2^w, 2^w) for w = 2 to 6; `fold` on every X < 2^w q at eight (q, w), six of them primes whose f splits with 1 to 4 lent wires (479, 991, 3967); M as gates on every (x, y) at q = 61, 127, 251 and 509, where the start runs with J = 3, 6, 4 and 7.
Mutants, all caught: an incrementer without its low bit, one that clears its carries after the sum, and a wire flipped just before each `free` call of `fold` and `convert` (in M at q = 61 and 127, and in each fold), which is the claim that every wire these changes give back is clean and needed clean.
The full `accept.py` passes: 13 pass, 0 fail, 1 pending.

## J and the swap on one wire in the start's semantic cells

A semantic cell of the rank-one start (the cofactors' cells, the small pass's, and the start's last tick) made j = b AND NOT g0 on a wire, used it, cleared it, then made sw = g0*b on a wire, used it and cleared it: 4 CCX.
Since j = b ^ g0*b, `_kind` makes g0*b once and a CX from b turns it into j; after j's use `_kind_swap` turns it back into sw with the same CX; `_kind_off` clears it with the CCX that made it: 2 CCX.
The gates between read g0 and b only (the cofactors' controlled double, the small pass's `_mod_double` under j, the last tick's double and its l0 = g0*R_0), so the wire holds exactly j where j was read and exactly sw where sw was read, and each cell's map is the same on every input. Nothing depends on q. The middle cells' `tick` already shared its wire this way.

40 cells a start at n = 256 (13 cofactor cells run forward and back, 13 in the small pass, the last tick), 2 CCX each: 2,938,640 -> 2,938,480 CCX (-160), 4,096 wires, `CARRY_JUNK` stays 1284.

**Checks.** `scripts/start_wires_check.py`'s M rows (every (x, y) at q = 61, 127, 251, 509) run every cell kind in all three places; two mutants are caught there: a cell that swaps on its J wire (no CX back), and a J wire that holds b.
`scripts/m_check.py` (the start up to q = 8191, J = 12) and the full `accept.py` pass: 13 pass, 0 fail, 1 pending.

### The three branches together

The lazy run ending at 8 bits (`CARRY_JUNK` 1268 on its own branch) and the start's five wires (1279 -> 1284 on theirs) meet at `CARRY_JUNK` = 1273: 4,096 wires, and 1274 gives 4,097.
At G with the square branch's rank-one commits, the start's wires and cells and the lazy end: 2,938,372 CCX. `start_wires_check.py`, `window_check.py`, `m_check.py` and the full `accept.py` pass on the merge: 13 pass, 0 fail, 1 pending.
