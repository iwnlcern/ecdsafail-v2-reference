# Exact controlled point addition for `secp256k1-controlled-exact-v1`

## Current mux contract

The merged path now uses the paired-tick contract D1-D4 in [the mux proof](docs/mux-proof.md), superseding the older unrestricted canonical per-symbol Bézout-cell claims below. Logical T and R are canonical and scratch starts clean, but after a non-final B1 the physical word stores H = 2T + R in S4's encoded form, borrowing the next cell's g0 for its high bit. A semantic subtract follows B1; next.g0 must be 1 before holding; a final B1 requires R = 0. The held tick restores the borrowed symbol. Fallback primes retain the old step.

The additional sweep rotates each no-subtract run so B1 is last in Bézout order.
It runs in Euclid's tail, one cell behind the offset sweep, with which it commutes: the offset sweep's swap acts only on b of g0 = 1 cells, and each B1 step only on b of two g0 = 0 cells.
So Euclid hands Bézout the B1-swept tape, and inverse Euclid unsweeps it before undoing its steps; this supersedes the placement in S2's last sentence and S17's last sentence of the mux proof, not the maps they state.
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

## Kept bottom carry for bit one

This branch builds on ab-godder's `mike/comp-ab-godder-pr9-286e36a3ba9f` (`lowt-mike` at `db9ae43`) and adds one edit, in `qec/two_bit.py`.
`_chain_down` now takes `keep = 1` from the add's second chain, so that chain's bottom carry c1 = l0 AND k0 stays built past the compare instead of being cleared.
On a held lane l0 = R0, so c1 is the k0 AND R0 term of bit one, and bit one reads it from c1 instead of computing and uncomputing it on a fresh wire around its use.
c1 is cleared with one CCX, l0 AND k0, after the B1 drop and before k0 changes, and its wire is freed.
Every tick call with a previous cell saves 2 CCX, 764 of the 766 calls at secp256k1, so the circuit at G loses 1,528 CCX at the same 3,135 wires.

## Junk wires under the wire cap

This branch builds on iwnlcern's `jack/comp-iwnlcern-pr10-0e70e4252785` (`v2/lowt-c1` at `a4d4c28`).
That circuit peaks at 3,135 wires, in the square, and the multiplier M runs at 1,312.
The cap is 4,096, and qubit-time at 4,096 wires stays below the reference's.
So this branch fills the wires up to the cap with junk that saves CCX, in two places.

**The rule.** A block that is applied forward and later inverted, with nothing in between writing a wire the block read, is a compute and uncompute pair.
Inside such a block, a temporary that the block clears with a CCX can stay set on a wire of its own.
The forward block loses the CCX that cleared it, and the inverse loses the CCX that rebuilt it.
The wire holds a function of the block's input, so the inverse meets the value it expects.
The price is one wire, held from the forward block to its inverse.

**Euclid carries** (`_shared_difference`, `_euclid_step`, `_euclid_pass` and `_body` in `qec/point_add.py`).
M is the forward Euclid pass, the Bezout pass, and the inverse Euclid pass, and the Bezout pass restores every wire the Euclid pass wrote.
A step's shared difference builds its carries in place on U and spends one CCX a bit to restore a_i.
With `junk` set, the carry out of each bit 1..k goes onto a junk wire as c ^ (a ^ c)(b ^ c), which leaves a_i and b_i in place, so those bits need no restore: 3 CCX a bit, not 4.
The bits above k run the in-place chain as before, with the last junk wire as their carry in, which their unwind restores.
The step's second-strip flag `two` can also stay on a junk wire, which drops the CCX that cleared it.
`_euclid_pass` hands the junk wires to its steps in order, each step's carries first and then its flag, and skips the first step, which may be `_euclid_tick0`, and the last.
`_body` allocates the junk before the forward pass and frees it after the inverse pass.
Each wire saves one CCX in the pass and one in its inverse, and M runs twice, so a wire is worth 4 CCX.

**Square row carries** (`_keep_add`, `_rows` and `SquareFold` in `qec/square.py`).
ab-godder's `SquareFold.KEEP` already did this for the Karatsuba leaves' rows and was left at 0.
It is now a constructor argument, and a row that K cannot cover in full keeps the carries K still has and finishes as a plain add.
Compute runs once and its inverse once, so a wire is worth 2 CCX.
`_Lend` lends the fold's wires E, T, t, c and k, which are clean until the fold, to the allocator during the Karatsuba recursion.
Its adds then take their pads and constant-add carries from those wires, and compute's own scratch falls from 128 wires to 32, below the modadd's 41.
That gives 87 more wires to the rows.

