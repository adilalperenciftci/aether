/* MIT License (https://opensource.org/licenses/MIT)
 *
 * Portions copyright (c) 2016 Thomas Pornin (BearSSL, https://bearssl.org)
 *
 * Portions copyright (c) 2026 Aether Developers.
 */

#include "aether_aes.h"
#include "../../../runtime/aether_resource_caps.h"
#include "../../../runtime/utils/aether_wipe.h"

#include <stdlib.h>
#include <string.h>
#include <stdint.h>

/* FIPS-197 AES in constant time (#2600).
 *
 * The cipher used to index a 256-byte S-box with key- and data-dependent
 * bytes, which leaks the key through the cache (Bernstein 2005; Osvik,
 * Shamir and Tromer 2006). This is the 64-bit bitsliced form of Thomas
 * Pornin's BearSSL "ct64" implementation (MIT licence): four blocks are
 * spread over eight 64-bit words, bit i of every state byte in word i, and
 * every step is a fixed sequence of AND, XOR, shifts and rotations:
 *
 *   SubBytes      the Boyar-Peralta circuit of 113 gates (eprint 2009/191),
 *                 and its inverse via the affine maps around it;
 *   ShiftRows     masks and shifts within each word;
 *   MixColumns    XORs and 16/32-bit rotations;
 *   key schedule  the same S-box circuit on one word.
 *
 * No branch and no memory index depends on the key or the data, which
 * tests/integration/crypto_ct_valgrind checks under Valgrind. Correctness
 * is pinned by the FIPS-197 KATs (tests/regression/test_aes.ae) and the
 * Wycheproof AES-GCM and AES-CMAC vectors. */

/* ---- the bitsliced S-box (BearSSL br_aes_ct64_bitslice_Sbox) ---- */

