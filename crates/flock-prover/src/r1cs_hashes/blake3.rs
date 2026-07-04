//! Monolithic BLAKE3 compression-function R1CS — one R1CS instance per
//! `compress(cv, m, counter, block_len, flags) → state[16]` call. Encodes
//! the 16-word state init, all 7 rounds (8 G's per round + the message
//! permutation), and the final output XORs in one big sparse system.
//!
//! ## Encoding choice — "Option D" (minimum-slot)
//!
//! BLAKE3 has no AND-based Ch/Maj; the only nonlinear constraints are the
//! carry_aux bits of 32-bit ADDs. Per compression: 7 rounds × 8 G × 6 ADDs
//! × 31 carry_aux = **10,416 ANDs**. We materialize **only the irreducible
//! slots**:
//!
//! - **No sum-bit slots**. Each ADD's 32 sum bits expand into lin_funcs at
//!   the use site (`s[i] = X[i] ⊕ Y[i] ⊕ ⊕_{j<i} carry_aux[j]`).
//! - **No `a_new` / `c_new` lin-id slots**. Lanes 0–3 ("a" positions) and
//!   8–11 ("c" positions) cascade — every read of these lanes inlines the
//!   full chain of carry_aux references from prior G's that touched the
//!   lane. After 7 rounds this chain is deep, but the slot count stays
//!   tight enough to fit `k_log = 14`.
//! - **`b_new` / `d_new` lin-id slots only**. Lanes 4–7 ("b" positions) and
//!   12–15 ("d" positions) are materialized as 32-bit lin-id slots per G,
//!   so the next G's read of these lanes is a single-slot lookup. This
//!   breaks the cascade for half the lanes — without it, `prove`-time
//!   matrix density would blow up further.
//!
//! Trade-off: matrix is **substantially denser** than a "materialize all
//! sums" encoding, so the slow-path
//! `apply_{a,b,c}_packed` and `sparse_row_fold` are slower per K-block.
//! But K halves (2^15 → 2^14), which speeds up PCS commit/open and lets
//! more instances fit at the same `m`. Picks favor `prove_fast` over `prove`.
//!
//! ## Witness layout per compression block (`k_log = 14`, `k = 16,384`)
//!
//! ```text
//!   z[0]                       = 1                    (constant)
//!   z[1     ..    257)         = cv[0..8]   (8 × 32-bit words)
//!   z[257   ..    769)         = m[0..16]   (16 × 32-bit words)
//!   z[769   ..    801)         = counter_lo
//!   z[801   ..    833)         = counter_hi
//!   z[833   ..    865)         = block_len
//!   z[865   ..    897)         = flags
//!   z[897   .. 14,897)         = 56 G blocks × 250 bits each
//!   z[14,897 .. 15,153)        = out_lo[0..8] = state[0..8] ^ state[8..16]
//!   z[15,153 .. 15,409)        = out_hi[0..8] = state[8..16] ^ cv[0..8]
//!   z[15,409 .. 16,384)        = padding (forced to 0 by empty rows)
//! ```
//!
//! Per G block layout (250 bits):
//! ```text
//!   [0   .. 31)    carry_aux for ADD_TMP0  = a + b
//!   [31  .. 62)    carry_aux for ADD_A1    = ADD_TMP0 + mx        (→ a_1)
//!   [62  .. 93)    carry_aux for ADD_C1    = c + d_1              (→ c_1)
//!   [93  .. 124)   carry_aux for ADD_TMP1  = a_1 + b_1
//!   [124 .. 155)   carry_aux for ADD_A2    = ADD_TMP1 + my        (→ a_new)
//!   [155 .. 186)   carry_aux for ADD_C2    = c_1 + d_2            (→ c_new)
//!   [186 .. 218)   b_new = rotr7(b_1 ^ c_2)                (lin-id)
//!   [218 .. 250)   d_new = rotr8(d_1 ^ a_2)                (lin-id)
//! ```
//!
//! `tmp_0`, `a_1`, `c_1`, `tmp_1`, `a_2 (a_new)`, `c_2 (c_new)`, `d_1`,
//! `b_1`, `d_2` are NEVER materialized as slots — they're lin_funcs
//! evaluated at row-build time and threaded forward in the state cascade.
//!
//! ## Constraint shape (`C = I`)
//!
//! Every z-slot is the output of one R1CS row:
//!
//! | Row kind            | A_row            | B_row           | Output       |
//! |---------------------|------------------|-----------------|--------------|
//! | Constant `z[0]`     | `[0]`            | `[0]`           | `z[0]·z[0]`  |
//! | Input slot          | `[slot]`         | `[Z_CONST]`     | `z[slot]·1`  |
//! | lin-id slot         | lin_func         | `[Z_CONST]`     | lin_func·1   |
//! | carry_aux           | lin_func_L       | lin_func_R      | (L)·(R)      |
//! | Padding             | `[]`             | `[]`            | `0·0`        |
//!
//! ## What this enforces
//!
//! - The 56 G-functions execute correctly: each ADD's carry_aux witness is
//!   constrained to `(X[i] ⊕ cin[i]) · (Y[i] ⊕ cin[i])`, so the sum bits
//!   `X[i] ⊕ Y[i] ⊕ cin[i]` are the correct 32-bit sum modulo 2³².
//! - `b_new`, `d_new` lin-id slots equal the right XOR-rotate of prior values.
//! - `out_lo[w] = state[w] ^ state[w+8]` and `out_hi[w] = state[w+8] ^ cv[w]`
//!   (BLAKE3 finalization).
//!
//! ## What this does NOT enforce
//!
//! - **Public-input pinning**: `cv`, `m`, `counter_*`, `block_len`, `flags`
//!   are "free" witness bits. PCS-level openings at fixed indices will
//!   eventually pin them to claimed public inputs.

use super::common::{BitRecord, add_carry_parts, or_bit_at, or_u32_at_bit, xor_dedup};
use flock_core::challenger::Challenger;
use flock_core::field::F128;
use flock_core::pcs::{Commitment, PcsParams};
use flock_core::proof::{R1csClaim, R1csProof};
use flock_core::r1cs::{BlockR1cs, SparseBinaryMatrix};
use flock_core::verifier;

// ---------------------------------------------------------------------------
// Public constants
// ---------------------------------------------------------------------------

/// Block dim: one BLAKE3 compression occupies `2^K_LOG = 16,384` z slots.
pub const K_LOG: usize = 14;
/// `k = 2^K_LOG`.
pub const K: usize = 1 << K_LOG;
/// Univariate-skip dim — must match [`flock_core::zerocheck::K_SKIP`].
pub const K_SKIP: usize = 6;

/// Number of BLAKE3 rounds.
pub const N_ROUNDS: usize = 7;
/// Number of G calls per round (4 column + 4 diagonal).
pub const N_G_PER_ROUND: usize = 8;
/// Total G calls per compression.
pub const N_G: usize = N_ROUNDS * N_G_PER_ROUND;
/// Bits per BLAKE3 word.
pub const WORD_BITS: usize = 32;

/// Carry_aux bits per 32-bit ADD (bit 0..30; bit 31 is the discarded
/// mod-2³² carry-out and isn't allocated).
pub const CARRY_BITS_PER_ADD: usize = WORD_BITS - 1; // 31
/// ADDs per G.
pub const ADDS_PER_G: usize = 6;
/// Lin-id 32-bit words per G (b_new, d_new).
pub const LIN_WORDS_PER_G: usize = 2;
/// Bits per G block (no sum-bit slots — see module docs).
pub const G_STRIDE: usize = ADDS_PER_G * CARRY_BITS_PER_ADD + LIN_WORDS_PER_G * WORD_BITS; // 250

/// BLAKE3 initial hash values (identical to SHA-256 IV).
pub const BLAKE3_IV: [u32; 8] = [
    0x6a09e667, 0xbb67ae85, 0x3c6ef372, 0xa54ff53a, 0x510e527f, 0x9b05688c, 0x1f83d9ab, 0x5be0cd19,
];

/// BLAKE3 message permutation applied between rounds.
pub const MSG_PERMUTATION: [usize; 16] = [2, 6, 3, 10, 7, 0, 4, 13, 1, 11, 12, 5, 9, 14, 15, 8];

/// Lanes touched by G index `g` within a round: `[a, b, c, d]`.
/// First 4 are column G's, last 4 are diagonal G's.
pub const G_LANES: [[usize; 4]; N_G_PER_ROUND] = [
    [0, 4, 8, 12],
    [1, 5, 9, 13],
    [2, 6, 10, 14],
    [3, 7, 11, 15],
    [0, 5, 10, 15],
    [1, 6, 11, 12],
    [2, 7, 8, 13],
    [3, 4, 9, 14],
];

/// Message-index pairs `(mx, my)` consumed by G index `g` within a round,
/// indexing into the (already-permuted) per-round message buffer.
pub const G_MSG_IDX: [[usize; 2]; N_G_PER_ROUND] = [
    [0, 1],
    [2, 3],
    [4, 5],
    [6, 7],
    [8, 9],
    [10, 11],
    [12, 13],
    [14, 15],
];

// ---------------------------------------------------------------------------
// Layout positions (bit indices into the per-block z slice of length K)
// ---------------------------------------------------------------------------

// **I/O-aligned layout** for the hash chain (forked from `blake3`): the input
// chaining value `cv` lives in aligned slot 0 and the output chaining value
// `out_lo` (= state[0..8] ^ state[8..16]) in aligned slot 1 — each a clean
// 256-bit (`2^8`) window, so the chain shift argument folds them via a single
// tensor opening. cv/out_lo are *exactly* 256 bits, so the slots have NO
// interior padding. Everything else (const, m, counters, flags, G-blocks,
// out_hi) packs after the two slots. The re-layout is purely a change of these
// base offsets — all bit placement goes through the `*_bit` accessors below.
pub const SLOT_BITS: usize = 256; // 2^8, one 256-bit chaining value
pub const CV_BASE: usize = 0; // input region, slot 0: [0, 256)
pub const OUT_LO_BASE: usize = SLOT_BITS; // output region, slot 1: [256, 512)
pub const Z_CONST_POS: usize = 2 * SLOT_BITS; // 512
pub const M_BASE: usize = Z_CONST_POS + 1; // 513
pub const T_LO_BASE: usize = M_BASE + 16 * WORD_BITS; // 1025
pub const T_HI_BASE: usize = T_LO_BASE + WORD_BITS; // 1057
pub const BLEN_BASE: usize = T_HI_BASE + WORD_BITS; // 1089
pub const FLAGS_BASE: usize = BLEN_BASE + WORD_BITS; // 1121
pub const GS_BASE: usize = FLAGS_BASE + WORD_BITS; // 1153
pub const OUT_HI_BASE: usize = GS_BASE + N_G * G_STRIDE; // 15,153
pub const USEFUL_BITS: usize = OUT_HI_BASE + 8 * WORD_BITS; // 15,409

// G sub-block: ADD `add_idx` ∈ 0..6 (carry_aux only), then lin-id
// `which` ∈ 0..2.
const ADD_TMP0: usize = 0;
const ADD_A1: usize = 1;
const ADD_C1: usize = 2;
const ADD_TMP1: usize = 3;
const ADD_A2: usize = 4;
const ADD_C2: usize = 5;
const LIN_B_NEW: usize = 0;
const LIN_D_NEW: usize = 1;

#[inline]
fn cv_bit(w: usize, b: usize) -> usize {
    debug_assert!(w < 8 && b < WORD_BITS);
    CV_BASE + WORD_BITS * w + b
}
#[inline]
fn m_bit(i: usize, b: usize) -> usize {
    debug_assert!(i < 16 && b < WORD_BITS);
    M_BASE + WORD_BITS * i + b
}
#[inline]
fn g_add_carry_bit(g: usize, add_idx: usize, b: usize) -> usize {
    debug_assert!(g < N_G && add_idx < ADDS_PER_G && b < CARRY_BITS_PER_ADD);
    GS_BASE + G_STRIDE * g + CARRY_BITS_PER_ADD * add_idx + b
}
#[inline]
fn g_lin_bit(g: usize, which: usize, b: usize) -> usize {
    debug_assert!(g < N_G && which < LIN_WORDS_PER_G && b < WORD_BITS);
    GS_BASE + G_STRIDE * g + ADDS_PER_G * CARRY_BITS_PER_ADD + WORD_BITS * which + b
}
#[inline]
fn out_lo_bit(w: usize, b: usize) -> usize {
    debug_assert!(w < 8 && b < WORD_BITS);
    OUT_LO_BASE + WORD_BITS * w + b
}
#[inline]
fn out_hi_bit(w: usize, b: usize) -> usize {
    debug_assert!(w < 8 && b < WORD_BITS);
    OUT_HI_BASE + WORD_BITS * w + b
}

// ---------------------------------------------------------------------------
// Reference BLAKE3 compression — the witness oracle. Cross-checked against
// the `blake3` crate in tests.
// ---------------------------------------------------------------------------

#[inline]
fn g_fn(state: &mut [u32; 16], a: usize, b: usize, c: usize, d: usize, mx: u32, my: u32) {
    state[a] = state[a].wrapping_add(state[b]).wrapping_add(mx);
    state[d] = (state[d] ^ state[a]).rotate_right(16);
    state[c] = state[c].wrapping_add(state[d]);
    state[b] = (state[b] ^ state[c]).rotate_right(12);
    state[a] = state[a].wrapping_add(state[b]).wrapping_add(my);
    state[d] = (state[d] ^ state[a]).rotate_right(8);
    state[c] = state[c].wrapping_add(state[d]);
    state[b] = (state[b] ^ state[c]).rotate_right(7);
}