**The budget** (`ControlledPointAdd._junk_budgets`).
Each stage is built alone with no junk to find its peak, and the room left under `WIRES_PER_BIT * n`, 4,096 at n = 256, is the stage's budget.
At secp256k1 that is 2,784 wires for each Euclid pass, of the 65,279 it could use, and 1,048 for the square's rows.
The circuit at G loses 13,232 CCX: 11,136 in the four Euclid passes and 2,096 in the square.

`scripts/junk_check.py` runs M on every x at every odd prime below 600 for eleven junk budgets, and the square's compute on every Y at every prime below 16,384 where the fold applies for up to eight keep budgets.
It also checks that the CCX saved is exactly 2 per junk wire used in M and 1 per kept wire in compute.

## Depth changes on the junk-wire build

This branch builds on abdowns's PR #14 (`lowt-junk` at `171738f`), which builds on ab-godder's PR #9 through our PR #10.
The changes below cut scheduled depth, not CCX.
Each keeps every stage's peak with no junk, M at 1,309 wires and the square at 3,045, so `_junk_budgets` still hands out 2,784 Euclid junk wires and 1,048 square wires, and the circuit at G stays at 3,192,795 CCX.
ALT, FAN, ROT, DP, INC and SEL are ours, from `v2/lean`, ported onto this code; `cs` is ours too.

### Euclid scratch scheduling

On odd Euclid ticks, the pass holds the most recently freed wire around the step call, then returns it.
Each step takes clean scratch and restores it to zero, so selecting another clean wire preserves the step function and its inverse on the same reachable domain.
Alternating scratch lets the next carry sweep overlap the previous strip sweep without changing the arithmetic or the allocator.
The hold sits around the step call, which now also passes the step its junk wires.
It raises the Euclid pass's peak with no junk from 1,282 to 1,283 wires, still below the Bézout pass's 1,309, so the junk budget does not move.
At G this step retains 4,096 wires and 3,192,795 CCX, with 32,924,026 scheduled ticks and 11,744,039 expanded operations.

### Parallel final coefficient swap

The final coefficient swap copies its control through a breadth-first CX tree onto scratch wires already touched and freed by that tick.
The free-wire contract makes those copies equal to the control, and the reverse tree clears them after the swap while restoring the allocator stack exactly.
Using only the tick's own wires preserves its arity and peak space, while distributing the swap controls reduces scheduled depth without adding CCX gates.
The port is the same lines on this tick: the tree fans `sw` as the tick computes it.
At G this step retains 4,096 wires and 3,192,795 CCX, with 31,415,772 scheduled ticks and 11,788,463 expanded operations.

### Euclid unwind and parallel rotation

The unwind replaces `c ^= a; v ^= a; v ^= c` with `v ^= c; c ^= a`, an identity on every bit state.
The complemented-control select `X(v); CCX(g1, v, a); X(v)` becomes `CCX(g1, v, a); CX(g1, a)`, while the empty X pair at bit zero disappears.
Each final `CX(g1, V[i])` moves into its unwind bit, across operations that neither write g1 nor change V[i] except by X.
This step's unwind has three branches, and the identity is derived for each.
Bit zero and the in-place bits take it as written.
A kept bit, whose carry sits on a junk wire, has no `c ^= a; v ^= a`, and takes the same tail without that CX: `v ^= c; a ^= g1 v; a ^= g1; v ^= c; v ^= g1`.
The top bit stays out of the loop, as `_top_bit` leaves it, so its g1 CX stays after the loop.
The conditional left rotation reverses the whole word and then all but its last bit, giving two layers of disjoint swaps with the same number of CCX gates.
A reversible CX tree copies the rotation control onto available clean tape wires and uncomputes those copies after both layers.
The pass supplies at most `(w - 1) // 2 - 1` copies from its unused, vacated or lent clean wires; sharing fewer copies round-robin preserves the same permutation.
The last step returns before the strip, so it takes no copies, and the zero-copy case retains the original step shape and serial rotation, including the smallest widths.
Under top_clear the lifted bit and V[w - 2] are both zero when two is set, so the strip rotates V[:w - 2] with the same permutation and swap count as the shortened serial strip.
`scripts/step_check.py` checks the rewritten step against the base's on every small-width variant, with four wrong edits as controls (`INVARIANTS.md`, `I2.step`).
At G this step retains 4,096 wires and 3,192,795 CCX, with 30,215,374 scheduled ticks and 11,532,839 expanded operations.