static void sbox_bits(uint64_t* q) {
    /* x0 is the high bit, x7 the low bit, as in Boyar and Peralta. */
    uint64_t x0, x1, x2, x3, x4, x5, x6, x7;
    uint64_t y1, y2, y3, y4, y5, y6, y7, y8, y9;
    uint64_t y10, y11, y12, y13, y14, y15, y16, y17, y18, y19;
    uint64_t y20, y21;
    uint64_t z0, z1, z2, z3, z4, z5, z6, z7, z8, z9;
    uint64_t z10, z11, z12, z13, z14, z15, z16, z17;
    uint64_t t0, t1, t2, t3, t4, t5, t6, t7, t8, t9;
    uint64_t t10, t11, t12, t13, t14, t15, t16, t17, t18, t19;
    uint64_t t20, t21, t22, t23, t24, t25, t26, t27, t28, t29;
    uint64_t t30, t31, t32, t33, t34, t35, t36, t37, t38, t39;
    uint64_t t40, t41, t42, t43, t44, t45, t46, t47, t48, t49;
    uint64_t t50, t51, t52, t53, t54, t55, t56, t57, t58, t59;
    uint64_t t60, t61, t62, t63, t64, t65, t66, t67;
    uint64_t s0, s1, s2, s3, s4, s5, s6, s7;

    x0 = q[7];
    x1 = q[6];
    x2 = q[5];
    x3 = q[4];
    x4 = q[3];
    x5 = q[2];
    x6 = q[1];
    x7 = q[0];

    /* Top linear transformation. */
    y14 = x3 ^ x5;
    y13 = x0 ^ x6;
    y9 = x0 ^ x3;
    y8 = x0 ^ x5;
    t0 = x1 ^ x2;
    y1 = t0 ^ x7;
    y4 = y1 ^ x3;
    y12 = y13 ^ y14;
    y2 = y1 ^ x0;
    y5 = y1 ^ x6;
    y3 = y5 ^ y8;
    t1 = x4 ^ y12;
    y15 = t1 ^ x5;
    y20 = t1 ^ x1;
    y6 = y15 ^ x7;
    y10 = y15 ^ t0;
    y11 = y20 ^ y9;
    y7 = x7 ^ y11;
    y17 = y10 ^ y11;
    y19 = y10 ^ y8;
    y16 = t0 ^ y11;
    y21 = y13 ^ y16;
    y18 = x0 ^ y16;

    /* Non-linear section. */
    t2 = y12 & y15;
    t3 = y3 & y6;
    t4 = t3 ^ t2;
    t5 = y4 & x7;
    t6 = t5 ^ t2;
    t7 = y13 & y16;
    t8 = y5 & y1;
    t9 = t8 ^ t7;
    t10 = y2 & y7;
    t11 = t10 ^ t7;
    t12 = y9 & y11;
    t13 = y14 & y17;
    t14 = t13 ^ t12;
    t15 = y8 & y10;
    t16 = t15 ^ t12;
    t17 = t4 ^ t14;
    t18 = t6 ^ t16;
    t19 = t9 ^ t14;
    t20 = t11 ^ t16;
    t21 = t17 ^ y20;
    t22 = t18 ^ y19;
    t23 = t19 ^ y21;
    t24 = t20 ^ y18;

    t25 = t21 ^ t22;
    t26 = t21 & t23;
    t27 = t24 ^ t26;
    t28 = t25 & t27;
    t29 = t28 ^ t22;
    t30 = t23 ^ t24;
    t31 = t22 ^ t26;
    t32 = t31 & t30;
    t33 = t32 ^ t24;
    t34 = t23 ^ t33;
    t35 = t27 ^ t33;
    t36 = t24 & t35;
    t37 = t36 ^ t34;
    t38 = t27 ^ t36;
    t39 = t29 & t38;
    t40 = t25 ^ t39;

    t41 = t40 ^ t37;
    t42 = t29 ^ t33;
    t43 = t29 ^ t40;
    t44 = t33 ^ t37;
    t45 = t42 ^ t41;
    z0 = t44 & y15;
    z1 = t37 & y6;
    z2 = t33 & x7;
    z3 = t43 & y16;
    z4 = t40 & y1;
    z5 = t29 & y7;
    z6 = t42 & y11;
    z7 = t45 & y17;
    z8 = t41 & y10;
    z9 = t44 & y12;
    z10 = t37 & y3;
    z11 = t33 & y4;
    z12 = t43 & y13;
    z13 = t40 & y5;
    z14 = t29 & y2;
    z15 = t42 & y9;
    z16 = t45 & y14;
    z17 = t41 & y8;

    /* Bottom linear transformation. */
    t46 = z15 ^ z16;
    t47 = z10 ^ z11;
    t48 = z5 ^ z13;
    t49 = z9 ^ z10;
    t50 = z2 ^ z12;
    t51 = z2 ^ z5;
    t52 = z7 ^ z8;
    t53 = z0 ^ z3;
    t54 = z6 ^ z7;
    t55 = z16 ^ z17;
    t56 = z12 ^ t48;
    t57 = t50 ^ t53;
    t58 = z4 ^ t46;
    t59 = z3 ^ t54;
    t60 = t46 ^ t57;
    t61 = z14 ^ t57;
    t62 = t52 ^ t58;
    t63 = t49 ^ t58;
    t64 = z4 ^ t59;
    t65 = t61 ^ t62;
    t66 = z1 ^ t63;
    s0 = t59 ^ t63;
    s6 = t56 ^ ~t62;
    s7 = t48 ^ ~t60;
    t67 = t64 ^ t65;
    s3 = t53 ^ t66;
    s4 = t51 ^ t66;
    s5 = t47 ^ t65;
    s1 = t64 ^ ~s3;
    s2 = t55 ^ ~t67;

    q[7] = s0;
    q[6] = s1;
    q[5] = s2;
    q[4] = s3;
    q[3] = s4;
    q[2] = s5;
    q[1] = s6;
    q[0] = s7;
}