fn round_fn(state: &mut [u32; 16], block: &[u32; 16]) {
    g_fn(state, 0, 4, 8, 12, block[0], block[1]);
    g_fn(state, 1, 5, 9, 13, block[2], block[3]);
    g_fn(state, 2, 6, 10, 14, block[4], block[5]);
    g_fn(state, 3, 7, 11, 15, block[6], block[7]);
    g_fn(state, 0, 5, 10, 15, block[8], block[9]);
    g_fn(state, 1, 6, 11, 12, block[10], block[11]);
    g_fn(state, 2, 7, 8, 13, block[12], block[13]);
    g_fn(state, 3, 4, 9, 14, block[14], block[15]);
}

fn permute(m: &mut [u32; 16]) {
    let mut permuted = [0u32; 16];
    for i in 0..16 {
        permuted[i] = m[MSG_PERMUTATION[i]];
    }
    *m = permuted;
}

/// BLAKE3 compression function. Returns the full 16-word output state
/// (post-finalization XOR). For chaining, the new CV is `out[0..8]`.
pub fn blake3_compress(
    cv: &[u32; 8],
    block_words: &[u32; 16],
    counter: u64,
    block_len: u32,
    flags: u32,
) -> [u32; 16] {
    let counter_low = counter as u32;
    let counter_high = (counter >> 32) as u32;
    let mut state = [
        cv[0],
        cv[1],
        cv[2],
        cv[3],
        cv[4],
        cv[5],
        cv[6],
        cv[7],
        BLAKE3_IV[0],
        BLAKE3_IV[1],
        BLAKE3_IV[2],
        BLAKE3_IV[3],
        counter_low,
        counter_high,
        block_len,
        flags,
    ];
    let mut block = *block_words;
    for r in 0..N_ROUNDS {
        round_fn(&mut state, &block);
        if r + 1 < N_ROUNDS {
            permute(&mut block);
        }
    }
    for i in 0..8 {
        state[i] ^= state[i + 8];
        state[i + 8] ^= cv[i];
    }
    state
}

/// `per_round_msg_idx()[r][g] = (mx_idx, my_idx)` for round `r`, G index `g`
/// — i.e., `PERM^r [G_MSG_IDX[g]]`.
fn per_round_msg_idx() -> [[[usize; 2]; N_G_PER_ROUND]; N_ROUNDS] {
    let mut perm = [0usize; 16];
    for i in 0..16 {
        perm[i] = i;
    }
    let mut out = [[[0usize; 2]; N_G_PER_ROUND]; N_ROUNDS];
    for r in 0..N_ROUNDS {
        for g in 0..N_G_PER_ROUND {
            out[r][g][0] = perm[G_MSG_IDX[g][0]];
            out[r][g][1] = perm[G_MSG_IDX[g][1]];
        }
        let mut next = [0usize; 16];
        for i in 0..16 {
            next[i] = perm[MSG_PERMUTATION[i]];
        }
        perm = next;
    }
    out
}

// ---------------------------------------------------------------------------
// Lin_func cascade — per-bit lists of slot indices XOR'd to evaluate one bit.
//
// In Option D, sum bits aren't materialized as slots; instead, the "value" of
// any intermediate bit is a `LinBits[i] = Vec<usize>` whose XOR equals that
// bit. The G-builder threads these lin_funcs forward through the state, so
// each lane's value at any point in the protocol is represented as a `Word`.
// ---------------------------------------------------------------------------

/// A 32-bit symbolic word. `bits[i]` is a list of slot indices whose XOR
/// equals bit `i` of the word.
#[derive(Clone)]
struct Word {
    bits: [Vec<usize>; WORD_BITS],
}

impl Word {
    fn zero() -> Self {
        Self {
            bits: std::array::from_fn(|_| Vec::new()),
        }
    }
    /// Construct from a 32-bit witness or lin-id slot whose 32 bits live at
    /// `[base + 0, base + 1, …, base + 31]`.
    fn from_slot_base(base: usize) -> Self {
        Self {
            bits: std::array::from_fn(|i| vec![base + i]),
        }
    }
    /// Construct from a 32-bit constant — bit `i` is `[Z_CONST]` if set,
    /// `[]` otherwise.
    fn from_const(val: u32) -> Self {
        Self {
            bits: std::array::from_fn(|i| {
                if (val >> i) & 1 == 1 {
                    vec![Z_CONST_POS]
                } else {
                    Vec::new()
                }
            }),
        }
    }
    /// Bitwise XOR, no dedup. Caller calls `dedup()` after a chain if it
    /// wants canonical rows.
    fn xor(&self, other: &Word) -> Word {
        let mut out = self.clone();
        for i in 0..WORD_BITS {
            out.bits[i].extend(&other.bits[i]);
        }
        out
    }
    /// `rotr(n)` — pure index permutation; doesn't touch slot lists.
    fn rotr(&self, n: usize) -> Word {
        Word {
            bits: std::array::from_fn(|i| self.bits[(i + n) % WORD_BITS].clone()),
        }
    }
    /// Sort + cancel duplicates per bit.
    fn dedup(mut self) -> Word {
        for i in 0..WORD_BITS {
            self.bits[i] = xor_dedup(std::mem::take(&mut self.bits[i]));
        }
        self
    }
    /// "Sum bit" lin_func of an ADD `x + y` whose carry_aux slots live at
    /// `[carry_base, carry_base + 31)`.
    ///
    ///   sum[i] = x[i] ⊕ y[i] ⊕ ⊕_{j<i} carry_aux[j]
    fn add_sum(x: &Word, y: &Word, carry_base: usize) -> Word {
        let mut out = Word::zero();
        for i in 0..WORD_BITS {
            let mut v = x.bits[i].clone();
            v.extend(&y.bits[i]);
            for j in 0..i {
                v.push(carry_base + j);
            }
            out.bits[i] = v;
        }
        out.dedup()
    }
}

// ---------------------------------------------------------------------------
// Per-ADD: write the 31 carry_aux rows and return the sum-bit `Word`.
//
//   carry_aux[i] = (X[i] ⊕ cin[i]) · (Y[i] ⊕ cin[i])   (R1CS AND row)
//   sum[i]       = X[i] ⊕ Y[i] ⊕ cin[i]                (no slot, lin_func)
//
// where cin[i] = ⊕_{j<i} carry_aux[j].
// ---------------------------------------------------------------------------

fn write_add_carry_rows(
    a_rows: &mut [Vec<usize>],
    b_rows: &mut [Vec<usize>],
    x: &Word,
    y: &Word,
    carry_base: usize,
) -> Word {
    for i in 0..CARRY_BITS_PER_ADD {
        let mut a = x.bits[i].clone();
        for j in 0..i {
            a.push(carry_base + j);
        }
        let mut b = y.bits[i].clone();
        for j in 0..i {
            b.push(carry_base + j);
        }
        a_rows[carry_base + i] = xor_dedup(a);
        b_rows[carry_base + i] = xor_dedup(b);
    }
    Word::add_sum(x, y, carry_base)
}

// ---------------------------------------------------------------------------
// Initial lane sources at the start of compression.
// ---------------------------------------------------------------------------

fn initial_lane_words() -> [Word; 16] {
    let mut s: [Word; 16] = std::array::from_fn(|_| Word::zero());
    for w in 0..8 {
        s[w] = Word::from_slot_base(cv_bit(w, 0));
    }
    for i in 0..4 {
        s[8 + i] = Word::from_const(BLAKE3_IV[i]);
    }
    s[12] = Word::from_slot_base(T_LO_BASE);
    s[13] = Word::from_slot_base(T_HI_BASE);
    s[14] = Word::from_slot_base(BLEN_BASE);
    s[15] = Word::from_slot_base(FLAGS_BASE);
    s
}

// ---------------------------------------------------------------------------
// Matrix builder
// ---------------------------------------------------------------------------

/// Build the per-block base matrices `(A_0, B_0)`. `C_0 = I_k` (circuit-shape
/// R1CS — every z slot is the output of its row).
pub fn build_matrices() -> (SparseBinaryMatrix, SparseBinaryMatrix) {
    let mut a_rows: Vec<Vec<usize>> = vec![Vec::new(); K];
    let mut b_rows: Vec<Vec<usize>> = vec![Vec::new(); K];

    // Constant z[0]: z[0]·z[0] = z[0]. Trivially satisfied for any boolean.
    a_rows[Z_CONST_POS] = vec![Z_CONST_POS];
    b_rows[Z_CONST_POS] = vec![Z_CONST_POS];

    // Input rows for cv, m, counter_lo, counter_hi, block_len, flags.
    let mut input_emit = |base: usize, len: usize| {
        for j in 0..len {
            let s = base + j;
            a_rows[s] = vec![s];
            b_rows[s] = vec![Z_CONST_POS];
        }
    };
    input_emit(CV_BASE, 8 * WORD_BITS);
    input_emit(M_BASE, 16 * WORD_BITS);
    input_emit(T_LO_BASE, WORD_BITS);
    input_emit(T_HI_BASE, WORD_BITS);
    input_emit(BLEN_BASE, WORD_BITS);
    input_emit(FLAGS_BASE, WORD_BITS);

    let msg_idx = per_round_msg_idx();
    let mut state: [Word; 16] = initial_lane_words();

    for r in 0..N_ROUNDS {
        for g_in_round in 0..N_G_PER_ROUND {
            let g = r * N_G_PER_ROUND + g_in_round;
            let [la, lb, lc, ld] = G_LANES[g_in_round];
            let [mx_idx, my_idx] = msg_idx[r][g_in_round];

            // Snapshot inputs before any state mutation. Cloning is cheap
            // (lane Words point at the same slot lists — we never alias).
            let a = state[la].clone();
            let b = state[lb].clone();
            let c = state[lc].clone();
            let d = state[ld].clone();
            let mx = Word::from_slot_base(m_bit(mx_idx, 0));
            let my = Word::from_slot_base(m_bit(my_idx, 0));

            // tmp_0 = a + b
            let tmp_0 = write_add_carry_rows(
                &mut a_rows,
                &mut b_rows,
                &a,
                &b,
                g_add_carry_bit(g, ADD_TMP0, 0),
            );
            // a_1 = tmp_0 + mx
            let a_1 = write_add_carry_rows(
                &mut a_rows,
                &mut b_rows,
                &tmp_0,
                &mx,
                g_add_carry_bit(g, ADD_A1, 0),
            );
            // d_1 = rotr16(d ^ a_1)
            let d_1 = d.xor(&a_1).dedup().rotr(16);
            // c_1 = c + d_1
            let c_1 = write_add_carry_rows(
                &mut a_rows,
                &mut b_rows,
                &c,
                &d_1,
                g_add_carry_bit(g, ADD_C1, 0),
            );
            // b_1 = rotr12(b ^ c_1)
            let b_1 = b.xor(&c_1).dedup().rotr(12);
            // tmp_1 = a_1 + b_1
            let tmp_1 = write_add_carry_rows(
                &mut a_rows,
                &mut b_rows,
                &a_1,
                &b_1,
                g_add_carry_bit(g, ADD_TMP1, 0),
            );
            // a_2 = tmp_1 + my   (= a_new — cascades)
            let a_2 = write_add_carry_rows(
                &mut a_rows,
                &mut b_rows,
                &tmp_1,
                &my,
                g_add_carry_bit(g, ADD_A2, 0),
            );
            // d_2 = rotr8(d_1 ^ a_2)
            let d_2 = d_1.xor(&a_2).dedup().rotr(8);
            // c_2 = c_1 + d_2    (= c_new — cascades)
            let c_2 = write_add_carry_rows(
                &mut a_rows,
                &mut b_rows,
                &c_1,
                &d_2,
                g_add_carry_bit(g, ADD_C2, 0),
            );
            // b_new = rotr7(b_1 ^ c_2)    (materialized lin-id)
            let b_new_word = b_1.xor(&c_2).dedup().rotr(7);
            for i in 0..WORD_BITS {
                let s = g_lin_bit(g, LIN_B_NEW, i);
                a_rows[s] = b_new_word.bits[i].clone();
                b_rows[s] = vec![Z_CONST_POS];
            }
            // d_new = d_2                  (materialized lin-id)
            for i in 0..WORD_BITS {
                let s = g_lin_bit(g, LIN_D_NEW, i);
                a_rows[s] = d_2.bits[i].clone();
                b_rows[s] = vec![Z_CONST_POS];
            }

            // Advance the symbolic state. `a_2` and `c_2` keep cascading;
            // `b_new` and `d_new` reset to single-slot lookups.
            state[la] = a_2;
            state[lb] = Word::from_slot_base(g_lin_bit(g, LIN_B_NEW, 0));
            state[lc] = c_2;
            state[ld] = Word::from_slot_base(g_lin_bit(g, LIN_D_NEW, 0));
        }
    }

    // Finalization XORs.
    //   out_lo[w] = state[w] ^ state[w+8]
    //   out_hi[w] = state[w+8] ^ cv[w]
    for w in 0..8 {
        let lo = state[w].xor(&state[w + 8]).dedup();
        for i in 0..WORD_BITS {
            let s = out_lo_bit(w, i);
            a_rows[s] = lo.bits[i].clone();
            b_rows[s] = vec![Z_CONST_POS];
        }
        let cv_w = Word::from_slot_base(cv_bit(w, 0));
        let hi = state[w + 8].xor(&cv_w).dedup();
        for i in 0..WORD_BITS {
            let s = out_hi_bit(w, i);
            a_rows[s] = hi.bits[i].clone();
            b_rows[s] = vec![Z_CONST_POS];
        }
    }

    // Padding rows [USEFUL_BITS..K): A = B = []. Constraint 0·0 = z[i]
    // forces z[i] = 0 for all padding bits.

    let to_mat = |rows| SparseBinaryMatrix {
        num_rows: K,
        num_cols: K,
        rows,
    };
    (to_mat(a_rows), to_mat(b_rows))
}