/* The inverse affine map of the S-box, A^-1(x) = (x <<< 1) ^ (x <<< 3) ^
 * (x <<< 6) ^ 0x05 in bit-planes: InvSubBytes(x) = A^-1(S(A^-1(x))), since
 * S(x) = A(x^-1). */
static void inv_affine_bits(uint64_t* q) {
    uint64_t q0 = ~q[0], q1 = ~q[1], q2 = q[2], q3 = q[3];
    uint64_t q4 = q[4], q5 = ~q[5], q6 = ~q[6], q7 = q[7];
    q[7] = q1 ^ q4 ^ q6;
    q[6] = q0 ^ q3 ^ q5;
    q[5] = q7 ^ q2 ^ q4;
    q[4] = q6 ^ q1 ^ q3;
    q[3] = q5 ^ q0 ^ q2;
    q[2] = q4 ^ q7 ^ q1;
    q[1] = q3 ^ q6 ^ q0;
    q[0] = q2 ^ q5 ^ q7;
}

static void inv_sbox_bits(uint64_t* q) {
    inv_affine_bits(q);
    sbox_bits(q);
    inv_affine_bits(q);
}

/* ---- packing (BearSSL br_aes_ct64_ortho / interleave_in / _out) ---- */

#define AE_SWAPN(cl, ch, s, x, y) do { \
        uint64_t a_ = (x), b_ = (y); \
        (x) = (a_ & (uint64_t)(cl)) | ((b_ & (uint64_t)(cl)) << (s)); \
        (y) = ((a_ & (uint64_t)(ch)) >> (s)) | (b_ & (uint64_t)(ch)); \
    } while (0)
#define AE_SWAP2(x, y) AE_SWAPN(0x5555555555555555ULL, 0xAAAAAAAAAAAAAAAAULL, 1, x, y)
#define AE_SWAP4(x, y) AE_SWAPN(0x3333333333333333ULL, 0xCCCCCCCCCCCCCCCCULL, 2, x, y)
#define AE_SWAP8(x, y) AE_SWAPN(0x0F0F0F0F0F0F0F0FULL, 0xF0F0F0F0F0F0F0F0ULL, 4, x, y)

static void ortho(uint64_t* q) {
    AE_SWAP2(q[0], q[1]);
    AE_SWAP2(q[2], q[3]);
    AE_SWAP2(q[4], q[5]);
    AE_SWAP2(q[6], q[7]);
    AE_SWAP4(q[0], q[2]);
    AE_SWAP4(q[1], q[3]);
    AE_SWAP4(q[4], q[6]);
    AE_SWAP4(q[5], q[7]);
    AE_SWAP8(q[0], q[4]);
    AE_SWAP8(q[1], q[5]);
    AE_SWAP8(q[2], q[6]);
    AE_SWAP8(q[3], q[7]);
}

static void interleave_in(uint64_t* q0, uint64_t* q1, const uint32_t* w) {
    uint64_t x0 = w[0], x1 = w[1], x2 = w[2], x3 = w[3];
    x0 |= (x0 << 16);
    x1 |= (x1 << 16);
    x2 |= (x2 << 16);
    x3 |= (x3 << 16);
    x0 &= 0x0000FFFF0000FFFFULL;
    x1 &= 0x0000FFFF0000FFFFULL;
    x2 &= 0x0000FFFF0000FFFFULL;
    x3 &= 0x0000FFFF0000FFFFULL;
    x0 |= (x0 << 8);
    x1 |= (x1 << 8);
    x2 |= (x2 << 8);
    x3 |= (x3 << 8);
    x0 &= 0x00FF00FF00FF00FFULL;
    x1 &= 0x00FF00FF00FF00FFULL;
    x2 &= 0x00FF00FF00FF00FFULL;
    x3 &= 0x00FF00FF00FF00FFULL;
    *q0 = x0 | (x2 << 8);
    *q1 = x1 | (x3 << 8);
}