/// Build a [`BlockR1cs`] batching `2^n_blocks_log` independent BLAKE3
/// compressions. `n_blocks_log ≥ 3` is required (lincheck needs `n_outer ≥ 8`).
pub fn build_block_r1cs(n_blocks_log: usize) -> BlockR1cs {
    let (a_0, b_0) = build_matrices();
    super::common::build_block_r1cs_with_matrices(
        n_blocks_log,
        K_LOG,
        K_SKIP,
        USEFUL_BITS,
        a_0,
        b_0,
        // Constant-wire pin (docs/const-wire-pin.md): forces z[Z_CONST_POS] = 1
        // in every block. Requires padding blocks filled with valid compressions.
        Some(Z_CONST_POS),
    )
}

// ---------------------------------------------------------------------------
// Lincheck circuit walker — mirrors `build_matrices`. Same structure as
// `blake3::Blake3LincheckCircuit` but uses this module's I/O-aligned slot
// positions (cv_bit/m_bit/etc.).
// ---------------------------------------------------------------------------

#[inline]
fn scatter_add_carry_rows(
    comb: &mut [F128],
    alpha: F128,
    eq_inner: &[F128],
    x: &Word,
    y: &Word,
    carry_base: usize,
) -> Word {
    for i in 0..CARRY_BITS_PER_ADD {
        let row = carry_base + i;
        let e = eq_inner[row];
        let ea = alpha * e;
        for &slot in x.bits[i].iter() {
            comb[slot] += ea;
        }
        for j in 0..i {
            comb[carry_base + j] += ea;
        }
        for &slot in y.bits[i].iter() {
            comb[slot] += e;
        }
        for j in 0..i {
            comb[carry_base + j] += e;
        }
    }
    Word::add_sum(x, y, carry_base)
}

#[inline]
fn scatter_lin_id_row(
    comb: &mut [F128],
    alpha: F128,
    eq_inner: &[F128],
    row: usize,
    word_bits_i: &[usize],
) {
    let e = eq_inner[row];
    let ea = alpha * e;
    for &slot in word_bits_i.iter() {
        comb[slot] += ea;
    }
    comb[Z_CONST_POS] += e;
}

pub struct Blake3LincheckCircuit;

impl flock_core::lincheck::LincheckCircuit for Blake3LincheckCircuit {
    fn n_cols(&self) -> usize {
        K
    }

    fn fold_alpha_batched(&self, alpha: F128, eq_inner: &[F128]) -> Vec<F128> {
        assert_eq!(eq_inner.len(), K, "eq_inner length must equal n_cols = K");
        let mut comb = vec![F128::ZERO; K];

        // Const row.
        let e0 = eq_inner[Z_CONST_POS];
        comb[Z_CONST_POS] += alpha * e0;
        comb[Z_CONST_POS] += e0;

        // Input self-loops for cv, m, counter, blen, flags.
        let input_emit = |comb: &mut [F128], base: usize, len: usize| {
            for j in 0..len {
                let s = base + j;
                let e = eq_inner[s];
                comb[s] += alpha * e;
                comb[Z_CONST_POS] += e;
            }
        };
        input_emit(&mut comb, CV_BASE, 8 * WORD_BITS);
        input_emit(&mut comb, M_BASE, 16 * WORD_BITS);
        input_emit(&mut comb, T_LO_BASE, WORD_BITS);
        input_emit(&mut comb, T_HI_BASE, WORD_BITS);
        input_emit(&mut comb, BLEN_BASE, WORD_BITS);
        input_emit(&mut comb, FLAGS_BASE, WORD_BITS);

        let msg_idx = per_round_msg_idx();
        let mut state: [Word; 16] = initial_lane_words();

        for r in 0..N_ROUNDS {
            for g_in_round in 0..N_G_PER_ROUND {
                let g = r * N_G_PER_ROUND + g_in_round;
                let [la, lb, lc, ld] = G_LANES[g_in_round];
                let [mx_idx, my_idx] = msg_idx[r][g_in_round];

                let a = state[la].clone();
                let b = state[lb].clone();
                let c = state[lc].clone();
                let d = state[ld].clone();
                let mx = Word::from_slot_base(m_bit(mx_idx, 0));
                let my = Word::from_slot_base(m_bit(my_idx, 0));

                let tmp_0 = scatter_add_carry_rows(
                    &mut comb,
                    alpha,
                    eq_inner,
                    &a,
                    &b,
                    g_add_carry_bit(g, ADD_TMP0, 0),
                );
                let a_1 = scatter_add_carry_rows(
                    &mut comb,
                    alpha,
                    eq_inner,
                    &tmp_0,
                    &mx,
                    g_add_carry_bit(g, ADD_A1, 0),
                );
                let d_1 = d.xor(&a_1).dedup().rotr(16);
                let c_1 = scatter_add_carry_rows(
                    &mut comb,
                    alpha,
                    eq_inner,
                    &c,
                    &d_1,
                    g_add_carry_bit(g, ADD_C1, 0),
                );
                let b_1 = b.xor(&c_1).dedup().rotr(12);
                let tmp_1 = scatter_add_carry_rows(
                    &mut comb,
                    alpha,
                    eq_inner,
                    &a_1,
                    &b_1,
                    g_add_carry_bit(g, ADD_TMP1, 0),
                );
                let a_2 = scatter_add_carry_rows(
                    &mut comb,
                    alpha,
                    eq_inner,
                    &tmp_1,
                    &my,
                    g_add_carry_bit(g, ADD_A2, 0),
                );
                let d_2 = d_1.xor(&a_2).dedup().rotr(8);
                let c_2 = scatter_add_carry_rows(
                    &mut comb,
                    alpha,
                    eq_inner,
                    &c_1,
                    &d_2,
                    g_add_carry_bit(g, ADD_C2, 0),
                );

                let b_new_word = b_1.xor(&c_2).dedup().rotr(7);
                for i in 0..WORD_BITS {
                    let s = g_lin_bit(g, LIN_B_NEW, i);
                    scatter_lin_id_row(&mut comb, alpha, eq_inner, s, &b_new_word.bits[i]);
                }
                for i in 0..WORD_BITS {
                    let s = g_lin_bit(g, LIN_D_NEW, i);
                    scatter_lin_id_row(&mut comb, alpha, eq_inner, s, &d_2.bits[i]);
                }

                state[la] = a_2;
                state[lb] = Word::from_slot_base(g_lin_bit(g, LIN_B_NEW, 0));
                state[lc] = c_2;
                state[ld] = Word::from_slot_base(g_lin_bit(g, LIN_D_NEW, 0));
            }
        }

        for w in 0..8 {
            let lo = state[w].xor(&state[w + 8]).dedup();
            for i in 0..WORD_BITS {
                let s = out_lo_bit(w, i);
                scatter_lin_id_row(&mut comb, alpha, eq_inner, s, &lo.bits[i]);
            }
            let cv_w = Word::from_slot_base(cv_bit(w, 0));
            let hi = state[w + 8].xor(&cv_w).dedup();
            for i in 0..WORD_BITS {
                let s = out_hi_bit(w, i);
                scatter_lin_id_row(&mut comb, alpha, eq_inner, s, &hi.bits[i]);
            }
        }

        comb
    }
}

// ---------------------------------------------------------------------------
// Witness generation (boolean)
// ---------------------------------------------------------------------------

/// Compute one 32-bit ADD, writing 31 carry_aux bits into `z` at `carry_base`.
/// Returns `x.wrapping_add(y)` (sum bits are NOT materialized in this
/// encoding — see module docs).
fn add_with_witness_carry_only(x: u32, y: u32, z: &mut [bool], carry_base: usize) -> u32 {
    let mut cin: u32 = 0;
    for i in 0..WORD_BITS {
        if i < CARRY_BITS_PER_ADD {
            let xi = (x >> i) & 1;
            let yi = (y >> i) & 1;
            let ci = (cin >> i) & 1;
            let carry_aux = (xi ^ ci) & (yi ^ ci);
            z[carry_base + i] = carry_aux == 1;
            let real_carry = carry_aux ^ ci;
            cin |= real_carry << (i + 1);
        }
    }
    x.wrapping_add(y)
}

#[inline]
fn write_word(z: &mut [bool], base: usize, val: u32) {
    for i in 0..WORD_BITS {
        z[base + i] = ((val >> i) & 1) == 1;
    }
}

/// Build the witness block for ONE compression. Length = `K`.
pub fn build_block_witness(
    cv: &[u32; 8],
    m: &[u32; 16],
    counter: u64,
    block_len: u32,
    flags: u32,
) -> Vec<bool> {
    let mut z = vec![false; K];
    z[Z_CONST_POS] = true;
    // Inputs.
    for w in 0..8 {
        write_word(&mut z, cv_bit(w, 0), cv[w]);
    }
    for i in 0..16 {
        write_word(&mut z, m_bit(i, 0), m[i]);
    }
    let counter_lo = counter as u32;
    let counter_hi = (counter >> 32) as u32;
    write_word(&mut z, T_LO_BASE, counter_lo);
    write_word(&mut z, T_HI_BASE, counter_hi);
    write_word(&mut z, BLEN_BASE, block_len);
    write_word(&mut z, FLAGS_BASE, flags);

    // Internal state evolution (matches the matrix builder's symbolic
    // cascade by construction).
    let mut state: [u32; 16] = [
        cv[0],
        cv[1],
        cv[2],
        cv[3],
        cv[4],
        cv[5],
        cv[6],
        cv[7],
        BLAKE3_IV[0],
        BLAKE3_IV[1],
        BLAKE3_IV[2],
        BLAKE3_IV[3],
        counter_lo,
        counter_hi,
        block_len,
        flags,
    ];
    let msg_idx = per_round_msg_idx();

    for r in 0..N_ROUNDS {
        for g_in_round in 0..N_G_PER_ROUND {
            let g = r * N_G_PER_ROUND + g_in_round;
            let [la, lb, lc, ld] = G_LANES[g_in_round];
            let [mx_i, my_i] = msg_idx[r][g_in_round];
            let mx = m[mx_i];
            let my = m[my_i];

            let a = state[la];
            let b = state[lb];
            let c = state[lc];
            let d = state[ld];

            let tmp_0 = add_with_witness_carry_only(a, b, &mut z, g_add_carry_bit(g, ADD_TMP0, 0));
            let a_1 = add_with_witness_carry_only(tmp_0, mx, &mut z, g_add_carry_bit(g, ADD_A1, 0));
            let d_1 = (d ^ a_1).rotate_right(16);
            let c_1 = add_with_witness_carry_only(c, d_1, &mut z, g_add_carry_bit(g, ADD_C1, 0));
            let b_1 = (b ^ c_1).rotate_right(12);
            let tmp_1 =
                add_with_witness_carry_only(a_1, b_1, &mut z, g_add_carry_bit(g, ADD_TMP1, 0));
            let a_2 = add_with_witness_carry_only(tmp_1, my, &mut z, g_add_carry_bit(g, ADD_A2, 0));
            let d_2 = (d_1 ^ a_2).rotate_right(8);
            let c_2 = add_with_witness_carry_only(c_1, d_2, &mut z, g_add_carry_bit(g, ADD_C2, 0));
            let b_new = (b_1 ^ c_2).rotate_right(7);
            let d_new = d_2;
            write_word(&mut z, g_lin_bit(g, LIN_B_NEW, 0), b_new);
            write_word(&mut z, g_lin_bit(g, LIN_D_NEW, 0), d_new);

            state[la] = a_2;
            state[lb] = b_new;
            state[lc] = c_2;
            state[ld] = d_new;
        }
    }

    for w in 0..8 {
        let lo = state[w] ^ state[w + 8];
        let hi = state[w + 8] ^ cv[w];
        write_word(&mut z, out_lo_bit(w, 0), lo);
        write_word(&mut z, out_hi_bit(w, 0), hi);
    }
    z
}

/// Minimum `n_blocks_log` needed to prove `n_blocks` BLAKE3 compressions,
/// subject to the lincheck floor of `n_blocks_log ≥ 3` (`n_outer ≥ 8`).
pub fn min_n_blocks_log(n_blocks: usize) -> usize {
    assert!(n_blocks >= 1, "n_blocks must be ≥ 1");
    let n = n_blocks.max(8);
    n.next_power_of_two().trailing_zeros() as usize
}

/// One BLAKE3 compression input: `(cv, m, counter, block_len, flags)`.
pub type Compression = ([u32; 8], [u32; 16], u64, u32, u32);

/// Generate the boolean witness vector for `blocks.len()` independent BLAKE3
/// compressions, padded to `2^n_blocks_log` slots. Padding blocks are
/// all-zero (trivially satisfy the R1CS). Parallel across instances via rayon.
pub fn generate_witness(blocks: &[Compression], n_blocks_log: usize) -> Vec<bool> {
    use rayon::prelude::*;
    let n_total = 1usize << n_blocks_log;
    let n_blocks = blocks.len();
    assert!(
        n_blocks <= n_total,
        "{n_blocks} compressions > 2^{n_blocks_log} = {n_total} slots"
    );
    let mut z = vec![false; n_total * K];
    z.par_chunks_mut(K)
        .take(n_blocks)
        .zip(blocks.par_iter())
        .for_each(|(chunk, (cv, m, t, b, d))| {
            let block = build_block_witness(cv, m, *t, *b, *d);
            chunk.copy_from_slice(&block);
        });
    z
}