static void interleave_out(uint32_t* w, uint64_t q0, uint64_t q1) {
    uint64_t x0 = q0 & 0x00FF00FF00FF00FFULL;
    uint64_t x1 = q1 & 0x00FF00FF00FF00FFULL;
    uint64_t x2 = (q0 >> 8) & 0x00FF00FF00FF00FFULL;
    uint64_t x3 = (q1 >> 8) & 0x00FF00FF00FF00FFULL;
    x0 |= (x0 >> 8);
    x1 |= (x1 >> 8);
    x2 |= (x2 >> 8);
    x3 |= (x3 >> 8);
    x0 &= 0x0000FFFF0000FFFFULL;
    x1 &= 0x0000FFFF0000FFFFULL;
    x2 &= 0x0000FFFF0000FFFFULL;
    x3 &= 0x0000FFFF0000FFFFULL;
    w[0] = (uint32_t)x0 | (uint32_t)(x0 >> 16);
    w[1] = (uint32_t)x1 | (uint32_t)(x1 >> 16);
    w[2] = (uint32_t)x2 | (uint32_t)(x2 >> 16);
    w[3] = (uint32_t)x3 | (uint32_t)(x3 >> 16);
}

/* ---- rounds (BearSSL ct64 encrypt and decrypt) ---- */

static void add_round_key(uint64_t* q, const uint64_t* sk) {
    for (int i = 0; i < 8; i++) q[i] ^= sk[i];
}

static void shift_rows(uint64_t* q) {
    for (int i = 0; i < 8; i++) {
        uint64_t x = q[i];
        q[i] = (x & 0x000000000000FFFFULL)
             | ((x & 0x00000000FFF00000ULL) >> 4)
             | ((x & 0x00000000000F0000ULL) << 12)
             | ((x & 0x0000FF0000000000ULL) >> 8)
             | ((x & 0x000000FF00000000ULL) << 8)
             | ((x & 0xF000000000000000ULL) >> 12)
             | ((x & 0x0FFF000000000000ULL) << 4);
    }
}

static void inv_shift_rows(uint64_t* q) {
    for (int i = 0; i < 8; i++) {
        uint64_t x = q[i];
        q[i] = (x & 0x000000000000FFFFULL)
             | ((x & 0x000000000FFF0000ULL) << 4)
             | ((x & 0x00000000F0000000ULL) >> 12)
             | ((x & 0x000000FF00000000ULL) << 8)
             | ((x & 0x0000FF0000000000ULL) >> 8)
             | ((x & 0x000F000000000000ULL) << 12)
             | ((x & 0xFFF0000000000000ULL) >> 4);
    }
}

static uint64_t rotr32(uint64_t x) {
    return (x << 32) | (x >> 32);
}

static void mix_columns(uint64_t* q) {
    uint64_t q0 = q[0], q1 = q[1], q2 = q[2], q3 = q[3];
    uint64_t q4 = q[4], q5 = q[5], q6 = q[6], q7 = q[7];
    uint64_t r0 = (q0 >> 16) | (q0 << 48);
    uint64_t r1 = (q1 >> 16) | (q1 << 48);
    uint64_t r2 = (q2 >> 16) | (q2 << 48);
    uint64_t r3 = (q3 >> 16) | (q3 << 48);
    uint64_t r4 = (q4 >> 16) | (q4 << 48);
    uint64_t r5 = (q5 >> 16) | (q5 << 48);
    uint64_t r6 = (q6 >> 16) | (q6 << 48);
    uint64_t r7 = (q7 >> 16) | (q7 << 48);
    q[0] = q7 ^ r7 ^ r0 ^ rotr32(q0 ^ r0);
    q[1] = q0 ^ r0 ^ q7 ^ r7 ^ r1 ^ rotr32(q1 ^ r1);
    q[2] = q1 ^ r1 ^ r2 ^ rotr32(q2 ^ r2);
    q[3] = q2 ^ r2 ^ q7 ^ r7 ^ r3 ^ rotr32(q3 ^ r3);
    q[4] = q3 ^ r3 ^ q7 ^ r7 ^ r4 ^ rotr32(q4 ^ r4);
    q[5] = q4 ^ r4 ^ r5 ^ rotr32(q5 ^ r5);
    q[6] = q5 ^ r5 ^ r6 ^ rotr32(q6 ^ r6);
    q[7] = q6 ^ r6 ^ r7 ^ rotr32(q7 ^ r7);
}

/* InvMixColumns as the standard pre-step, each column times
 * {04}x^2 + {05}, then MixColumns: in bit-planes, multiplying a byte by
 * {04} is a linear map, and the pre-step pairs row i with row i + 2,
 * which is a 32-bit rotation of each word. */
static void inv_mix_columns(uint64_t* q) {
    /* u = xtime(xtime(a ^ (a >>> 2 rows))) for every byte. */
    uint64_t a[8], u[8];
    for (int i = 0; i < 8; i++) a[i] = q[i] ^ rotr32(q[i]);
    /* xtime twice: bit i of 4a is bit i-2 of a, with the reduction
     * polynomial 0x1b folded in for the two bits that shift out. */
    u[0] = a[6];
    u[1] = a[7] ^ a[6];
    u[2] = a[0] ^ a[7];
    u[3] = a[1] ^ a[6];
    u[4] = a[2] ^ a[7] ^ a[6];
    u[5] = a[3] ^ a[7];
    u[6] = a[4];
    u[7] = a[5];
    for (int i = 0; i < 8; i++) q[i] ^= u[i];
    mix_columns(q);
}

static void encrypt_bits(int rounds, const uint64_t* sk, uint64_t* q) {
    add_round_key(q, sk);
    for (int u = 1; u < rounds; u++) {
        sbox_bits(q);
        shift_rows(q);
        mix_columns(q);
        add_round_key(q, sk + (u << 3));
    }
    sbox_bits(q);
    shift_rows(q);
    add_round_key(q, sk + (rounds << 3));
}

static void decrypt_bits(int rounds, const uint64_t* sk, uint64_t* q) {
    add_round_key(q, sk + (rounds << 3));
    for (int u = rounds - 1; u > 0; u--) {
        inv_shift_rows(q);
        inv_sbox_bits(q);
        add_round_key(q, sk + (u << 3));
        inv_mix_columns(q);
    }
    inv_shift_rows(q);
    inv_sbox_bits(q);
    add_round_key(q, sk);
}

/* ---- key schedule (BearSSL br_aes_ct64_keysched / skey_expand) ---- */

static uint32_t sub_word(uint32_t x) {
    uint64_t q[8];
    memset(q, 0, sizeof q);
    q[0] = x;
    ortho(q);
    sbox_bits(q);
    ortho(q);
    return (uint32_t)q[0];
}

static uint32_t dec32le(const uint8_t* p) {
    return (uint32_t)p[0] | ((uint32_t)p[1] << 8)
         | ((uint32_t)p[2] << 16) | ((uint32_t)p[3] << 24);
}

static void enc32le(uint8_t* p, uint32_t x) {
    p[0] = (uint8_t)x;
    p[1] = (uint8_t)(x >> 8);
    p[2] = (uint8_t)(x >> 16);
    p[3] = (uint8_t)(x >> 24);
}

typedef struct {
    uint64_t sk[120]; /* expanded round keys, bitsliced: 8 words per round */
    int rounds;
    int encrypt;
} AeAes;