// ---------------------------------------------------------------------------
// Fast witness generation with (a, b, c) — emits the R1CS row-witnesses
// directly from the BLAKE3 computation, in F_{2^128}-packed form. Skips the
// `apply_block_diag_packed` pass downstream.
//
// Row-witness semantics (matching `build_matrices`):
// - Constant z[0]:       (z, a, b, c) = (1, 1, 1, 1).
// - Input slot:          (z, a, b, c) = (val, val, 1, val).
// - Lin-id slot:         (z, a, b, c) = (lin_val, lin_val, 1, lin_val).
// - Carry_aux row i:     (z, a, b, c) = (carry_aux, X⊕cin, Y⊕cin, carry_aux).
// - Padding row:         all zero (already zero on entry).
// ---------------------------------------------------------------------------

/// One 32-bit ADD: returns `(sum, left, right, carry_aux)` for the caller to
/// place into the per-G records. Sum bits are NOT materialized in this
/// encoding (Option D).
///
/// **c is not written.** Since `C = I` in this R1CS, `c == z` byte-for-byte,
/// so callers can use `z_packed` directly as the c-side input to zerocheck —
/// no separate c buffer is needed.
///
/// Word-level derivation:
/// ```text
///   sum       = x + y (mod 2^32)
///   cin       = sum ⊕ x ⊕ y          (since sum[i] = x[i] ⊕ y[i] ⊕ cin[i])
///   left      = x ⊕ cin              (per-bit X ⊕ cin → operand_x of carry row)
///   right     = y ⊕ cin              (per-bit Y ⊕ cin → operand_y of carry row)
///   carry_aux = left ∧ right
/// ```
/// Bit 31 is the discarded mod-2³² carry-out and is masked off so the
/// record push doesn't spill into the next slot.
// Record-relative positions: carries at 31·i, lin words after all carries.
const REC_C0: usize = 0;
const REC_C1: usize = CARRY_BITS_PER_ADD;
const REC_C2: usize = 2 * CARRY_BITS_PER_ADD;
const REC_C3: usize = 3 * CARRY_BITS_PER_ADD;
const REC_C4: usize = 4 * CARRY_BITS_PER_ADD;
const REC_C5: usize = 5 * CARRY_BITS_PER_ADD;
const REC_LIN0: usize = ADDS_PER_G * CARRY_BITS_PER_ADD;
const REC_LIN1: usize = REC_LIN0 + WORD_BITS;

/// Write a 32-bit lin-id (or input) slot: (z, a) = val, b = all-ones.
/// **c is not written** — same `c == z` aliasing trick as above.
#[inline]
fn write_lin_word_ab_packed(bit_off: usize, val: u32, z: &mut [u64], a: &mut [u64], b: &mut [u64]) {
    or_u32_at_bit(z, bit_off, val);
    or_u32_at_bit(a, bit_off, val);
    or_u32_at_bit(b, bit_off, 0xFFFF_FFFF);
}

/// Build the (z, a, b) blocks for ONE compression instance, into u64 views
/// of the F128-packed per-block storage. Buffers must be zero on entry.
///
/// **No c buffer.** Since `C = I` (this is the circuit-shape R1CS), `c == z`
/// byte-for-byte; callers use `z_packed` directly as the c-side input to
/// zerocheck.
fn build_block_witness_ab_packed_into(
    cv: &[u32; 8],
    m: &[u32; 16],
    counter: u64,
    block_len: u32,
    flags: u32,
    z: &mut [u64],
    a: &mut [u64],
    b: &mut [u64],
) {
    const U64_PER_BLOCK: usize = K / 64;
    debug_assert_eq!(z.len(), U64_PER_BLOCK);
    debug_assert_eq!(a.len(), U64_PER_BLOCK);
    debug_assert_eq!(b.len(), U64_PER_BLOCK);

    // Constant z[0] = 1; a/b also 1 (z[0]·z[0] = z[0]).
    or_bit_at(z, Z_CONST_POS);
    or_bit_at(a, Z_CONST_POS);
    or_bit_at(b, Z_CONST_POS);

    // Input rows.
    let counter_lo = counter as u32;
    let counter_hi = (counter >> 32) as u32;
    for w in 0..8 {
        write_lin_word_ab_packed(cv_bit(w, 0), cv[w], z, a, b);
    }
    for i in 0..16 {
        write_lin_word_ab_packed(m_bit(i, 0), m[i], z, a, b);
    }
    write_lin_word_ab_packed(T_LO_BASE, counter_lo, z, a, b);
    write_lin_word_ab_packed(T_HI_BASE, counter_hi, z, a, b);
    write_lin_word_ab_packed(BLEN_BASE, block_len, z, a, b);
    write_lin_word_ab_packed(FLAGS_BASE, flags, z, a, b);

    // BLAKE3 state evolution.
    let mut state: [u32; 16] = [
        cv[0],
        cv[1],
        cv[2],
        cv[3],
        cv[4],
        cv[5],
        cv[6],
        cv[7],
        BLAKE3_IV[0],
        BLAKE3_IV[1],
        BLAKE3_IV[2],
        BLAKE3_IV[3],
        counter_lo,
        counter_hi,
        block_len,
        flags,
    ];
    let msg_idx = per_round_msg_idx();
    for r in 0..N_ROUNDS {
        for g_in_round in 0..N_G_PER_ROUND {
            let g = r * N_G_PER_ROUND + g_in_round;
            let [la, lb, lc, ld] = G_LANES[g_in_round];
            let [mx_i, my_i] = msg_idx[r][g_in_round];
            let mx = m[mx_i];
            let my = m[my_i];

            let a_val = state[la];
            let b_val = state[lb];
            let c_val = state[lc];
            let d_val = state[ld];

            let mut rz = BitRecord::<4>::new();
            let mut ra = BitRecord::<4>::new();
            let mut rb = BitRecord::<4>::new();

            macro_rules! add_into {
                ($pos:ident, $x:expr, $y:expr) => {{
                    let (sum, left, right, carry) = add_carry_parts($x, $y);
                    rz.push::<$pos>(carry);
                    ra.push::<$pos>(left);
                    rb.push::<$pos>(right);
                    sum
                }};
            }

            let tmp_0 = add_into!(REC_C0, a_val, b_val);
            let a_1 = add_into!(REC_C1, tmp_0, mx);
            let d_1 = (d_val ^ a_1).rotate_right(16);
            let c_1 = add_into!(REC_C2, c_val, d_1);
            let b_1 = (b_val ^ c_1).rotate_right(12);
            let tmp_1 = add_into!(REC_C3, a_1, b_1);
            let a_2 = add_into!(REC_C4, tmp_1, my);
            let d_2 = (d_1 ^ a_2).rotate_right(8);
            let c_2 = add_into!(REC_C5, c_1, d_2);
            let b_new = (b_1 ^ c_2).rotate_right(7);
            let d_new = d_2;
            rz.push::<REC_LIN0>(b_new);
            ra.push::<REC_LIN0>(b_new);
            rb.push::<REC_LIN0>(0xFFFF_FFFF);
            rz.push::<REC_LIN1>(d_new);
            ra.push::<REC_LIN1>(d_new);
            rb.push::<REC_LIN1>(0xFFFF_FFFF);

            let g_base = GS_BASE + G_STRIDE * g;
            rz.flush(z, g_base);
            ra.flush(a, g_base);
            rb.flush(b, g_base);

            state[la] = a_2;
            state[lb] = b_new;
            state[lc] = c_2;
            state[ld] = d_new;
        }
    }

    // Finalization XOR rows.
    for w in 0..8 {
        let lo = state[w] ^ state[w + 8];
        let hi = state[w + 8] ^ cv[w];
        write_lin_word_ab_packed(out_lo_bit(w, 0), lo, z, a, b);
        write_lin_word_ab_packed(out_hi_bit(w, 0), hi, z, a, b);
    }
}

/// **The fast path.** Produces `(z, a, b)` directly as F_{2^128}-packed
/// vectors — no bool intermediates, no `pack_witness` step, no
/// `apply_block_diag_packed`. Parallel across compression instances via rayon.
///
/// **No c buffer** — since `C = I` (circuit-shape R1CS), `c == z`
/// byte-for-byte; callers wrap `z_packed` as the c-side input to zerocheck.
pub fn generate_witness_with_ab_packed(
    blocks: &[Compression],
    n_blocks_log: usize,
) -> (
    Vec<flock_core::field::F128>,
    Vec<flock_core::field::F128>,
    Vec<flock_core::field::F128>,
) {
    use flock_core::field::F128;
    use rayon::prelude::*;
    let n_total = 1usize << n_blocks_log;
    let n_blocks = blocks.len();
    assert!(
        n_blocks <= n_total,
        "{n_blocks} compressions > 2^{n_blocks_log} = {n_total} slots"
    );

    const F128_PER_BLOCK: usize = K / 128;
    let total_f128 = n_total * F128_PER_BLOCK;
    let mut z = vec![F128::ZERO; total_f128];
    let mut a = vec![F128::ZERO; total_f128];
    let mut b = vec![F128::ZERO; total_f128];

    // Constant-wire pin (docs/const-wire-pin.md): padding slots get a valid
    // compression of the all-zero input (constant = 1), matching
    // [`generate_witness_with_ab_packed_and_lincheck`].
    let padding: Compression = ([0u32; 8], [0u32; 16], 0u64, 0u32, 0u32);

    z.par_chunks_mut(F128_PER_BLOCK)
        .zip(a.par_chunks_mut(F128_PER_BLOCK))
        .zip(b.par_chunks_mut(F128_PER_BLOCK))
        .enumerate()
        .for_each(|(idx, ((z_c, a_c), b_c))| {
            let (cv, m, t, bl, fl) = if idx < n_blocks {
                &blocks[idx]
            } else {
                &padding
            };
            // SAFETY: F128 is repr(C, align(16)) with LE u64 halves — same
            // byte layout as a u64 pair.
            let z_u64: &mut [u64] = unsafe {
                std::slice::from_raw_parts_mut(z_c.as_mut_ptr() as *mut u64, z_c.len() * 2)
            };
            let a_u64: &mut [u64] = unsafe {
                std::slice::from_raw_parts_mut(a_c.as_mut_ptr() as *mut u64, a_c.len() * 2)
            };
            let b_u64: &mut [u64] = unsafe {
                std::slice::from_raw_parts_mut(b_c.as_mut_ptr() as *mut u64, b_c.len() * 2)
            };
            build_block_witness_ab_packed_into(cv, m, *t, *bl, *fl, z_u64, a_u64, b_u64);
        });

    (z, a, b)
}

/// Like [`generate_witness_with_ab_packed`] but also emits the lincheck
/// byte-stripe layout in the same parallel pass. Replaces the separate
/// `pack_z_lincheck_from_packed` call entirely.
///
/// Returns `(z, a, b, z_lincheck)`; **no c buffer** (c == z byte-for-byte).
///
/// `z_lincheck` has length `n_total · K / 8`, indexed as
/// `z_lincheck[byte_idx · K + i_inner]`, with bit `r` of that byte equal to
/// `z[i_inner, 8·byte_idx + r]`.
///
/// Parallelism granularity: 8 compressions per task; each task writes its 8
/// commit chunks then bit-transposes the just-written z u64s into its
/// lincheck stripe while they are still hot in L1.
pub fn generate_witness_with_ab_packed_and_lincheck(
    blocks: &[Compression],
    n_blocks_log: usize,
) -> (
    Vec<flock_core::field::F128>,
    Vec<flock_core::field::F128>,
    Vec<flock_core::field::F128>,
    Vec<u8>,
) {
    // Constant-wire pin (docs/const-wire-pin.md): fill padding blocks with a
    // valid compression (of the all-zero input) so the constant cell is 1 in
    // every block. (The chain forbids padding, so this only affects the
    // standalone batch setup.)
    let padding: Compression = ([0u32; 8], [0u32; 16], 0u64, 0u32, 0u32);
    super::common::drive_witness_packed_and_lincheck(
        blocks,
        Some(&padding),
        n_blocks_log,
        K_LOG,
        |block: &Compression, z_u64, a_u64, b_u64| {
            let (cv, m, t, bl, fl) = block;
            build_block_witness_ab_packed_into(cv, m, *t, *bl, *fl, z_u64, a_u64, b_u64);
        },
    )
}

// ---------------------------------------------------------------------------
// Convenience API: Blake3Setup
// ---------------------------------------------------------------------------

/// Bundles the monolithic BLAKE3 compression R1CS + PCS params sized for
/// `n_blocks` compressions. Mirrors [`super::sha2::Sha256Setup`].
#[derive(Clone, Debug)]
pub struct Blake3Setup {
    pub n_blocks: usize,
    pub r1cs: BlockR1cs,
    pub pcs_params: PcsParams,
}

impl Blake3Setup {
    /// Build a setup for `n_blocks` BLAKE3 compressions with PCS
    /// `log_inv_rate = 1`.
    /// [`Self::new`] with the **batch-major** witness layout (see
    /// [`flock_core::r1cs::WitnessLayout`]). The generic matrix provers and
    /// chain/Merkle wrappers still require row-major.
    pub fn new_batch_major(n_blocks: usize) -> Self {
        let mut s = Self::new(n_blocks);
        s.r1cs.layout = flock_core::r1cs::WitnessLayout::BatchMajor;
        s
    }