static void expand_key(AeAes* c, const uint8_t* key, int keylen) {
    static const uint8_t rcon[10] = { 0x01, 0x02, 0x04, 0x08, 0x10, 0x20, 0x40, 0x80, 0x1B, 0x36 };
    int nk = keylen / 4;
    int rounds = nk + 6;
    int nkf = (rounds + 1) * 4;
    uint32_t skey[60];
    uint64_t comp[30];
    c->rounds = rounds;
    for (int i = 0; i < nk; i++) skey[i] = dec32le(key + 4 * i);
    uint32_t tmp = skey[nk - 1];
    for (int i = nk, j = 0, k = 0; i < nkf; i++) {
        if (j == 0) {
            tmp = (tmp << 24) | (tmp >> 8);
            tmp = sub_word(tmp) ^ rcon[k];
        } else if (nk > 6 && j == 4) {
            tmp = sub_word(tmp);
        }
        tmp ^= skey[i - nk];
        skey[i] = tmp;
        if (++j == nk) {
            j = 0;
            k++;
        }
    }
    for (int i = 0, j = 0; i < nkf; i += 4, j += 2) {
        uint64_t q[8];
        interleave_in(&q[0], &q[4], skey + i);
        q[1] = q[0];
        q[2] = q[0];
        q[3] = q[0];
        q[5] = q[4];
        q[6] = q[4];
        q[7] = q[4];
        ortho(q);
        comp[j + 0] = (q[0] & 0x1111111111111111ULL) | (q[1] & 0x2222222222222222ULL)
                    | (q[2] & 0x4444444444444444ULL) | (q[3] & 0x8888888888888888ULL);
        comp[j + 1] = (q[4] & 0x1111111111111111ULL) | (q[5] & 0x2222222222222222ULL)
                    | (q[6] & 0x4444444444444444ULL) | (q[7] & 0x8888888888888888ULL);
    }
    int n = (rounds + 1) << 1;
    for (int u = 0, v = 0; u < n; u++, v += 4) {
        uint64_t x0 = comp[u], x1 = comp[u], x2 = comp[u], x3 = comp[u];
        x0 &= 0x1111111111111111ULL;
        x1 &= 0x2222222222222222ULL;
        x2 &= 0x4444444444444444ULL;
        x3 &= 0x8888888888888888ULL;
        x1 >>= 1;
        x2 >>= 2;
        x3 >>= 3;
        c->sk[v + 0] = (x0 << 4) - x0;
        c->sk[v + 1] = (x1 << 4) - x1;
        c->sk[v + 2] = (x2 << 4) - x2;
        c->sk[v + 3] = (x3 << 4) - x3;
    }
    aether_wipe(skey, sizeof skey);
    aether_wipe(comp, sizeof comp);
}

/* Run 1 to 4 blocks (16 * nb bytes at in) through the cipher into out;
 * in and out may alias. */
static void run_blocks(const AeAes* c, int encrypt, const uint8_t* in, uint8_t* out, int nb) {
    uint32_t w[16];
    uint64_t q[8];
    memset(w, 0, sizeof w);
    for (int i = 0; i < 4 * nb; i++) w[i] = dec32le(in + 4 * i);
    for (int i = 0; i < 4; i++) interleave_in(&q[i], &q[i + 4], w + (i << 2));
    ortho(q);
    if (encrypt) encrypt_bits(c->rounds, c->sk, q);
    else         decrypt_bits(c->rounds, c->sk, q);
    ortho(q);
    for (int i = 0; i < 4; i++) interleave_out(w + (i << 2), q[i], q[i + 4]);
    for (int i = 0; i < 4 * nb; i++) enc32le(out + 4 * i, w[i]);
    aether_wipe(w, sizeof w);
    aether_wipe(q, sizeof q);
}

int aether_aes_available(void) { return 1; }

void* aether_aes_new(const void* key, int keylen, int encrypt) {
    if (!key) return NULL;
    if (keylen != 16 && keylen != 24 && keylen != 32) return NULL;
    AeAes* c = (AeAes*)aether_caps_malloc(sizeof(AeAes));
    if (!c) return NULL;
    memset(c, 0, sizeof(*c));
    c->encrypt = encrypt ? 1 : 0;
    expand_key(c, (const uint8_t*)key, keylen);
    return c;
}