    /// Fast-path witness generation dispatched on the r1cs's witness layout.
    fn generate_witness_ab(
        &self,
        blocks: &[Compression],
    ) -> (
        Vec<flock_core::field::F128>,
        Vec<flock_core::field::F128>,
        Vec<flock_core::field::F128>,
        Vec<u8>,
    ) {
        match self.r1cs.layout {
            flock_core::r1cs::WitnessLayout::RowMajor => {
                generate_witness_with_ab_packed_and_lincheck(blocks, self.n_blocks_log())
            }
            flock_core::r1cs::WitnessLayout::BatchMajor => {
                generate_witness_batch_major(blocks, self.n_blocks_log())
            }
        }
    }

    pub fn new(n_blocks: usize) -> Self {
        Self::with_log_inv_rate(n_blocks, 1)
    }

    /// Build a setup with a custom PCS `log_inv_rate`.
    pub fn with_log_inv_rate(n_blocks: usize, log_inv_rate: usize) -> Self {
        // Rate keys the legacy profiles: 1 -> Fast, 2 -> Slim.
        let profile = match log_inv_rate {
            1 => flock_core::pcs::ligerito::LigeritoProfile::Fast,
            2 => flock_core::pcs::ligerito::LigeritoProfile::Slim,
            _ => flock_core::pcs::ligerito::LigeritoProfile::Fast, // BaseFold-only rates
        };
        Self::with_profile_and_rate(n_blocks, profile, log_inv_rate)
    }

    /// Build a setup for a named Ligerito profile (fast/slim/secure);
    /// the PCS rate follows the profile.
    pub fn with_profile(
        n_blocks: usize,
        profile: flock_core::pcs::ligerito::LigeritoProfile,
    ) -> Self {
        Self::with_profile_and_rate(n_blocks, profile, profile.log_inv_rate())
    }

    fn with_profile_and_rate(
        n_blocks: usize,
        profile: flock_core::pcs::ligerito::LigeritoProfile,
        log_inv_rate: usize,
    ) -> Self {
        assert!(n_blocks >= 1, "n_blocks must be ≥ 1");
        let n_log = min_n_blocks_log(n_blocks);
        let r1cs = build_block_r1cs(n_log);
        // Warm the CSC fold circuit here so its one-time build (a pass over
        // ~21M nonzeros) stays out of the first prove/verify, and pre-fault
        // the prove-cycle scratch buffers (see scratch::prewarm_prover).
        r1cs.csc_lincheck_circuit();
        flock_core::scratch::prewarm_prover(r1cs.m);
        let pcs_params = PcsParams {
            m: r1cs.m,
            log_inv_rate,
            log_batch_size: 6,
            profile,
        };
        Self {
            n_blocks,
            r1cs,
            pcs_params,
        }
    }

    pub fn m(&self) -> usize {
        self.r1cs.m
    }
    pub fn n_blocks_log(&self) -> usize {
        self.r1cs.m - self.r1cs.k_log
    }
    pub fn n_block_slots(&self) -> usize {
        1usize << self.n_blocks_log()
    }

    pub fn generate_witness(&self, blocks: &[Compression]) -> Vec<bool> {
        assert_eq!(
            blocks.len(),
            self.n_blocks,
            "expected {} blocks, got {}",
            self.n_blocks,
            blocks.len()
        );
        generate_witness(blocks, self.n_blocks_log())
    }

    /// Full prover pipeline.
    pub fn prove<Ch: Challenger>(
        &self,
        blocks: &[Compression],
        challenger: &mut Ch,
    ) -> (R1csProof, Commitment, R1csClaim) {
        let z_packed = self.generate_witness_packed(blocks);
        crate::prover::prove(&self.r1cs, &z_packed, &self.pcs_params, challenger)
    }

    /// Packed witness trace for the generic (matrix-driven) provers — see
    /// `Sha256HybridSetup::generate_witness_packed`.
    pub fn generate_witness_packed(&self, blocks: &[Compression]) -> Vec<F128> {
        let (z_packed, _a, _b, _stripe) = self.generate_witness_ab(blocks);
        z_packed
    }

    /// Generic (matrix-driven) prover on the **Ligerito** backend — the
    /// counterpart of [`Self::prove`] (BaseFold). Same witness path;
    /// produces a proof byte-identical to [`Self::prove_fast`] and
    /// verifiable with [`Self::verify`].
    pub fn prove_ligerito<Ch: Challenger>(
        &self,
        blocks: &[Compression],
        challenger: &mut Ch,
    ) -> (flock_core::proof::R1csProofLigerito, Commitment, R1csClaim) {
        let z_packed = self.generate_witness_packed(blocks);
        crate::prover::prove_ligerito(&self.r1cs, z_packed, &self.pcs_params, challenger)
    }

    /// Like [`Self::prove`] but emits `a`, `b`, `c` during witness gen
    /// directly in F_{2^128}-packed form — no bool intermediates, no
    /// `pack_witness`, no `apply_block_diag_packed`.
    ///
    pub fn prove_fast_basefold<Ch: Challenger>(
        &self,
        blocks: &[Compression],
        challenger: &mut Ch,
    ) -> (R1csProof, Commitment, R1csClaim) {
        assert_eq!(blocks.len(), self.n_blocks);
        let (z_packed, a_packed_f128, b_packed_f128, z_packed_lincheck) =
            self.generate_witness_ab(blocks);
        let lc_circuit = self.r1cs.csc_lincheck_circuit();
        crate::prover::prove_fast_from_witness(
            &self.r1cs,
            &self.pcs_params,
            z_packed,
            a_packed_f128,
            b_packed_f128,
            z_packed_lincheck,
            lc_circuit,
            challenger,
        )
    }

    pub fn verify_basefold<Ch: Challenger>(
        &self,
        commitment: &Commitment,
        proof: &R1csProof,
        challenger: &mut Ch,
    ) -> Result<R1csClaim, verifier::VerifyError> {
        let lc_circuit = self.r1cs.csc_lincheck_circuit();
        verifier::verify(&self.r1cs, commitment, proof, lc_circuit, challenger)
    }

    /// Ligerito-backend prove. Requires m ≥ ~21.
    pub fn prove_fast<Ch: Challenger>(
        &self,
        blocks: &[Compression],
        challenger: &mut Ch,
    ) -> (flock_core::proof::R1csProofLigerito, Commitment, R1csClaim) {
        assert_eq!(blocks.len(), self.n_blocks);
        let (codeword, (z_packed, a_packed_f128, b_packed_f128, z_packed_lincheck)) =
            flock_core::pcs::prefault_codeword_during(&self.pcs_params, || {
                self.generate_witness_ab(blocks)
            });
        let lc_circuit = self.r1cs.csc_lincheck_circuit();
        crate::prover::prove_fast_ligerito_from_witness(
            &self.r1cs,
            &self.pcs_params,
            z_packed,
            a_packed_f128,
            b_packed_f128,
            z_packed_lincheck,
            lc_circuit,
            codeword,
            challenger,
        )
    }

    /// [`Self::prove_fast`] with a per-phase timing breakdown of the real
    /// Ligerito prover (witness gen + commit + zerocheck + lincheck + recursive
    /// open). Benchmark-only.
    pub fn prove_fast_timed<Ch: Challenger>(
        &self,
        blocks: &[Compression],
        challenger: &mut Ch,
    ) -> (
        flock_core::proof::R1csProofLigerito,
        Commitment,
        R1csClaim,
        crate::prover::ProvePhaseTimings,
    ) {
        assert_eq!(blocks.len(), self.n_blocks);
        let t0 = std::time::Instant::now();
        let (z_packed, a_packed_f128, b_packed_f128, z_packed_lincheck) =
            self.generate_witness_ab(blocks);
        let witness_s = t0.elapsed().as_secs_f64();
        let lc_circuit = self.r1cs.csc_lincheck_circuit();
        let (proof, commitment, claim, mut timings) = crate::prover::prove_fast_ligerito_timed(
            &self.r1cs,
            &self.pcs_params,
            z_packed,
            a_packed_f128,
            b_packed_f128,
            z_packed_lincheck,
            lc_circuit,
            None,
            challenger,
        );
        timings.witness_s = witness_s;
        (proof, commitment, claim, timings)
    }

    pub fn verify<Ch: Challenger>(
        &self,
        commitment: &Commitment,
        proof: &flock_core::proof::R1csProofLigerito,
        challenger: &mut Ch,
    ) -> Result<R1csClaim, verifier::VerifyError> {
        let lc_circuit = self.r1cs.csc_lincheck_circuit();
        verifier::verify_ligerito(
            &self.r1cs,
            commitment,
            proof,
            lc_circuit,
            &self.pcs_params,
            challenger,
        )
    }
}

// ---------------------------------------------------------------------------
// Hash chain: BLAKE3 geometry + thin wrappers over the generic chain core.
// ---------------------------------------------------------------------------

pub use super::chain_common::{ChainFold, ChainProof, ChainVerifyError};

/// BLAKE3's I/O-region geometry for the generic chain core. The input chaining
/// value `cv` sits in aligned slot 0 (byte 0), the output chaining value
/// `out_lo` in slot 1 (byte 32); each region is exactly 256 bits in a 256-bit
/// (`region_log = 8`) slot — no interior padding. Within a slot the layout is
/// word-contiguous (8 × 32-bit words), and since the low `K_SKIP = 6` physical
/// bits are the φ8 z-skip block, the fold weight matches the generic
/// `phys_weights[p] = λ[p & 63]·eq(r_rest, p >> 6)`.
pub const CHAIN_LAYOUT: super::chain_common::ChainLayout = super::chain_common::ChainLayout {
    k_log: K_LOG,
    k_skip: K_SKIP,
    region_log: 8,                    // SLOT_BITS = 2^8 = 256
    region_bits: 256,                 // 8 words × 32 bits, fills the slot exactly
    input_byte_off: CV_BASE / 8,      // 0
    output_byte_off: OUT_LO_BASE / 8, // 32
};

/// Convert a public 256-bit chaining value (8 × u32 words, LE bit order within
/// each word) to the region's **physical** within-slot bool layout. The region
/// is word-contiguous: physical bit `32·w + b` holds bit `b` of word `w`.
pub fn cv_to_phys_bits(cv: &[u32; 8]) -> Vec<bool> {
    let mut phys = vec![false; 256];
    for w in 0..8 {
        for b in 0..WORD_BITS {
            phys[WORD_BITS * w + b] = (cv[w] >> b) & 1 == 1;
        }
    }
    phys
}

impl Blake3Setup {
    /// Prove that the committed compressions form a sequential chaining-value
    /// chain: for each instance `i`, the output CV (`out_lo`) equals the input
    /// CV (`cv`) of instance `i+1`, with public endpoints `cv_0` (first input)
    /// and `cv_last` (last output).
    ///
    /// The prover is **given the full sequence** of `Compression`s (one per
    /// instance) so trace-gen is parallel; for an honest chain the caller sets
    /// `blocks[i+1].cv = out_lo(compress(blocks[i]))`.
    pub fn prove_chain_basefold<Ch: Challenger>(
        &self,
        blocks: &[Compression],
        challenger: &mut Ch,
    ) -> (ChainProof, Commitment) {
        assert_eq!(blocks.len(), self.n_blocks);
        // The chain shift sumcheck enforces the relation across ALL witness
        // slots, including padding. If n_blocks < n_block_slots, padding blocks
        // (all-zero) break the chain at the boundary and the proof cannot
        // verify with the user's intended endpoints. Require an exact fit
        // (n_blocks a power of 2 ≥ 8, the lincheck floor).
        assert_eq!(
            self.n_blocks,
            self.n_block_slots(),
            "prove_chain requires n_blocks to exactly fill n_block_slots \
             (no padding); got n_blocks={}, n_block_slots={}. Use a \
             power-of-2 ≥ 8.",
            self.n_blocks,
            self.n_block_slots(),
        );
        let n_log = self.n_blocks_log();
        let (z_packed, a_packed, b_packed, z_lincheck) =
            generate_witness_with_ab_packed_and_lincheck(blocks, n_log);
        let lc_circuit = self.r1cs.csc_lincheck_circuit();
        super::chain_common::prove_chain_generic(
            &self.r1cs,
            &self.pcs_params,
            &CHAIN_LAYOUT,
            z_packed,
            a_packed,
            b_packed,
            z_lincheck,
            lc_circuit,
            challenger,
        )
    }

    /// Ligerito-backend mirror of [`Self::prove_chain`].
    pub fn prove_chain<Ch: Challenger>(
        &self,
        blocks: &[Compression],
        challenger: &mut Ch,
    ) -> (super::chain_common::ChainProofLigerito, Commitment) {
        assert_eq!(blocks.len(), self.n_blocks);
        assert_eq!(self.n_blocks, self.n_block_slots());
        let n_log = self.n_blocks_log();
        let (z_packed, a_packed, b_packed, z_lincheck) =
            generate_witness_with_ab_packed_and_lincheck(blocks, n_log);
        let lc_circuit = self.r1cs.csc_lincheck_circuit();
        super::chain_common::prove_chain_ligerito_generic(
            &self.r1cs,
            &self.pcs_params,
            &CHAIN_LAYOUT,
            z_packed,
            a_packed,
            b_packed,
            z_lincheck,
            lc_circuit,
            challenger,
        )
    }

    pub fn verify_chain<Ch: Challenger>(
        &self,
        commitment: &Commitment,
        proof: &super::chain_common::ChainProofLigerito,
        cv_0: &[u32; 8],
        cv_last: &[u32; 8],
        challenger: &mut Ch,
    ) -> Result<(), ChainVerifyError> {
        assert_eq!(self.n_blocks, self.n_block_slots());
        let n_log = self.n_blocks_log();
        let cv_0_phys = cv_to_phys_bits(cv_0);
        let cv_last_phys = cv_to_phys_bits(cv_last);
        let lc_circuit = self.r1cs.csc_lincheck_circuit();
        super::chain_common::verify_chain_ligerito_generic(
            &self.r1cs,
            &CHAIN_LAYOUT,
            commitment,
            proof,
            n_log,
            &cv_0_phys,
            &cv_last_phys,
            lc_circuit,
            &self.pcs_params,
            challenger,
        )
    }

    /// Verify a [`ChainProof`] against public endpoints `cv_0` (first input CV)
    /// and `cv_last` (last output CV).
    pub fn verify_chain_basefold<Ch: Challenger>(
        &self,
        commitment: &Commitment,
        proof: &ChainProof,
        cv_0: &[u32; 8],
        cv_last: &[u32; 8],
        challenger: &mut Ch,
    ) -> Result<(), ChainVerifyError> {
        // Mirror `prove_chain`'s requirement: chain proof must cover exactly
        // one compression per witness slot (no padding) to be meaningful.
        assert_eq!(
            self.n_blocks,
            self.n_block_slots(),
            "verify_chain requires n_blocks to exactly fill n_block_slots \
             (no padding); got n_blocks={}, n_block_slots={}. Use a \
             power-of-2 ≥ 8.",
            self.n_blocks,
            self.n_block_slots(),
        );
        let n_log = self.n_blocks_log();
        let cv0_phys = cv_to_phys_bits(cv_0);
        let cvlast_phys = cv_to_phys_bits(cv_last);
        let lc_circuit = self.r1cs.csc_lincheck_circuit();
        super::chain_common::verify_chain_generic(
            &self.r1cs,
            &CHAIN_LAYOUT,
            commitment,
            proof,
            n_log,
            &cv0_phys,
            &cvlast_phys,
            lc_circuit,
            challenger,
        )
    }
}

// ---------------------------------------------------------------------------
// Tests
// ---------------------------------------------------------------------------

// ---------------------------------------------------------------------------
// Batch-major witness producer (WitnessLayout::BatchMajor).
//
// V = 8 compressions in lockstep ([u32; 8] lanes); witness fields OR'd
// V-wide into an L1-resident interleaved row buffer (already batch-major
// order), NT-flushed per useful 128-bit chunk by the shared driver. See
// `common::drive_witness_batch_major`.
// ---------------------------------------------------------------------------

use super::common::{BM_V, BmRow, add_carry_parts_v, or_bit_row, or_u32_row};

#[inline(always)]
fn bm_xor_rotr(x: &[u32; BM_V], y: &[u32; BM_V], r: u32) -> [u32; BM_V] {
    std::array::from_fn(|j| (x[j] ^ y[j]).rotate_right(r))
}

struct BmRows<'a> {
    z: &'a mut [BmRow],
    a: &'a mut [BmRow],
    b: &'a mut [BmRow],
}

#[inline(always)]
fn bm_write_lin(rows: &mut BmRows<'_>, bit: usize, vals: &[u32; BM_V]) {
    or_u32_row(rows.z, bit, vals);
    or_u32_row(rows.a, bit, vals);
    or_u32_row(rows.b, bit, &[0xFFFF_FFFF; BM_V]);
}

#[inline(always)]
fn bm_add_inline(
    rows: &mut BmRows<'_>,
    x: &[u32; BM_V],
    y: &[u32; BM_V],
    carry_bit: usize,
) -> [u32; BM_V] {
    let (sum, left, right, carry) = add_carry_parts_v(x, y);
    or_u32_row(rows.z, carry_bit, &carry);
    or_u32_row(rows.a, carry_bit, &left);
    or_u32_row(rows.b, carry_bit, &right);
    sum
}

/// Build one V = 8 group of compressions into interleaved rows. Mirrors
/// [`build_block_witness_ab_packed_into`] field-for-field (byte-equality is
/// pinned by the lockstep test below).
fn build_group_batch_major(
    inputs: [&Compression; BM_V],
    rz: &mut [BmRow],
    ra: &mut [BmRow],
    rb: &mut [BmRow],
) {
    let mut rows = BmRows {
        z: rz,
        a: ra,
        b: rb,
    };
    let cv: [[u32; BM_V]; 8] = std::array::from_fn(|w| std::array::from_fn(|j| inputs[j].0[w]));
    let m: [[u32; BM_V]; 16] = std::array::from_fn(|i| std::array::from_fn(|j| inputs[j].1[i]));
    let counter_lo: [u32; BM_V] = std::array::from_fn(|j| inputs[j].2 as u32);
    let counter_hi: [u32; BM_V] = std::array::from_fn(|j| (inputs[j].2 >> 32) as u32);
    let block_len: [u32; BM_V] = std::array::from_fn(|j| inputs[j].3);
    let flags: [u32; BM_V] = std::array::from_fn(|j| inputs[j].4);

    or_bit_row(rows.z, Z_CONST_POS);
    or_bit_row(rows.a, Z_CONST_POS);
    or_bit_row(rows.b, Z_CONST_POS);

    for w in 0..8 {
        bm_write_lin(&mut rows, cv_bit(w, 0), &cv[w]);
    }
    for i in 0..16 {
        bm_write_lin(&mut rows, m_bit(i, 0), &m[i]);
    }
    bm_write_lin(&mut rows, T_LO_BASE, &counter_lo);
    bm_write_lin(&mut rows, T_HI_BASE, &counter_hi);
    bm_write_lin(&mut rows, BLEN_BASE, &block_len);
    bm_write_lin(&mut rows, FLAGS_BASE, &flags);

    let mut state: [[u32; BM_V]; 16] = [
        cv[0],
        cv[1],
        cv[2],
        cv[3],
        cv[4],
        cv[5],
        cv[6],
        cv[7],
        [BLAKE3_IV[0]; BM_V],
        [BLAKE3_IV[1]; BM_V],
        [BLAKE3_IV[2]; BM_V],
        [BLAKE3_IV[3]; BM_V],
        counter_lo,
        counter_hi,
        block_len,
        flags,
    ];
    let msg_idx = per_round_msg_idx();
    for r in 0..N_ROUNDS {
        for g_in_round in 0..N_G_PER_ROUND {
            let g = r * N_G_PER_ROUND + g_in_round;
            let [la, lb, lc, ld] = G_LANES[g_in_round];
            let [mx_i, my_i] = msg_idx[r][g_in_round];
            let mx = m[mx_i];
            let my = m[my_i];

            let a_val = state[la];
            let b_val = state[lb];
            let c_val = state[lc];
            let d_val = state[ld];

            let tmp_0 = bm_add_inline(&mut rows, &a_val, &b_val, g_add_carry_bit(g, ADD_TMP0, 0));
            let a_1 = bm_add_inline(&mut rows, &tmp_0, &mx, g_add_carry_bit(g, ADD_A1, 0));
            let d_1 = bm_xor_rotr(&d_val, &a_1, 16);
            let c_1 = bm_add_inline(&mut rows, &c_val, &d_1, g_add_carry_bit(g, ADD_C1, 0));
            let b_1 = bm_xor_rotr(&b_val, &c_1, 12);
            let tmp_1 = bm_add_inline(&mut rows, &a_1, &b_1, g_add_carry_bit(g, ADD_TMP1, 0));
            let a_2 = bm_add_inline(&mut rows, &tmp_1, &my, g_add_carry_bit(g, ADD_A2, 0));
            let d_2 = bm_xor_rotr(&d_1, &a_2, 8);
            let c_2 = bm_add_inline(&mut rows, &c_1, &d_2, g_add_carry_bit(g, ADD_C2, 0));
            let b_new = bm_xor_rotr(&b_1, &c_2, 7);
            let d_new = d_2;
            bm_write_lin(&mut rows, g_lin_bit(g, LIN_B_NEW, 0), &b_new);
            bm_write_lin(&mut rows, g_lin_bit(g, LIN_D_NEW, 0), &d_new);

            state[la] = a_2;
            state[lb] = b_new;
            state[lc] = c_2;
            state[ld] = d_new;
        }
    }

    for w in 0..8 {
        let lo: [u32; BM_V] = std::array::from_fn(|j| state[w][j] ^ state[w + 8][j]);
        let hi: [u32; BM_V] = std::array::from_fn(|j| state[w + 8][j] ^ cv[w][j]);
        bm_write_lin(&mut rows, out_lo_bit(w, 0), &lo);
        bm_write_lin(&mut rows, out_hi_bit(w, 0), &hi);
    }
}

/// Batch-major counterpart of [`generate_witness_with_ab_packed_and_lincheck`]
/// — `(z, a, b, z_lincheck)` with z/a/b in the batch-major layout. Padding
/// slots run a compression of the all-zero input (constant wire = 1).
pub fn generate_witness_batch_major(
    blocks: &[Compression],
    n_blocks_log: usize,
) -> (
    Vec<flock_core::field::F128>,
    Vec<flock_core::field::F128>,
    Vec<flock_core::field::F128>,
    Vec<u8>,
) {
    let padding: Compression = ([0u32; 8], [0u32; 16], 0u64, 0u32, 0u32);
    super::common::drive_witness_batch_major(
        blocks,
        &padding,
        n_blocks_log,
        K_LOG,
        USEFUL_BITS,
        build_group_batch_major,
    )
}

#[cfg(test)]
mod tests {
    use super::*;

    /// SplitMix64.
    struct Rng(u64);
    impl Rng {
        fn new(seed: u64) -> Self {
            Self(seed)
        }
        fn next_u32(&mut self) -> u32 {
            self.0 = self.0.wrapping_add(0x9E3779B97F4A7C15);
            let mut z = self.0;
            z = (z ^ (z >> 30)).wrapping_mul(0xBF58476D1CE4E5B9);
            z = (z ^ (z >> 27)).wrapping_mul(0x94D049BB133111EB);
            (z ^ (z >> 31)) as u32
        }
    }

    /// BLAKE3 chunk flags (subset).
    const CHUNK_START: u32 = 1 << 0;
    const CHUNK_END: u32 = 1 << 1;
    const ROOT: u32 = 1 << 3;

    /// Batch-major witness equality vs the row-major driver (word-transpose
    /// + identical stripe), incl. padding slots via a non-power-of-two count.
    #[test]
    fn batch_major_witness_matches_row_major_transposed() {
        for (n_inputs, n_log) in [(8usize, 3usize), (11, 4)] {
            let mut rng = Rng::new(0xBA7C_B3 + n_log as u64);
            let inputs: Vec<Compression> = (0..n_inputs)
                .map(|_| {
                    let cv: [u32; 8] = std::array::from_fn(|_| rng.next_u32());
                    let m: [u32; 16] = std::array::from_fn(|_| rng.next_u32());
                    let counter = ((rng.next_u32() as u64) << 32) | (rng.next_u32() as u64);
                    (cv, m, counter, 64u32, 11u32)
                })
                .collect();

            let (z_r, a_r, b_r, stripe_r) =
                generate_witness_with_ab_packed_and_lincheck(&inputs, n_log);
            let (z_b, a_b, b_b, stripe_b) = generate_witness_batch_major(&inputs, n_log);

            assert_eq!(stripe_b, stripe_r, "stripe diverged (n_log={n_log})");

            let chunks_per_block = K / 128;
            let transpose = |row: &[flock_core::field::F128]| {
                let mut out = vec![flock_core::field::F128::ZERO; row.len()];
                for o in 0..1usize << n_log {
                    for c in 0..chunks_per_block {
                        out[(c << n_log) + o] = row[o * chunks_per_block + c];
                    }
                }
                out
            };
            assert_eq!(z_b, transpose(&z_r), "z diverged (n_log={n_log})");
            assert_eq!(a_b, transpose(&a_r), "a diverged (n_log={n_log})");
            assert_eq!(b_b, transpose(&b_r), "b diverged (n_log={n_log})");
        }
    }

    /// Batch-major end-to-end roundtrip (BaseFold) + tamper rejection.
    #[test]
    fn batch_major_prove_fast_basefold_roundtrip() {
        use flock_core::challenger::FsChallenger;

        let setup = Blake3Setup::new_batch_major(8);
        let mut rng = Rng::new(0xBA7C_F013);
        let inputs: Vec<Compression> = (0..8)
            .map(|_| {
                let cv: [u32; 8] = std::array::from_fn(|_| rng.next_u32());
                let m: [u32; 16] = std::array::from_fn(|_| rng.next_u32());
                let counter = ((rng.next_u32() as u64) << 32) | (rng.next_u32() as u64);
                (cv, m, counter, 64u32, 11u32)
            })
            .collect();

        let mut ch_p = FsChallenger::new(b"flock-test-v0");
        let (proof, commitment, claim_p) = setup.prove_fast_basefold(&inputs, &mut ch_p);
        let mut ch_v = FsChallenger::new(b"flock-test-v0");
        let claim_v = setup
            .verify_basefold(&commitment, &proof, &mut ch_v)
            .unwrap_or_else(|e| panic!("batch-major verifier rejected: {e:?}"));
        assert_eq!(claim_p, claim_v);

        let mut bad = proof.clone();
        bad.zerocheck.final_a_eval.lo ^= 1;
        let mut ch = FsChallenger::new(b"flock-test-v0");
        assert!(
            setup.verify_basefold(&commitment, &bad, &mut ch).is_err(),
            "tampered batch-major proof accepted"
        );
    }