void aether_aes_free(void* ctx) {
    if (!ctx) return;
    /* Key material must not outlive the context: aether_wipe, as a memset
     * before a free is a dead store the compiler may drop (#3402). */
    aether_wipe(ctx, sizeof(AeAes));
    aether_caps_free(ctx, sizeof(AeAes));
}

int aether_aes_block(void* ctx, const void* in, void* out) {
    AeAes* c = (AeAes*)ctx;
    if (!c || !in || !out) return 0;
    run_blocks(c, c->encrypt, (const uint8_t*)in, (uint8_t*)out, 1);
    return 1;
}

int aether_aes_cbc_encrypt(void* ctx, const void* iv, const void* in,
                           void* out, int n) {
    AeAes* c = (AeAes*)ctx;
    if (!c || !c->encrypt || !iv || !in || !out) return 0;
    if (n < 0 || n % 16 != 0) return 0;
    uint8_t prev[16];
    memcpy(prev, iv, 16);
    const uint8_t* ip = (const uint8_t*)in;
    uint8_t* op = (uint8_t*)out;
    for (int off = 0; off < n; off += 16) {
        uint8_t blk[16];
        for (int i = 0; i < 16; i++) blk[i] = (uint8_t)(ip[off + i] ^ prev[i]);
        run_blocks(c, 1, blk, op + off, 1);
        memcpy(prev, op + off, 16);
    }
    return 1;
}

int aether_aes_cbc_decrypt(void* ctx, const void* iv, const void* in,
                           void* out, int n) {
    AeAes* c = (AeAes*)ctx;
    if (!c || c->encrypt || !iv || !in || !out) return 0;
    if (n < 0 || n % 16 != 0) return 0;
    uint8_t prev[16], cur[64], dec[64];
    memcpy(prev, iv, 16);
    const uint8_t* ip = (const uint8_t*)in;
    uint8_t* op = (uint8_t*)out;
    for (int off = 0; off < n; off += 64) {
        int nb = (n - off) / 16;
        if (nb > 4) nb = 4;
        memcpy(cur, ip + off, (size_t)(16 * nb)); /* in and out may alias */
        run_blocks(c, 0, cur, dec, nb);
        for (int b = 0; b < nb; b++) {
            const uint8_t* chain = b == 0 ? prev : cur + 16 * (b - 1);
            for (int i = 0; i < 16; i++) op[off + 16 * b + i] = (uint8_t)(dec[16 * b + i] ^ chain[i]);
        }
        memcpy(prev, cur + 16 * (nb - 1), 16);
    }
    return 1;
}

int aether_aes_ctr_xor(void* ctx, const void* iv, const void* in,
                       void* out, int n) {
    AeAes* c = (AeAes*)ctx;
    if (!c || !c->encrypt || !iv || !in || !out) return 0;
    if (n < 0) return 0;
    uint8_t ctr[16], blocks[64];
    memcpy(ctr, iv, 16);
    const uint8_t* ip = (const uint8_t*)in;
    uint8_t* op = (uint8_t*)out;
    for (int off = 0; off < n; off += 64) {
        int left = n - off;
        int nb = (left + 15) / 16;
        if (nb > 4) nb = 4;
        for (int b = 0; b < nb; b++) {
            memcpy(blocks + 16 * b, ctr, 16);
            /* The counter is public (the IV and a block count): a branch
             * on its carry leaks nothing. */
            for (int i = 15; i >= 0; i--) { if (++ctr[i]) break; }
        }
        run_blocks(c, 1, blocks, blocks, nb);
        int chunk = left < 64 ? left : 64;
        for (int i = 0; i < chunk; i++) op[off + i] = (uint8_t)(ip[off + i] ^ blocks[i]);
    }
    aether_wipe(blocks, sizeof blocks);
    return 1;
}