    #[test]
    fn layout_constants() {
        // I/O-aligned layout: cv in slot 0, out_lo in slot 1 (both 256-bit).
        assert_eq!(CV_BASE, 0);
        assert_eq!(OUT_LO_BASE, 256);
        assert_eq!(Z_CONST_POS, 512);
        assert_eq!(M_BASE, 513);
        assert_eq!(GS_BASE, 1153);
        assert_eq!(G_STRIDE, 250);
        assert_eq!(N_G, 56);
        assert_eq!(OUT_HI_BASE, 15_153);
        assert_eq!(USEFUL_BITS, 15_409);
        assert!(USEFUL_BITS <= K);
        assert_eq!(CV_BASE % SLOT_BITS, 0);
        assert_eq!(OUT_LO_BASE % SLOT_BITS, 0);
    }

    /// Reference compression matches the `blake3` crate for empty input
    /// (a single root-block, single-chunk, ROOT-flagged compression).
    #[test]
    fn compress_matches_blake3_crate_empty() {
        let state = blake3_compress(
            &BLAKE3_IV,
            &[0u32; 16],
            0,
            0,
            CHUNK_START | CHUNK_END | ROOT,
        );
        let mut got = [0u8; 32];
        for w in 0..8 {
            got[w * 4..w * 4 + 4].copy_from_slice(&state[w].to_le_bytes());
        }
        let expected = *::blake3::hash(b"").as_bytes();
        assert_eq!(got, expected);
    }

    /// Reference compression matches the `blake3` crate for a full 64-byte
    /// input (single block + single chunk + root).
    #[test]
    fn compress_matches_blake3_crate_64_bytes() {
        let mut rng = Rng::new(0xDEAD_BEEF);
        let mut bytes = [0u8; 64];
        for byte in bytes.iter_mut() {
            *byte = (rng.next_u32() & 0xFF) as u8;
        }
        let mut m = [0u32; 16];
        for i in 0..16 {
            m[i] = u32::from_le_bytes(bytes[i * 4..i * 4 + 4].try_into().unwrap());
        }
        let state = blake3_compress(&BLAKE3_IV, &m, 0, 64, CHUNK_START | CHUNK_END | ROOT);
        let mut got = [0u8; 32];
        for w in 0..8 {
            got[w * 4..w * 4 + 4].copy_from_slice(&state[w].to_le_bytes());
        }
        let expected = *::blake3::hash(&bytes).as_bytes();
        assert_eq!(got, expected);
    }

    /// Witness's out_lo / out_hi slots equal the BLAKE3 finalization XORs.
    #[test]
    fn witness_encodes_correct_output() {
        let mut rng = Rng::new(0x1234_5678);
        let cv: [u32; 8] = std::array::from_fn(|_| rng.next_u32());
        let m: [u32; 16] = std::array::from_fn(|_| rng.next_u32());
        let counter = ((rng.next_u32() as u64) << 32) | (rng.next_u32() as u64);
        let block_len = 64;
        let flags = CHUNK_START | CHUNK_END | ROOT;
        let z = build_block_witness(&cv, &m, counter, block_len, flags);
        let expected = blake3_compress(&cv, &m, counter, block_len, flags);
        for w in 0..8 {
            let mut got = 0u32;
            for b in 0..WORD_BITS {
                if z[out_lo_bit(w, b)] {
                    got |= 1 << b;
                }
            }
            assert_eq!(got, expected[w], "out_lo[{w}] mismatch");
            let mut got_hi = 0u32;
            for b in 0..WORD_BITS {
                if z[out_hi_bit(w, b)] {
                    got_hi |= 1 << b;
                }
            }
            assert_eq!(got_hi, expected[w + 8], "out_hi[{w}] mismatch");
        }
    }

    #[test]
    fn honest_witness_satisfies_r1cs() {
        let mut rng = Rng::new(0xCAFE_F00D);
        for &n_blocks in &[1usize, 3, 8] {
            let n_log = min_n_blocks_log(n_blocks).max(3);
            let r1cs = build_block_r1cs(n_log);
            let blocks: Vec<Compression> = (0..n_blocks)
                .map(|_| {
                    let cv: [u32; 8] = std::array::from_fn(|_| rng.next_u32());
                    let m: [u32; 16] = std::array::from_fn(|_| rng.next_u32());
                    (cv, m, rng.next_u32() as u64, 64u32, 11u32)
                })
                .collect();
            let z = generate_witness(&blocks, n_log);
            assert_eq!(z.len(), r1cs.n());
            assert!(
                r1cs.satisfies(&z),
                "witness for {n_blocks} compressions fails R1CS"
            );
        }
    }

    #[test]
    fn mutated_witness_fails() {
        let mut rng = Rng::new(0xBEEF_F00D);
        let cv: [u32; 8] = std::array::from_fn(|_| rng.next_u32());
        let m: [u32; 16] = std::array::from_fn(|_| rng.next_u32());
        let r1cs = build_block_r1cs(3);
        let blocks = vec![(cv, m, 0u64, 64u32, 11u32)];
        let mut z = generate_witness(&blocks, 3);
        assert!(r1cs.satisfies(&z));
        // Flip a carry_aux bit inside G #10 (middle of round 1).
        z[g_add_carry_bit(10, ADD_A2, 5)] ^= true;
        assert!(
            !r1cs.satisfies(&z),
            "tampered carry bit should violate R1CS"
        );
    }

    /// End-to-end prove/verify for one compression. Slow in debug, fast in
    /// release.
    #[test]
    fn end_to_end_prove_verify() {
        use flock_core::challenger::FsChallenger;
        let setup = Blake3Setup::new(1);
        let mut rng = Rng::new(0xC0DE_5A55);
        let cv: [u32; 8] = std::array::from_fn(|_| rng.next_u32());
        let m: [u32; 16] = std::array::from_fn(|_| rng.next_u32());
        let blocks = vec![(cv, m, 0u64, 64u32, 11u32)];
        let mut ch_p = FsChallenger::new(b"flock-test-v0");
        let (proof, commitment, claim_p) = setup.prove(&blocks, &mut ch_p);
        let mut ch_v = FsChallenger::new(b"flock-test-v0");
        let claim_v = setup
            .verify_basefold(&commitment, &proof, &mut ch_v)
            .unwrap_or_else(|e| panic!("verify rejected honest BLAKE3 proof: {e:?}"));
        assert_eq!(claim_p, claim_v);
    }

    /// A mutated BLAKE3 witness produces a proof that fails verification.
    #[test]
    fn verify_rejects_mutation() {
        use flock_core::challenger::FsChallenger;
        let setup = Blake3Setup::new(1);
        let mut rng = Rng::new(0xBADD_BEEF);
        let cv: [u32; 8] = std::array::from_fn(|_| rng.next_u32());
        let m: [u32; 16] = std::array::from_fn(|_| rng.next_u32());
        let blocks = vec![(cv, m, 0u64, 64u32, 11u32)];
        let mut z = setup.generate_witness(&blocks);
        assert!(setup.r1cs.satisfies(&z));
        z[g_add_carry_bit(15, ADD_A2, 3)] ^= true;
        assert!(!setup.r1cs.satisfies(&z));
        let mut ch_p = FsChallenger::new(b"flock-test-v0");
        let z_packed = flock_core::pcs::pack_witness(&z, setup.r1cs.m);
        let (proof, commitment, _) =
            crate::prover::prove(&setup.r1cs, &z_packed, &setup.pcs_params, &mut ch_p);
        let mut ch_v = FsChallenger::new(b"flock-test-v0");
        assert!(
            setup
                .verify_basefold(&commitment, &proof, &mut ch_v)
                .is_err(),
            "tampered witness produced an accepted proof"
        );
    }

    /// `generate_witness_with_ab_packed` agrees with the matrix-vector
    /// products `apply_a_packed(z)` and `apply_b_packed(z)`. Also asserts
    /// `apply_c_packed(z) == z` (C = I), validating the aliasing assumption
    /// used by prove_fast.
    #[test]
    fn generate_witness_with_ab_packed_matches_apply() {
        for &n_blocks in &[1usize, 4, 8] {
            let n_log = min_n_blocks_log(n_blocks).max(3);
            let r1cs = build_block_r1cs(n_log);
            let mut rng = Rng::new(0xABCD_5A55 + n_blocks as u64);
            let blocks: Vec<Compression> = (0..n_blocks)
                .map(|_| {
                    let cv: [u32; 8] = std::array::from_fn(|_| rng.next_u32());
                    let m: [u32; 16] = std::array::from_fn(|_| rng.next_u32());
                    (cv, m, rng.next_u32() as u64, 64u32, 11u32)
                })
                .collect();

            let (z, a, b) = generate_witness_with_ab_packed(&blocks, n_log);
            let a_ref = r1cs.apply_a_packed(&z);
            let b_ref = r1cs.apply_b_packed(&z);
            let c_ref = r1cs.apply_c_packed(&z);
            assert_eq!(a, a_ref, "a mismatch at n_blocks={n_blocks}");
            assert_eq!(b, b_ref, "b mismatch at n_blocks={n_blocks}");
            // C = I, so c == z. prove_fast relies on this for the c-aliasing.
            assert_eq!(c_ref, z, "C is not identity at n_blocks={n_blocks}");
            assert!(r1cs.satisfies_packed(&z));
        }
    }

    /// The fused generator produces (z, a, b) byte-identical to
    /// `generate_witness_with_ab_packed` AND a lincheck stripe byte-identical
    /// `Blake3LincheckCircuit` walker matches the sparse fold byte-for-byte
    /// at random α + random eq_inner.
    #[test]
    fn lincheck_circuit_matches_sparse() {
        use flock_core::lincheck::{LincheckCircuit, SparseMatrixCircuit};

        let mut rng = Rng::new(0xB1A_E3_CCA1);
        let (a_0, b_0) = build_matrices();
        let sparse = SparseMatrixCircuit::new(&a_0, &b_0);
        let walker = Blake3LincheckCircuit;
        assert_eq!(sparse.n_cols(), walker.n_cols());

        let n_cols = walker.n_cols();
        let alpha = F128 {
            lo: ((rng.next_u32() as u64) << 32) | rng.next_u32() as u64,
            hi: ((rng.next_u32() as u64) << 32) | rng.next_u32() as u64,
        };
        let eq_inner: Vec<F128> = (0..n_cols)
            .map(|_| F128 {
                lo: ((rng.next_u32() as u64) << 32) | rng.next_u32() as u64,
                hi: ((rng.next_u32() as u64) << 32) | rng.next_u32() as u64,
            })
            .collect();

        let expected = sparse.fold_alpha_batched(alpha, &eq_inner);
        let got = walker.fold_alpha_batched(alpha, &eq_inner);
        for c in 0..n_cols {
            assert_eq!(expected[c], got[c], "comb mismatch at col {c}");
        }

        // CSC gather (what prove_fast/verify actually use) matches too.
        let csc = flock_core::lincheck::CscCircuit::from_matrices(&a_0, &b_0);
        let got_csc = csc.fold_alpha_batched(alpha, &eq_inner);
        assert_eq!(expected, got_csc, "CSC fold mismatch");
    }

    /// to `pack_z_lincheck_from_packed(z)`.
    #[test]
    fn fused_lincheck_matches_separate() {
        use flock_core::lincheck::pack_z_lincheck_from_packed;
        for &n_blocks in &[1usize, 4, 8, 13] {
            let n_log = min_n_blocks_log(n_blocks).max(3);
            let r1cs = build_block_r1cs(n_log);
            let mut rng = Rng::new(0xABCD_EF00 + n_blocks as u64);
            let blocks: Vec<Compression> = (0..n_blocks)
                .map(|_| {
                    let cv: [u32; 8] = std::array::from_fn(|_| rng.next_u32());
                    let m: [u32; 16] = std::array::from_fn(|_| rng.next_u32());
                    (cv, m, rng.next_u32() as u64, 64u32, 11u32)
                })
                .collect();

            let (z1, a1, b1) = generate_witness_with_ab_packed(&blocks, n_log);
            let lincheck_ref = pack_z_lincheck_from_packed(&z1, r1cs.m, r1cs.k_log);
            let (z2, a2, b2, lincheck_new) =
                generate_witness_with_ab_packed_and_lincheck(&blocks, n_log);
            assert_eq!(z1, z2, "z mismatch at n_blocks={n_blocks}");
            assert_eq!(a1, a2, "a mismatch at n_blocks={n_blocks}");
            assert_eq!(b1, b2, "b mismatch at n_blocks={n_blocks}");
            assert_eq!(
                lincheck_ref, lincheck_new,
                "lincheck stripe mismatch at n_blocks={n_blocks}"
            );
        }
    }

    /// Full prove→verify round-trip through the Ligerito PCS for EACH named
    /// profile (fast = JohnsonOod 100-bit, slim = JohnsonOod 100-bit + query
    /// grinding, secure = UDR 120-bit). 256 blocks → m=22, the smallest
    /// embedded config. Drives OOD binding + fold grinding through the real
    /// R1CS / ring-switch / recursive-sumcheck pipeline end to end.
    #[test]
    fn prove_verify_ligerito_all_profiles() {
        use flock_core::challenger::FsChallenger;
        use flock_core::pcs::ligerito::LigeritoProfile;
        let blocks: Vec<Compression> = {
            let mut rng = Rng::new(0x9A11_0F11);
            (0..256)
                .map(|_| {
                    let cv: [u32; 8] = std::array::from_fn(|_| rng.next_u32());
                    let m: [u32; 16] = std::array::from_fn(|_| rng.next_u32());
                    (cv, m, 0u64, 64u32, 11u32)
                })
                .collect()
        };
        for profile in [
            LigeritoProfile::Fast,
            LigeritoProfile::Slim,
            LigeritoProfile::Secure,
        ] {
            let setup = Blake3Setup::with_profile(256, profile);
            let mut ch_p = FsChallenger::new(b"flock-blake3-prof");
            let (proof, commitment, claim_p) = setup.prove_ligerito(&blocks, &mut ch_p);
            let mut ch_v = FsChallenger::new(b"flock-blake3-prof");
            let claim_v = setup
                .verify(&commitment, &proof, &mut ch_v)
                .unwrap_or_else(|e| {
                    panic!(
                        "ligerito verify rejected for profile {}: {e:?}",
                        profile.as_str()
                    )
                });
            assert_eq!(
                claim_p,
                claim_v,
                "claim mismatch for profile {}",
                profile.as_str()
            );
        }
    }

    /// Ligerito-backend prove_fast roundtrip. Needs ≥ 256 blocks (m=22) for
    /// the default Ligerito config at log_batch_size=6.
    #[test]
    #[ignore]
    fn prove_fast_ligerito_roundtrip() {
        use flock_core::challenger::FsChallenger;
        let setup = Blake3Setup::new(256);
        let mut rng = Rng::new(0xb1a_3211e);
        let blocks: Vec<Compression> = (0..256)
            .map(|_| {
                let cv: [u32; 8] = std::array::from_fn(|_| rng.next_u32());
                let m: [u32; 16] = std::array::from_fn(|_| rng.next_u32());
                (cv, m, 0u64, 64u32, 11u32)
            })
            .collect();
        let mut ch_p = FsChallenger::new(b"flock-blake3-lig-v0");
        let (proof, commitment, claim_p) = setup.prove_fast(&blocks, &mut ch_p);
        let mut ch_v = FsChallenger::new(b"flock-blake3-lig-v0");
        let claim_v = setup
            .verify(&commitment, &proof, &mut ch_v)
            .unwrap_or_else(|e| panic!("ligerito verify rejected: {e:?}"));
        assert_eq!(claim_p, claim_v);
    }

    /// Generic (matrix-driven) Ligerito prove produces a byte-identical
    /// proof to the specialized `prove_fast` — pins that the generic path
    /// (bool trace → pack → apply → prove) and the fused path agree.
    #[test]
    fn prove_ligerito_generic_matches_prove_fast() {
        use flock_core::challenger::FsChallenger;
        let setup = Blake3Setup::new(256);
        let mut rng = Rng::new(0xb1a_63112);
        let blocks: Vec<Compression> = (0..256)
            .map(|_| {
                let cv: [u32; 8] = std::array::from_fn(|_| rng.next_u32());
                let m: [u32; 16] = std::array::from_fn(|_| rng.next_u32());
                (cv, m, 0u64, 64u32, 11u32)
            })
            .collect();
        let mut ch_f = FsChallenger::new(b"flock-blake3-gvf");
        let (proof_f, commit_f, claim_f) = setup.prove_fast(&blocks, &mut ch_f);
        let mut ch_g = FsChallenger::new(b"flock-blake3-gvf");
        let (proof_g, commit_g, claim_g) = setup.prove_ligerito(&blocks, &mut ch_g);
        assert_eq!(commit_f.root, commit_g.root);
        assert_eq!(claim_f, claim_g);
        assert_eq!(
            bincode::serialize(&proof_f).unwrap(),
            bincode::serialize(&proof_g).unwrap(),
            "generic and fused Ligerito proofs must be byte-identical"
        );
    }

    /// `prove_fast_basefold` produces an accepting proof (legacy BaseFold path).
    #[test]
    fn prove_fast_basefold_roundtrip() {
        use flock_core::challenger::FsChallenger;
        let setup = Blake3Setup::new(1);
        let mut rng = Rng::new(0xFA57_5A55);
        let cv: [u32; 8] = std::array::from_fn(|_| rng.next_u32());
        let m: [u32; 16] = std::array::from_fn(|_| rng.next_u32());
        let blocks = vec![(cv, m, 0u64, 64u32, 11u32)];
        let mut ch_p = FsChallenger::new(b"flock-test-v0");
        let (proof, commitment, claim_p) = setup.prove_fast_basefold(&blocks, &mut ch_p);
        let mut ch_v = FsChallenger::new(b"flock-test-v0");
        let claim_v = setup
            .verify_basefold(&commitment, &proof, &mut ch_v)
            .unwrap_or_else(|e| panic!("prove_fast_basefold: verifier rejected: {e:?}"));
        assert_eq!(claim_p, claim_v);
    }

    /// Constant-wire pin (docs/const-wire-pin.md). `new(5)` has padding blocks
    /// (filled with a valid all-zero-input compression, constant = 1) so the
    /// honest proof verifies; the all-zero witness must be rejected by the pin.
    /// (For BLAKE3 the pin lives on the R1CS-built CSC circuit, not the walker.)
    #[test]
    fn const_pin_all_zero_rejected() {
        use flock_core::challenger::FsChallenger;

        let n = 5; // 3 padding blocks
        let setup = Blake3Setup::new(n);

        // (1) Honest proof with filled padding verifies.
        let mut rng = Rng::new(0x5EED_B1A3);
        let blocks: Vec<Compression> = (0..n)
            .map(|_| {
                let cv: [u32; 8] = std::array::from_fn(|_| rng.next_u32());
                let m: [u32; 16] = std::array::from_fn(|_| rng.next_u32());
                (cv, m, rng.next_u32() as u64, 64u32, 11u32)
            })
            .collect();
        let mut ch_p = FsChallenger::new(b"honest");
        let (proof, commitment, claim_p) = setup.prove_fast_basefold(&blocks, &mut ch_p);
        let mut ch_v = FsChallenger::new(b"honest");
        let claim_v = setup
            .verify_basefold(&commitment, &proof, &mut ch_v)
            .unwrap_or_else(|e| panic!("honest padded proof rejected: {e:?}"));
        assert_eq!(claim_p, claim_v);

        // (2) All-zero witness must be rejected by the pin.
        let zeros: Vec<Compression> = vec![([0u32; 8], [0u32; 16], 0u64, 0u32, 0u32); n];
        let (mut z, mut a, mut b, mut zlc) =
            generate_witness_with_ab_packed_and_lincheck(&zeros, setup.n_blocks_log());
        z.iter_mut()
            .for_each(|v| *v = flock_core::field::F128::ZERO);
        a.iter_mut()
            .for_each(|v| *v = flock_core::field::F128::ZERO);
        b.iter_mut()
            .for_each(|v| *v = flock_core::field::F128::ZERO);
        zlc.iter_mut().for_each(|v| *v = 0);
        let circuit = setup.r1cs.csc_lincheck_circuit();
        let mut ch_p = FsChallenger::new(b"poc");
        let (proof, commitment, _) = crate::prover::prove_fast_from_witness(
            &setup.r1cs,
            &setup.pcs_params,
            z,
            a,
            b,
            zlc,
            circuit,
            &mut ch_p,
        );
        let mut ch_v = FsChallenger::new(b"poc");
        let res = setup.verify_basefold(&commitment, &proof, &mut ch_v);
        assert!(
            matches!(res, Err(flock_core::verifier::VerifyError::Lincheck(_))),
            "all-zero witness must be rejected by the constant-wire pin; got {res:?}"
        );
    }

    /// `prove_fast_basefold` matches `prove` (same commitment + claim).
    #[test]
    fn prove_fast_basefold_matches_prove() {
        use flock_core::challenger::FsChallenger;
        let setup = Blake3Setup::new(1);
        let mut rng = Rng::new(0xDEED_1234);
        let cv: [u32; 8] = std::array::from_fn(|_| rng.next_u32());
        let m: [u32; 16] = std::array::from_fn(|_| rng.next_u32());
        let blocks = vec![(cv, m, 0u64, 64u32, 11u32)];
        let mut ch1 = FsChallenger::new(b"flock-test-v0");
        let (_p1, c1, claim1) = setup.prove(&blocks, &mut ch1);
        let mut ch2 = FsChallenger::new(b"flock-test-v0");
        let (_p2, c2, claim2) = setup.prove_fast_basefold(&blocks, &mut ch2);
        assert_eq!(c1.root, c2.root, "commitments must match");
        assert_eq!(claim1, claim2, "claims must match");
    }

    #[test]
    fn setup_sizes_correctly() {
        for &(n_blocks, expected_n_log) in
            &[(1usize, 3), (8, 3), (9, 4), (16, 4), (17, 5), (1000, 10)]
        {
            let setup = Blake3Setup::new(n_blocks);
            assert_eq!(setup.n_blocks_log(), expected_n_log, "n_blocks={n_blocks}");
            assert_eq!(setup.m(), K_LOG + expected_n_log);
            assert!(setup.n_block_slots() >= n_blocks);
        }
    }
}

#[cfg(test)]
mod chain_e2e_tests {
    use super::*;
    use flock_core::challenger::FsChallenger;

    struct R(u64);
    impl R {
        fn nx(&mut self) -> u64 {
            self.0 = self.0.wrapping_add(0x9E3779B97F4A7C15);
            let mut z = self.0;
            z = (z ^ (z >> 30)).wrapping_mul(0xBF58476D1CE4E5B9);
            z = (z ^ (z >> 27)).wrapping_mul(0x94D049BB133111EB);
            z ^ (z >> 31)
        }
        fn w(&mut self) -> u32 {
            self.nx() as u32
        }
        fn cv(&mut self) -> [u32; 8] {
            let mut c = [0u32; 8];
            for x in c.iter_mut() {
                *x = self.w();
            }
            c
        }
        fn msg(&mut self) -> [u32; 16] {
            let mut m = [0u32; 16];
            for x in m.iter_mut() {
                *x = self.w();
            }
            m
        }
    }

    /// The new chaining value out of `compress` is `state[0..8]` = `out_lo`.
    fn out_cv(block: &Compression) -> [u32; 8] {
        let (cv, m, ctr, blen, flags) = block;
        let st = blake3_compress(cv, m, *ctr, *blen, *flags);
        let mut o = [0u32; 8];
        o.copy_from_slice(&st[0..8]);
        o
    }

    /// Build an honest CV chain: each instance's input cv = previous instance's
    /// output cv. Messages/counter/flags are arbitrary per instance. Returns the
    /// blocks plus public endpoints (cv_0, cv_last).
    fn honest_chain(n: usize, seed: u64) -> (Vec<Compression>, [u32; 8], [u32; 8]) {
        let mut rng = R(seed);
        let cv0 = rng.cv();
        let mut blocks = Vec::with_capacity(n);
        let mut cur = cv0;
        for _ in 0..n {
            let block: Compression = (cur, rng.msg(), rng.nx(), rng.w(), rng.w());
            cur = out_cv(&block); // next input cv = this output cv
            blocks.push(block);
        }
        let cv_last = cur; // = out_cv(blocks[n-1])
        (blocks, cv0, cv_last)
    }

    /// Ligerito-backend chain roundtrip. Needs ≥ 128 blocks (m=21+).
    #[test]
    #[ignore]
    fn chain_prove_verify_ligerito_roundtrip() {
        // K=256 → n_log=8 → m=22 (smallest Ligerito target with BLAKE3 K_LOG=14).
        let setup = Blake3Setup::new(256);
        let n = setup.n_block_slots();
        let (blocks, cv0, cv_last) = honest_chain(n, 0xB3_511_3E);
        let mut chp = FsChallenger::new(b"b3-chain-lig");
        let (proof, comm) = setup.prove_chain(&blocks, &mut chp);
        let mut chv = FsChallenger::new(b"b3-chain-lig");
        setup
            .verify_chain(&comm, &proof, &cv0, &cv_last, &mut chv)
            .expect("ligerito chain must verify");
    }

    #[test]
    fn chain_prove_verify_basefold_roundtrip() {
        let setup = Blake3Setup::new(8); // n_log = 3, 8 instances, m = 17
        let n = setup.n_block_slots();
        let (blocks, cv0, cv_last) = honest_chain(n, 0xB3_C0FFEE);

        let mut chp = FsChallenger::new(b"b3-chain");
        let (proof, comm) = setup.prove_chain_basefold(&blocks, &mut chp);

        let mut chv = FsChallenger::new(b"b3-chain");
        setup
            .verify_chain_basefold(&comm, &proof, &cv0, &cv_last, &mut chv)
            .expect("honest BLAKE3 chain must verify");
    }

    #[test]
    fn chain_wrong_endpoint_rejects() {
        let setup = Blake3Setup::new(8);
        let n = setup.n_block_slots();
        let (blocks, cv0, mut cv_last) = honest_chain(n, 0xB3_1234);

        let mut chp = FsChallenger::new(b"b3-chain");
        let (proof, comm) = setup.prove_chain_basefold(&blocks, &mut chp);

        cv_last[0] ^= 1; // corrupt the public output endpoint
        let mut chv = FsChallenger::new(b"b3-chain");
        assert!(
            setup
                .verify_chain_basefold(&comm, &proof, &cv0, &cv_last, &mut chv)
                .is_err()
        );
    }

    #[test]
    fn chain_broken_link_rejects() {
        let setup = Blake3Setup::new(8);
        let n = setup.n_block_slots();
        let (mut blocks, cv0, cv_last) = honest_chain(n, 0xB3_55);

        // Break the chain: instance 2's input cv no longer equals out_cv(block 1).
        let mut rng = R(0xB3_999);
        blocks[2].0 = rng.cv();

        let mut chp = FsChallenger::new(b"b3-chain");
        let (proof, comm) = setup.prove_chain_basefold(&blocks, &mut chp);
        let mut chv = FsChallenger::new(b"b3-chain");
        assert!(
            setup
                .verify_chain_basefold(&comm, &proof, &cv0, &cv_last, &mut chv)
                .is_err()
        );
    }
}
