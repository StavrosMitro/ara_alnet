// Copyright 2020 ETH Zurich and University of Bologna.
//
// SPDX-License-Identifier: Apache-2.0
//
// Licensed under the Apache License, Version 2.0 (the "License");
// you may not use this file except in compliance with the License.
// You may obtain a copy of the License at
//
//    http://www.apache.org/licenses/LICENSE-2.0
//
// Unless required by applicable law or agreed to in writing, software
// distributed under the License is distributed on an "AS IS" BASIS,
// WITHOUT WARRANTIES OR CONDITIONS OF ANY KIND, either express or implied.
// See the License for the specific language governing permissions and
// limitations under the License.

// Author: Matheus Cavalcante, ETH Zurich
//         Samuel Riedel, ETH Zurich
// modified versions of fmatmul Author: Stavros Mitropoulos, NTUA

#include <stddef.h>
#include "fmatmul.h"

#define MIN(a, b) ((a) < (b) ? (a) : (b))

void fmatmul(float *c, const _Float16 *a, const _Float16 *b,
             const unsigned long int M, const unsigned long int N,
             const unsigned long int P) {
  if (M <= 4) {
    fmatmul_4x4(c, a, b, M, N, P);
  } else if (M <= 8) {
    fmatmul_8x8(c, a, b, M, N, P);
  } else if (M <= 64) {
    fmatmul_16x16(c, a, b, M, N, P);
  } else if (M <= 128) {
    // With an 8x8 matmul, use LMUL=2 to increase vl.
    fmatmul_8x8(c, a, b, M, N, P);
  } else {
    // With a 4x4 matmul, use LMUL=4 to increase vl.
    fmatmul_4x4(c, a, b, M, N, P);
  }
}

void fmatmul_fused(float *c, const _Float16 *a, const _Float16 *b,
                   const float *bias, const unsigned long int M,
                   const unsigned long int N, const unsigned long int P) {
  if (M <= 4) {
    fmatmul_4x4_fused(c, a, b, bias, M, N, P);
  } else if (M <= 8) {
    fmatmul_8x8_fused(c, a, b, bias, M, N, P);
  } else if (M <= 64) {
    fmatmul_16x16_fused(c, a, b, bias, M, N, P);
  } else if (M <= 128) {
    // With an 8x8 matmul, use LMUL=2 to increase vl.
    fmatmul_8x8_fused(c, a, b, bias, M, N, P);
  } else {
    // With a 4x4 matmul, use LMUL=4 to increase vl.
    fmatmul_4x4_fused(c, a, b, bias, M, N, P);
  }
}

void fmatmul_nt(float *c, const _Float16 *a, const _Float16 *b,
                const unsigned long int M, const unsigned long int N,
                const unsigned long int P) {
  if (M <= 4) {
    fmatmul_4x4_nt(c, a, b, M, N, P);
  } else if (M <= 8) {
    fmatmul_8x8_nt(c, a, b, M, N, P);
  } else if (M <= 64) {
    fmatmul_16x16_nt(c, a, b, M, N, P);
  } else if (M <= 128) {
    // With an 8x8 matmul, use LMUL=2 to increase vl.
    fmatmul_8x8_nt(c, a, b, M, N, P);
  } else {
    // With a 4x4 matmul, use LMUL=4 to increase vl.
    fmatmul_4x4_nt(c, a, b, M, N, P);
  }
}

void fmatmul_tn(float *c, const _Float16 *a, const _Float16 *b,
                const unsigned long int M, const unsigned long int N,
                const unsigned long int P) {
  if (N <= 4) {
    fmatmul_4x4_tn(c, a, b, M, N, P);
  } else if (N <= 8) {
    fmatmul_8x8_tn(c, a, b, M, N, P);
  } else if (N <= 64) {
    fmatmul_16x16_tn(c, a, b, M, N, P);
  } else if (N <= 128) {
    // With an 8x8 matmul, use LMUL=2 to increase vl.
    fmatmul_8x8_tn(c, a, b, M, N, P);
  } else {
    // With a 4x4 matmul, use LMUL=4 to increase vl.
    fmatmul_4x4_tn(c, a, b, M, N, P);
  }

  if (M == 0)
    return;

  // Scale by 1/M using vector instructions. c is FP32 output.
  const float inv_batch = 1.0f / (float)M;
  size_t remaining = (size_t)N * (size_t)P;
  float *dst = c;
  while (remaining > 0) {
    size_t vl = 0;
    asm volatile("vsetvli %0, %1, e32, m8, ta, ma" : "=r"(vl) : "r"(remaining));
    asm volatile("vle32.v v8, (%0)" :: "r"(dst) : "memory");
    asm volatile("vfmul.vf v8, v8, %0" :: "f"(inv_batch));
    asm volatile("vse32.v v8, (%0)" :: "r"(dst) : "memory");
    dst += vl;
    remaining -= vl;
  }
}

// ---------------
// 4x4
// ---------------

void fmatmul_4x4(float *c, const _Float16 *a, const _Float16 *b,
                 const unsigned long int M, const unsigned long int N,
                 const unsigned long int P) {
  // We work on 4 rows of the matrix at once
  const unsigned long int block_size = 4;
  unsigned long int block_size_p;

  // Set the vector configuration
  asm volatile("vsetvli %0, %1, e16, m2, ta, ma" : "=r"(block_size_p) : "r"(P)); 
  /*
  block_size_p --> actual vector length
  vsetvli returns min(input, VLMAX)
  */

  // Slice the matrix into a manageable number of columns p_
  for (unsigned long int p = 0; p < P; p += block_size_p) {
    // Set the vector length
    const unsigned long int p_ = MIN(P - p, block_size_p);

    // Find pointers to the submatrices
    const _Float16 *b_ = b + p;
    float *c_ = c + p;

    asm volatile("vsetvli zero, %0, e16, m2, ta, ma" ::"r"(p_));

    // Iterate over the rows
    for (unsigned long int m = 0; m < M; m += block_size) {
      // Find pointer to the submatrices
      const _Float16 *a_ = a + m * N;
      float *c__ = c_ + m * P;

      fmatmul_vec_4x4_slice_init(p_);
      fmatmul_vec_4x4(c__, a_, b_, N, P, p_);
    }
  }
}

void fmatmul_4x4_fused(float *c, const _Float16 *a, const _Float16 *b,
                       const float *bias, const unsigned long int M,
                       const unsigned long int N, const unsigned long int P) {
  // We work on 4 rows of the matrix at once
  const unsigned long int block_size = 4;
  unsigned long int block_size_p;

  // Set the vector configuration
  asm volatile("vsetvli %0, %1, e16, m2, ta, ma" : "=r"(block_size_p) : "r"(P));

  // Slice the matrix into a manageable number of columns p_
  for (unsigned long int p = 0; p < P; p += block_size_p) {
    // Set the vector length
    const unsigned long int p_ = MIN(P - p, block_size_p);

    // Find pointers to the submatrices
    const _Float16 *b_ = b + p;
    float *c_ = c + p;
    const float *bias_slice = bias + p;

    asm volatile("vsetvli zero, %0, e16, m2, ta, ma" : : "r"(p_));

    // Iterate over the rows
    for (unsigned long int m = 0; m < M; m += block_size) {
      // Find pointer to the submatrices
      const _Float16 *a_ = a + m * N;
      float *c__ = c_ + m * P;

      fmatmul_vec_4x4_slice_init_fused(bias_slice, p_);
      fmatmul_vec_4x4(c__, a_, b_, N, P, p_);
    }
  }
}

void fmatmul_4x4_nt(float *c, const _Float16 *a, const _Float16 *b,
                    const unsigned long int M, const unsigned long int N,
                    const unsigned long int P) {
  // We work on 4 rows of the matrix at once
  const unsigned long int block_size = 4;
  unsigned long int block_size_p;

  // Set the vector configuration
  asm volatile("vsetvli %0, %1, e16, m2, ta, ma" : "=r"(block_size_p) : "r"(P));

  // Slice the matrix into a manageable number of columns p_
  for (unsigned long int p = 0; p < P; p += block_size_p) {
    // Set the vector length
    const unsigned long int p_ = MIN(P - p, block_size_p);

    // Find pointers to the submatrices
    const _Float16 *b_ = b + p * N;
    float *c_ = c + p;

    asm volatile("vsetvli zero, %0, e16, m2, ta, ma" : : "r"(p_));

    // Iterate over the rows
    for (unsigned long int m = 0; m < M; m += block_size) {
      // Find pointer to the submatrices
      const _Float16 *a_ = a + m * N;
      float *c__ = c_ + m * P;

      fmatmul_vec_4x4_slice_init(p_);
      fmatmul_vec_4x4_nt(c__, a_, b_, N, P, p_);
    }
  }
}

void fmatmul_4x4_tn(float *c, const _Float16 *a, const _Float16 *b,
                    const unsigned long int M, const unsigned long int N,
                    const unsigned long int P) {
  const unsigned long int block_size = 4;
  unsigned long int block_size_p;

  asm volatile("vsetvli %0, %1, e16, m2, ta, ma" : "=r"(block_size_p) : "r"(P));

  for (unsigned long int p = 0; p < P; p += block_size_p) {
    const unsigned long int p_ = MIN(P - p, block_size_p);

    const _Float16 *b_ = b + p;
    float *c_ = c + p;

    asm volatile("vsetvli zero, %0, e16, m2, ta, ma" : : "r"(p_));

    for (unsigned long int n = 0; n < N; n += block_size) {
      const _Float16 *a_ = a + n;
      float *c__ = c_ + n * P;

      fmatmul_vec_4x4_slice_init(p_);
      fmatmul_vec_4x4_tn(c__, a_, b_, M, P, N, p_);
    }
  }
}

// ---------------
// 4x4 deferred (A * B^T)
// ---------------
static inline void fmatmul_vec_4x4_deferred(float *c, const _Float16 *a,
                                            const _Float16 *b,
                                            const unsigned long int N,
                                            const unsigned long int ldc) {
  const _Float16 *a0 = a;
  const _Float16 *a1 = a + N;
  const _Float16 *a2 = a + 2 * N;
  const _Float16 *a3 = a + 3 * N;

  const _Float16 *b0 = b;
  const _Float16 *b1 = b + N;
  const _Float16 *b2 = b + 2 * N;
  const _Float16 *b3 = b + 3 * N;

  // 1. Αρχικοποίηση 16 Accumulators (v16-v31) ως FP32 (e32, m1)
  asm volatile("vsetvli zero, %0, e32, m1, ta, ma" : : "r"(N));
  asm volatile("vmv.v.i v16, 0");
  asm volatile("vmv.v.i v17, 0");
  asm volatile("vmv.v.i v18, 0");
  asm volatile("vmv.v.i v19, 0");
  asm volatile("vmv.v.i v20, 0");
  asm volatile("vmv.v.i v21, 0");
  asm volatile("vmv.v.i v22, 0");
  asm volatile("vmv.v.i v23, 0");
  asm volatile("vmv.v.i v24, 0");
  asm volatile("vmv.v.i v25, 0");
  asm volatile("vmv.v.i v26, 0");
  asm volatile("vmv.v.i v27, 0");
  asm volatile("vmv.v.i v28, 0");
  asm volatile("vmv.v.i v29, 0");
  asm volatile("vmv.v.i v30, 0");
  asm volatile("vmv.v.i v31, 0");

  unsigned long int k = N;
  while (k > 0) {
    unsigned long int vl;
    // 2. Χρησιμοποιούμε Fractional LMUL (mf2) για τα 16-bit inputs!
    asm volatile("vsetvli %0, %1, e16, mf2, ta, ma" : "=r"(vl) : "r"(k));

    asm volatile("vle16.v v0, (%0)" : : "r"(a0)); a0 += vl;
    asm volatile("vle16.v v1, (%0)" : : "r"(a1)); a1 += vl;
    asm volatile("vle16.v v2, (%0)" : : "r"(a2)); a2 += vl;
    asm volatile("vle16.v v3, (%0)" : : "r"(a3)); a3 += vl;

    asm volatile("vle16.v v4, (%0)" : : "r"(b0)); b0 += vl;
    asm volatile("vle16.v v5, (%0)" : : "r"(b1)); b1 += vl;
    asm volatile("vle16.v v6, (%0)" : : "r"(b2)); b2 += vl;
    asm volatile("vle16.v v7, (%0)" : : "r"(b3)); b3 += vl;

    // Τα dest (v16-v31) γίνονται m1 με ασφάλεια
    asm volatile("vfwmacc.vv v16, v0, v4");
    asm volatile("vfwmacc.vv v17, v0, v5");
    asm volatile("vfwmacc.vv v18, v0, v6");
    asm volatile("vfwmacc.vv v19, v0, v7");

    asm volatile("vfwmacc.vv v20, v1, v4");
    asm volatile("vfwmacc.vv v21, v1, v5");
    asm volatile("vfwmacc.vv v22, v1, v6");
    asm volatile("vfwmacc.vv v23, v1, v7");

    asm volatile("vfwmacc.vv v24, v2, v4");
    asm volatile("vfwmacc.vv v25, v2, v5");
    asm volatile("vfwmacc.vv v26, v2, v6");
    asm volatile("vfwmacc.vv v27, v2, v7");

    asm volatile("vfwmacc.vv v28, v3, v4");
    asm volatile("vfwmacc.vv v29, v3, v5");
    asm volatile("vfwmacc.vv v30, v3, v6");
    asm volatile("vfwmacc.vv v31, v3, v7");

    k -= vl;
  }

  // 3. Επιστροφή σε FP32 (e32, m1) για το Reduction
  asm volatile("vsetvli zero, %0, e32, m1, ta, ma" : : "r"(N));
  asm volatile("vmv.v.i v8, 0"); // scalar 0 για το sum

  // vfredsum.vs (όχι vredsum)
  asm volatile("vfredsum.vs v16, v16, v8");
  asm volatile("vfredsum.vs v17, v17, v8");
  asm volatile("vfredsum.vs v18, v18, v8");
  asm volatile("vfredsum.vs v19, v19, v8");
  asm volatile("vfredsum.vs v20, v20, v8");
  asm volatile("vfredsum.vs v21, v21, v8");
  asm volatile("vfredsum.vs v22, v22, v8");
  asm volatile("vfredsum.vs v23, v23, v8");
  asm volatile("vfredsum.vs v24, v24, v8");
  asm volatile("vfredsum.vs v25, v25, v8");
  asm volatile("vfredsum.vs v26, v26, v8");
  asm volatile("vfredsum.vs v27, v27, v8");
  asm volatile("vfredsum.vs v28, v28, v8");
  asm volatile("vfredsum.vs v29, v29, v8");
  asm volatile("vfredsum.vs v30, v30, v8");
  asm volatile("vfredsum.vs v31, v31, v8");

  float *c_ptr = c;
  float res;

  asm volatile("vfmv.f.s %0, v16" : "=f"(res)); c_ptr[0] += res;
  asm volatile("vfmv.f.s %0, v17" : "=f"(res)); c_ptr[1] += res;
  asm volatile("vfmv.f.s %0, v18" : "=f"(res)); c_ptr[2] += res;
  asm volatile("vfmv.f.s %0, v19" : "=f"(res)); c_ptr[3] += res;
  c_ptr += ldc;

  asm volatile("vfmv.f.s %0, v20" : "=f"(res)); c_ptr[0] += res;
  asm volatile("vfmv.f.s %0, v21" : "=f"(res)); c_ptr[1] += res;
  asm volatile("vfmv.f.s %0, v22" : "=f"(res)); c_ptr[2] += res;
  asm volatile("vfmv.f.s %0, v23" : "=f"(res)); c_ptr[3] += res;
  c_ptr += ldc;

  asm volatile("vfmv.f.s %0, v24" : "=f"(res)); c_ptr[0] += res;
  asm volatile("vfmv.f.s %0, v25" : "=f"(res)); c_ptr[1] += res;
  asm volatile("vfmv.f.s %0, v26" : "=f"(res)); c_ptr[2] += res;
  asm volatile("vfmv.f.s %0, v27" : "=f"(res)); c_ptr[3] += res;
  c_ptr += ldc;

  asm volatile("vfmv.f.s %0, v28" : "=f"(res)); c_ptr[0] += res;
  asm volatile("vfmv.f.s %0, v29" : "=f"(res)); c_ptr[1] += res;
  asm volatile("vfmv.f.s %0, v30" : "=f"(res)); c_ptr[2] += res;
  asm volatile("vfmv.f.s %0, v31" : "=f"(res)); c_ptr[3] += res;
}

void fmatmul_4x4_deferred(float *c, const _Float16 *a, const _Float16 *b,
                          const unsigned long int M, const unsigned long int N,
                          const unsigned long int P) {
  // C = A * B^T
  // A: [M x N], B: [P x N], C: [M x P]
  for (unsigned long int m = 0; m < M; m += 4) {
    for (unsigned long int p = 0; p < P; p += 4) {
      const _Float16 *a_block = a + m * N;
      const _Float16 *b_block = b + p * N;
      float *c_block = c + m * P + p;

      fmatmul_vec_4x4_deferred(c_block, a_block, b_block, N, P);
    }
  }
}

void fmatmul_vec_4x4_slice_init(unsigned long int vl) {
  asm volatile("vsetvli zero, %0, e32, m4, ta, ma" :: "r"(vl));
  asm volatile("vmv.v.i v0,  0");
  asm volatile("vmv.v.i v4,  0");
  asm volatile("vmv.v.i v8,  0");
  asm volatile("vmv.v.i v12, 0");
  asm volatile("vsetvli zero, %0, e16, m2, ta, ma" :: "r"(vl));
}

void fmatmul_vec_4x4_slice_load_bias(const float *bias_slice, unsigned long int vl) {
  asm volatile("vsetvli zero, %0, e32, m4, ta, ma" :: "r"(vl));
  asm volatile("vle32.v v0, (%0);" ::"r"(bias_slice));
  asm volatile("vmv.v.v v4,  v0");
  asm volatile("vmv.v.v v8,  v0");
  asm volatile("vmv.v.v v12, v0");
  asm volatile("vsetvli zero, %0, e16, m2, ta, ma" :: "r"(vl));
}

void fmatmul_vec_4x4_slice_init_fused(const float *bias_slice, unsigned long int vl) {
  asm volatile("vsetvli zero, %0, e32, m4, ta, ma" :: "r"(vl));
  asm volatile("vle32.v v0, (%0);" ::"r"(bias_slice));
  asm volatile("vmv.v.v v4,  v0");
  asm volatile("vmv.v.v v8,  v0");
  asm volatile("vmv.v.v v12, v0");
  asm volatile("vsetvli zero, %0, e16, m2, ta, ma" :: "r"(vl));
}

void fmatmul_vec_4x4(float *c, const _Float16 *a, const _Float16 *b,
                     const unsigned long int N, const unsigned long int P,
                     const unsigned long int vl) {
  // Temporary variables
  _Float16 t0, t1, t2, t3;

  // Original pointer
  const _Float16 *a_ = a;

  asm volatile("vsetvli zero, %0, e16, m2, ta, ma" :: "r"(vl));
  // Prefetch one row of matrix B
  asm volatile("vle16.v v16, (%0);" ::"r"(b));
  b += P;

  // Prefetch one row of scalar values
  t0 = *a, a += N;
  t1 = *a, a += N;
  t2 = *a, a += N;
  t3 = *a;

  // Compute the multiplication
  unsigned long int n = 0;

  while (n != N) {


    // Calculate pointer to the matrix A
    a = a_ + ++n;

    asm volatile("vfwmacc.vf v0, %0, v16" ::"f"(t0));
    t0 = *a, a += N;

    // Load one row of B
    asm volatile("vle16.v v20, (%0);" ::"r"(b));
    b += P;

    asm volatile("vfwmacc.vf v4, %0, v16" ::"f"(t1));
    t1 = *a, a += N;
    asm volatile("vfwmacc.vf v8, %0, v16" ::"f"(t2));
    t2 = *a, a += N;
    asm volatile("vfwmacc.vf v12, %0, v16" ::"f"(t3));
    t3 = *a;

    a = a_ + ++n;

    if (n == N)
      break;

    asm volatile("vfwmacc.vf v0, %0, v20" ::"f"(t0));
    t0 = *a, a += N;

    // Load one row of B
    asm volatile("vle16.v v16, (%0);" ::"r"(b));
    b += P;

    asm volatile("vfwmacc.vf v4, %0, v20" ::"f"(t1));
    t1 = *a, a += N;
    asm volatile("vfwmacc.vf v8, %0, v20" ::"f"(t2));
    t2 = *a, a += N;
    asm volatile("vfwmacc.vf v12, %0, v20" ::"f"(t3));
    t3 = *a;
  }

  // Last iteration: store results
  asm volatile("vfwmacc.vf v0, %0, v20" ::"f"(t0));
  asm volatile("vse32.v v0, (%0);" ::"r"(c));
  c += P;
  asm volatile("vfwmacc.vf v4, %0, v20" ::"f"(t1));
  asm volatile("vse32.v v4, (%0);" ::"r"(c));
  c += P;
  asm volatile("vfwmacc.vf v8, %0, v20" ::"f"(t2));
  asm volatile("vse32.v v8, (%0);" ::"r"(c));
  c += P;
  asm volatile("vfwmacc.vf v12, %0, v20" ::"f"(t3));
  asm volatile("vse32.v v12, (%0);" ::"r"(c));
}

void fmatmul_vec_4x4_nt(float *c, const _Float16 *a, const _Float16 *b,
                        const unsigned long int N, const unsigned long int P,
                        const unsigned long int vl) {
  // Temporary variables
  _Float16 t0, t1, t2, t3;

  const _Float16 *a_ = a;
  long stride_b_bytes = (long)N * (long)sizeof(_Float16);

  asm volatile("vsetvli zero, %0, e16, m2, ta, ma" :: "r"(vl));
  // Prefetch one column of matrix B (row-major B, strided by N)
  asm volatile("vlse16.v v16, (%0), %1" : : "r"(b), "r"(stride_b_bytes));
  b += 1;

  // Prefetch one column of scalar values from A
  t0 = *a, a += N;
  t1 = *a, a += N;
  t2 = *a, a += N;
  t3 = *a;

  // Compute the multiplication
  unsigned long int n = 0;

  while (n != N) {
    // Calculate pointer to the matrix A
    a = a_ + ++n;

    asm volatile("vfwmacc.vf v0, %0, v16" ::"f"(t0));
    t0 = *a, a += N;

    // Load next column of B
    asm volatile("vlse16.v v20, (%0), %1" : : "r"(b), "r"(stride_b_bytes));
    b += 1;

    asm volatile("vfwmacc.vf v4, %0, v16" ::"f"(t1));
    t1 = *a, a += N;
    asm volatile("vfwmacc.vf v8, %0, v16" ::"f"(t2));
    t2 = *a, a += N;
    asm volatile("vfwmacc.vf v12, %0, v16" ::"f"(t3));
    t3 = *a;

    a = a_ + ++n;

    if (n == N)
      break;

    asm volatile("vfwmacc.vf v0, %0, v20" ::"f"(t0));
    t0 = *a, a += N;

    // Load next column of B
    asm volatile("vlse16.v v16, (%0), %1" : : "r"(b), "r"(stride_b_bytes));
    b += 1;

    asm volatile("vfwmacc.vf v4, %0, v20" ::"f"(t1));
    t1 = *a, a += N;
    asm volatile("vfwmacc.vf v8, %0, v20" ::"f"(t2));
    t2 = *a, a += N;
    asm volatile("vfwmacc.vf v12, %0, v20" ::"f"(t3));
    t3 = *a;
  }

  // Last iteration: store results
  asm volatile("vfwmacc.vf v0, %0, v20" ::"f"(t0));
  asm volatile("vse32.v v0, (%0);" ::"r"(c));
  c += P;
  asm volatile("vfwmacc.vf v4, %0, v20" ::"f"(t1));
  asm volatile("vse32.v v4, (%0);" ::"r"(c));
  c += P;
  asm volatile("vfwmacc.vf v8, %0, v20" ::"f"(t2));
  asm volatile("vse32.v v8, (%0);" ::"r"(c));
  c += P;
  asm volatile("vfwmacc.vf v12, %0, v20" ::"f"(t3));
  asm volatile("vse32.v v12, (%0);" ::"r"(c));
}

void fmatmul_vec_4x4_tn(float *c, const _Float16 *a, const _Float16 *b,
                        const unsigned long int N, const unsigned long int P,
                        const unsigned long int lda, const unsigned long int vl) {
  _Float16 t0, t1, t2, t3;

  asm volatile("vsetvli zero, %0, e16, m2, ta, ma" :: "r"(vl));
  if (N <= 2) { //batchsize=2
    const _Float16 *a_row = a;
    for (unsigned long int m = 0; m < N; m++) {
      asm volatile("vle16.v v16, (%0);" ::"r"(b));
      b += P;

      t0 = a_row[0];
      t1 = a_row[1];
      t2 = a_row[2];
      t3 = a_row[3];

      asm volatile("vfwmacc.vf v0, %0, v16" ::"f"(t0));
      asm volatile("vfwmacc.vf v4, %0, v16" ::"f"(t1));
      asm volatile("vfwmacc.vf v8, %0, v16" ::"f"(t2));
      asm volatile("vfwmacc.vf v12, %0, v16" ::"f"(t3));

      a_row += lda;
    }

    asm volatile("vse32.v v0, (%0);" ::"r"(c));
    c += P;
    asm volatile("vse32.v v4, (%0);" ::"r"(c));
    c += P;
    asm volatile("vse32.v v8, (%0);" ::"r"(c));
    c += P;
    asm volatile("vse32.v v12, (%0);" ::"r"(c));
    return;
  }

  // Prefetch one row of matrix B.
  asm volatile("vle16.v v16, (%0);" ::"r"(b));
  b += P;

  // TN: load 4 contiguous elements from A, then advance by lda (row stride).
  t0 = a[0];
  t1 = a[1];
  t2 = a[2];
  t3 = a[3];
  a += lda;

  unsigned long int n = 0;

  while (n != N) {
    n++;

    asm volatile("vfwmacc.vf v0, %0, v16" ::"f"(t0));
    t0 = a[0];

    asm volatile("vle16.v v20, (%0);" ::"r"(b));
    b += P;

    asm volatile("vfwmacc.vf v4, %0, v16" ::"f"(t1));
    t1 = a[1];
    asm volatile("vfwmacc.vf v8, %0, v16" ::"f"(t2));
    t2 = a[2];
    asm volatile("vfwmacc.vf v12, %0, v16" ::"f"(t3));
    t3 = a[3];

    a += lda;

    if (n == N)
      break;

    n++;

    asm volatile("vfwmacc.vf v0, %0, v20" ::"f"(t0));
    t0 = a[0];

    asm volatile("vle16.v v16, (%0);" ::"r"(b));
    b += P;

    asm volatile("vfwmacc.vf v4, %0, v20" ::"f"(t1));
    t1 = a[1];
    asm volatile("vfwmacc.vf v8, %0, v20" ::"f"(t2));
    t2 = a[2];
    asm volatile("vfwmacc.vf v12, %0, v20" ::"f"(t3));
    t3 = a[3];

    a += lda;
  }

  asm volatile("vfwmacc.vf v0, %0, v20" ::"f"(t0));
  asm volatile("vfwmacc.vf v4, %0, v20" ::"f"(t1));
  asm volatile("vfwmacc.vf v8, %0, v20" ::"f"(t2));
  asm volatile("vfwmacc.vf v12, %0, v20" ::"f"(t3));

  asm volatile("vsetvli zero, %0, e32, m4, ta, ma" :: "r"(vl));
  asm volatile("vse32.v v0, (%0);" ::"r"(c));
  c += P;
  
  asm volatile("vse32.v v4, (%0);" ::"r"(c));
  c += P;
  
  asm volatile("vse32.v v8, (%0);" ::"r"(c));
  c += P;
  asm volatile("vse32.v v12, (%0);" ::"r"(c));
}

// ---------------
// 8x8
// ---------------

void fmatmul_8x8(float *c, const _Float16 *a, const _Float16 *b,
                 const unsigned long int M, const unsigned long int N,
                 const unsigned long int P) {
  // We work on 4 rows of the matrix at once
  const unsigned long int block_size = 8;
  unsigned long int block_size_p;

  // Set the vector configuration
  asm volatile("vsetvli %0, %1, e16, m1, ta, ma" : "=r"(block_size_p) : "r"(P));

  // Slice the matrix into a manageable number of columns p_
  for (unsigned long int p = 0; p < P; p += block_size_p) {
    // Set the vector length
    const unsigned long int p_ = MIN(P - p, block_size_p);

    // Find pointers to the submatrices
    const _Float16 *b_ = b + p;
    float *c_ = c + p;

    asm volatile("vsetvli zero, %0, e16, m1, ta, ma" ::"r"(p_));

    // Iterate over the rows
    for (unsigned long int m = 0; m < M; m += block_size) {
      // Find pointer to the submatrices
      const _Float16 *a_ = a + m * N;
      float *c__ = c_ + m * P;

      fmatmul_vec_8x8_slice_init(p_);
      fmatmul_vec_8x8(c__, a_, b_, N, P, p_);
    }
  }
}

void fmatmul_8x8_fused(float *c, const _Float16 *a, const _Float16 *b,
                       const float *bias, const unsigned long int M,
                       const unsigned long int N, const unsigned long int P) {
  // We work on 4 rows of the matrix at once
  const unsigned long int block_size = 8;
  unsigned long int block_size_p;

  // Set the vector configuration
  asm volatile("vsetvli %0, %1, e16, m1, ta, ma" : "=r"(block_size_p) : "r"(P));

  // Slice the matrix into a manageable number of columns p_
  for (unsigned long int p = 0; p < P; p += block_size_p) {
    // Set the vector length
    const unsigned long int p_ = MIN(P - p, block_size_p);

    // Find pointers to the submatrices
    const _Float16 *b_ = b + p;
    float *c_ = c + p;
    const float *bias_slice = bias + p;

    asm volatile("vsetvli zero, %0, e16, m1, ta, ma" : : "r"(p_));

    // Iterate over the rows
    for (unsigned long int m = 0; m < M; m += block_size) {
      // Find pointer to the submatrices
      const _Float16 *a_ = a + m * N;
      float *c__ = c_ + m * P;

      fmatmul_vec_8x8_slice_init_fused(bias_slice, p_);
      fmatmul_vec_8x8(c__, a_, b_, N, P, p_);
    }
  }
}

void fmatmul_8x8_nt(float *c, const _Float16 *a, const _Float16 *b,
                    const unsigned long int M, const unsigned long int N,
                    const unsigned long int P) {
  // We work on 4 rows of the matrix at once
  const unsigned long int block_size = 8;
  unsigned long int block_size_p;

  // Set the vector configuration
  asm volatile("vsetvli %0, %1, e16, m1, ta, ma" : "=r"(block_size_p) : "r"(P));

  // Slice the matrix into a manageable number of columns p_
  for (unsigned long int p = 0; p < P; p += block_size_p) {
    // Set the vector length
    const unsigned long int p_ = MIN(P - p, block_size_p);

    // Find pointers to the submatrices
    const _Float16 *b_ = b + p * N;
    float *c_ = c + p;

    asm volatile("vsetvli zero, %0, e16, m1, ta, ma" : : "r"(p_));

    // Iterate over the rows
    for (unsigned long int m = 0; m < M; m += block_size) {
      // Find pointer to the submatrices
      const _Float16 *a_ = a + m * N;
      float *c__ = c_ + m * P;

      fmatmul_vec_8x8_slice_init(p_);
      fmatmul_vec_8x8_nt(c__, a_, b_, N, P, p_);
    }
  }
}

void fmatmul_8x8_tn(float *c, const _Float16 *a, const _Float16 *b,
                    const unsigned long int M, const unsigned long int N,
                    const unsigned long int P) {
  const unsigned long int block_size = 8;
  unsigned long int block_size_p;

  asm volatile("vsetvli %0, %1, e16, m1, ta, ma" : "=r"(block_size_p) : "r"(P));

  for (unsigned long int p = 0; p < P; p += block_size_p) {
    const unsigned long int p_ = MIN(P - p, block_size_p);

    const _Float16 *b_ = b + p;
    float *c_ = c + p;

    asm volatile("vsetvli zero, %0, e16, m1, ta, ma" : : "r"(p_));

    for (unsigned long int n = 0; n < N; n += block_size) {
      const _Float16 *a_ = a + n;
      float *c__ = c_ + n * P;

      fmatmul_vec_8x8_slice_init(p_);
      fmatmul_vec_8x8_tn(c__, a_, b_, M, P, N, p_);
    }
  }
}

void fmatmul_vec_8x8_slice_init(unsigned long int vl) {
  asm volatile("vsetvli zero, %0, e32, m2, ta, ma" :: "r"(vl));
  asm volatile("vmv.v.i v0,  0");
  asm volatile("vmv.v.i v2,  0");
  asm volatile("vmv.v.i v4,  0");
  asm volatile("vmv.v.i v6,  0");
  asm volatile("vmv.v.i v8,  0");
  asm volatile("vmv.v.i v10, 0");
  asm volatile("vmv.v.i v12, 0");
  asm volatile("vmv.v.i v14, 0");
  asm volatile("vsetvli zero, %0, e16, m1, ta, ma" :: "r"(vl));
}

void fmatmul_vec_8x8_slice_load_bias(const float *bias_slice, unsigned long int vl) {
  asm volatile("vsetvli zero, %0, e32, m2, ta, ma" :: "r"(vl));
  asm volatile("vle32.v v0, (%0);" ::"r"(bias_slice));
  asm volatile("vmv.v.v v2,  v0");
  asm volatile("vmv.v.v v4,  v0");
  asm volatile("vmv.v.v v6,  v0");
  asm volatile("vmv.v.v v8,  v0");
  asm volatile("vmv.v.v v10, v0");
  asm volatile("vmv.v.v v12, v0");
  asm volatile("vmv.v.v v14, v0");
  asm volatile("vsetvli zero, %0, e16, m1, ta, ma" :: "r"(vl));
}

void fmatmul_vec_8x8_slice_init_fused(const float *bias_slice, unsigned long int vl) {
  asm volatile("vsetvli zero, %0, e32, m2, ta, ma" :: "r"(vl));
  asm volatile("vle32.v v0, (%0);" ::"r"(bias_slice));
  asm volatile("vmv.v.v v2,  v0");
  asm volatile("vmv.v.v v4,  v0");
  asm volatile("vmv.v.v v6,  v0");
  asm volatile("vmv.v.v v8,  v0");
  asm volatile("vmv.v.v v10, v0");
  asm volatile("vmv.v.v v12, v0");
  asm volatile("vmv.v.v v14, v0");
  asm volatile("vsetvli zero, %0, e16, m1, ta, ma" :: "r"(vl));
}

void fmatmul_vec_8x8(float *c, const _Float16 *a, const _Float16 *b,
                     const unsigned long int N, const unsigned long int P,
                     const unsigned long int vl) {
  // Temporary variables
  _Float16 t0, t1, t2, t3, t4, t5, t6, t7;

  // Original pointer
  const _Float16 *a_ = a;

  asm volatile("vsetvli zero, %0, e16, m1, ta, ma" :: "r"(vl));
  // Prefetch one row of matrix B
  asm volatile("vle16.v v18, (%0);" ::"r"(b));
  b += P;

  // Prefetch one row of scalar values
  t0 = *a, a += N;
  t1 = *a, a += N;
  t2 = *a, a += N;
  t3 = *a, a += N;
  t4 = *a, a += N;
  t5 = *a, a += N;
  t6 = *a, a += N;
  t7 = *a;

  // Compute the multiplication
  unsigned long int n = 0;

  while (n != N) {
#ifdef VCD_DUMP
    // Start dumping VCD
    if (n == 8)
      event_trigger = +1;
    // Stop dumping VCD
    if (n == 12)
      event_trigger = -1;
#endif

    // Calculate pointer to the matrix A
    a = a_ + ++n;

    asm volatile("vfwmacc.vf v0, %0, v18" ::"f"(t0));
    t0 = *a, a += N;

    // Load one row of B
    asm volatile("vle16.v v20, (%0);" ::"r"(b));
    b += P;

    asm volatile("vfwmacc.vf v2, %0, v18" ::"f"(t1));
    t1 = *a, a += N;
    asm volatile("vfwmacc.vf v4, %0, v18" ::"f"(t2));
    t2 = *a, a += N;
    asm volatile("vfwmacc.vf v6, %0, v18" ::"f"(t3));
    t3 = *a, a += N;
    asm volatile("vfwmacc.vf v8, %0, v18" ::"f"(t4));
    t4 = *a, a += N;
    asm volatile("vfwmacc.vf v10, %0, v18" ::"f"(t5));
    t5 = *a, a += N;
    asm volatile("vfwmacc.vf v12, %0, v18" ::"f"(t6));
    t6 = *a, a += N;
    asm volatile("vfwmacc.vf v14, %0, v18" ::"f"(t7));
    t7 = *a;

    a = a_ + ++n;

    if (n == N)
      break;

    asm volatile("vfwmacc.vf v0, %0, v20" ::"f"(t0));
    t0 = *a, a += N;

    // Load one row of B
    asm volatile("vle16.v v18, (%0);" ::"r"(b));
    b += P;

    asm volatile("vfwmacc.vf v2, %0, v20" ::"f"(t1));
    t1 = *a, a += N;
    asm volatile("vfwmacc.vf v4, %0, v20" ::"f"(t2));
    t2 = *a, a += N;
    asm volatile("vfwmacc.vf v6, %0, v20" ::"f"(t3));
    t3 = *a, a += N;
    asm volatile("vfwmacc.vf v8, %0, v20" ::"f"(t4));
    t4 = *a, a += N;
    asm volatile("vfwmacc.vf v10, %0, v20" ::"f"(t5));
    t5 = *a, a += N;
    asm volatile("vfwmacc.vf v12, %0, v20" ::"f"(t6));
    t6 = *a, a += N;
    asm volatile("vfwmacc.vf v14, %0, v20" ::"f"(t7));
    t7 = *a;
  }

  // Last iteration: final math (Ακόμα σε e16, m1)
  asm volatile("vfwmacc.vf v0, %0, v20" ::"f"(t0));
  asm volatile("vfwmacc.vf v2, %0, v20" ::"f"(t1));
  asm volatile("vfwmacc.vf v4, %0, v20" ::"f"(t2));
  asm volatile("vfwmacc.vf v6, %0, v20" ::"f"(t3));
  asm volatile("vfwmacc.vf v8, %0, v20" ::"f"(t4));
  asm volatile("vfwmacc.vf v10, %0, v20" ::"f"(t5));
  asm volatile("vfwmacc.vf v12, %0, v20" ::"f"(t6));
  asm volatile("vfwmacc.vf v14, %0, v20" ::"f"(t7));

  // --- ΚΡΙΣΙΜΟ CONTEXT SWITCH ---
  // Γυρνάμε τον επεξεργαστή σε 32-bit mode (m2) για να γράψει σωστά τα FP32 αποτελέσματα!
  asm volatile("vsetvli zero, %0, e32, m2, ta, ma" :: "r"(vl));

  asm volatile("vse32.v v0, (%0);" ::"r"(c));
  c += P;
  asm volatile("vse32.v v2, (%0);" ::"r"(c));
  c += P;
  asm volatile("vse32.v v4, (%0);" ::"r"(c));
  c += P;
  asm volatile("vse32.v v6, (%0);" ::"r"(c));
  c += P;
  asm volatile("vse32.v v8, (%0);" ::"r"(c));
  c += P;
  asm volatile("vse32.v v10, (%0);" ::"r"(c));
  c += P;
  asm volatile("vse32.v v12, (%0);" ::"r"(c));
  c += P;
  asm volatile("vse32.v v14, (%0);" ::"r"(c));
}

void fmatmul_vec_8x8_nt(float *c, const _Float16 *a, const _Float16 *b,
                        const unsigned long int N, const unsigned long int P,
                        const unsigned long int vl) {
  // Temporary variables
  _Float16 t0, t1, t2, t3, t4, t5, t6, t7;

  // Original pointer
  const _Float16 *a_ = a;
  long stride_b_bytes = (long)N * (long)sizeof(_Float16);

  asm volatile("vsetvli zero, %0, e16, m1, ta, ma" :: "r"(vl));
  // Prefetch one column of matrix B (row-major B, strided by N)
  asm volatile("vlse16.v v18, (%0), %1" : : "r"(b), "r"(stride_b_bytes));
  b += 1;

  // Prefetch one column of scalar values
  t0 = *a, a += N;
  t1 = *a, a += N;
  t2 = *a, a += N;
  t3 = *a, a += N;
  t4 = *a, a += N;
  t5 = *a, a += N;
  t6 = *a, a += N;
  t7 = *a;

  // Compute the multiplication
  unsigned long int n = 0;

  while (n != N) {
#ifdef VCD_DUMP
    // Start dumping VCD
    if (n == 8)
      event_trigger = +1;
    // Stop dumping VCD
    if (n == 12)
      event_trigger = -1;
#endif

    // Calculate pointer to the matrix A
    a = a_ + ++n;

    asm volatile("vfwmacc.vf v0, %0, v18" ::"f"(t0));
    t0 = *a, a += N;

    // Load next column of B
    asm volatile("vlse16.v v20, (%0), %1" : : "r"(b), "r"(stride_b_bytes));
    b += 1;

    asm volatile("vfwmacc.vf v2, %0, v18" ::"f"(t1));
    t1 = *a, a += N;
    asm volatile("vfwmacc.vf v4, %0, v18" ::"f"(t2));
    t2 = *a, a += N;
    asm volatile("vfwmacc.vf v6, %0, v18" ::"f"(t3));
    t3 = *a, a += N;
    asm volatile("vfwmacc.vf v8, %0, v18" ::"f"(t4));
    t4 = *a, a += N;
    asm volatile("vfwmacc.vf v10, %0, v18" ::"f"(t5));
    t5 = *a, a += N;
    asm volatile("vfwmacc.vf v12, %0, v18" ::"f"(t6));
    t6 = *a, a += N;
    asm volatile("vfwmacc.vf v14, %0, v18" ::"f"(t7));
    t7 = *a;

    a = a_ + ++n;

    if (n == N)
      break;

    asm volatile("vfwmacc.vf v0, %0, v20" ::"f"(t0));
    t0 = *a, a += N;

    // Load next column of B
    asm volatile("vlse16.v v18, (%0), %1" : : "r"(b), "r"(stride_b_bytes));
    b += 1;

    asm volatile("vfwmacc.vf v2, %0, v20" ::"f"(t1));
    t1 = *a, a += N;
    asm volatile("vfwmacc.vf v4, %0, v20" ::"f"(t2));
    t2 = *a, a += N;
    asm volatile("vfwmacc.vf v6, %0, v20" ::"f"(t3));
    t3 = *a, a += N;
    asm volatile("vfwmacc.vf v8, %0, v20" ::"f"(t4));
    t4 = *a, a += N;
    asm volatile("vfwmacc.vf v10, %0, v20" ::"f"(t5));
    t5 = *a, a += N;
    asm volatile("vfwmacc.vf v12, %0, v20" ::"f"(t6));
    t6 = *a, a += N;
    asm volatile("vfwmacc.vf v14, %0, v20" ::"f"(t7));
    t7 = *a;
  }

  // Last iteration: final math (Ακόμα σε e16, m1)
  asm volatile("vfwmacc.vf v0, %0, v20" ::"f"(t0));
  asm volatile("vfwmacc.vf v2, %0, v20" ::"f"(t1));
  asm volatile("vfwmacc.vf v4, %0, v20" ::"f"(t2));
  asm volatile("vfwmacc.vf v6, %0, v20" ::"f"(t3));
  asm volatile("vfwmacc.vf v8, %0, v20" ::"f"(t4));
  asm volatile("vfwmacc.vf v10, %0, v20" ::"f"(t5));
  asm volatile("vfwmacc.vf v12, %0, v20" ::"f"(t6));
  asm volatile("vfwmacc.vf v14, %0, v20" ::"f"(t7));

  // --- ΚΡΙΣΙΜΟ CONTEXT SWITCH ---
  // Γυρνάμε τον επεξεργαστή σε 32-bit mode (m2) για να γράψει σωστά τα FP32 αποτελέσματα!
  asm volatile("vsetvli zero, %0, e32, m2, ta, ma" :: "r"(vl));

  asm volatile("vse32.v v0, (%0);" ::"r"(c));
  c += P;
  asm volatile("vse32.v v2, (%0);" ::"r"(c));
  c += P;
  asm volatile("vse32.v v4, (%0);" ::"r"(c));
  c += P;
  asm volatile("vse32.v v6, (%0);" ::"r"(c));
  c += P;
  asm volatile("vse32.v v8, (%0);" ::"r"(c));
  c += P;
  asm volatile("vse32.v v10, (%0);" ::"r"(c));
  c += P;
  asm volatile("vse32.v v12, (%0);" ::"r"(c));
  c += P;
  asm volatile("vse32.v v14, (%0);" ::"r"(c));
}

void fmatmul_vec_8x8_tn(float *c, const _Float16 *a, const _Float16 *b,
                        const unsigned long int N, const unsigned long int P,
                        const unsigned long int lda, const unsigned long int vl) {
  _Float16 t0, t1, t2, t3, t4, t5, t6, t7;

  asm volatile("vsetvli zero, %0, e16, m1, ta, ma" :: "r"(vl));
  if (N <= 2) {
    const _Float16 *a_row = a;
    for (unsigned long int m = 0; m < N; m++) {
      asm volatile("vle16.v v18, (%0);" ::"r"(b));
      b += P;

      t0 = a_row[0];
      t1 = a_row[1];
      t2 = a_row[2];
      t3 = a_row[3];
      t4 = a_row[4];
      t5 = a_row[5];
      t6 = a_row[6];
      t7 = a_row[7];

      asm volatile("vfwmacc.vf v0, %0, v18" ::"f"(t0));
      asm volatile("vfwmacc.vf v2, %0, v18" ::"f"(t1));
      asm volatile("vfwmacc.vf v4, %0, v18" ::"f"(t2));
      asm volatile("vfwmacc.vf v6, %0, v18" ::"f"(t3));
      asm volatile("vfwmacc.vf v8, %0, v18" ::"f"(t4));
      asm volatile("vfwmacc.vf v10, %0, v18" ::"f"(t5));
      asm volatile("vfwmacc.vf v12, %0, v18" ::"f"(t6));
      asm volatile("vfwmacc.vf v14, %0, v18" ::"f"(t7));

      a_row += lda;
    }

    asm volatile("vsetvli zero, %0, e32, m2, ta, ma" :: "r"(vl));
    asm volatile("vse32.v v0, (%0);" ::"r"(c));
    c += P;
    asm volatile("vse32.v v2, (%0);" ::"r"(c));
    c += P;
    asm volatile("vse32.v v4, (%0);" ::"r"(c));
    c += P;
    asm volatile("vse32.v v6, (%0);" ::"r"(c));
    c += P;
    asm volatile("vse32.v v8, (%0);" ::"r"(c));
    c += P;
    asm volatile("vse32.v v10, (%0);" ::"r"(c));
    c += P;
    asm volatile("vse32.v v12, (%0);" ::"r"(c));
    c += P;
    asm volatile("vse32.v v14, (%0);" ::"r"(c));
    return;
  }

  asm volatile("vle16.v v18, (%0);" ::"r"(b));
  b += P;

  t0 = a[0];
  t1 = a[1];
  t2 = a[2];
  t3 = a[3];
  t4 = a[4];
  t5 = a[5];
  t6 = a[6];
  t7 = a[7];
  a += lda;

  unsigned long int n = 0;

  while (n != N) {
#ifdef VCD_DUMP
    if (n == 8)
      event_trigger = +1;
    if (n == 12)
      event_trigger = -1;
#endif

    n++;

    asm volatile("vfwmacc.vf v0, %0, v18" ::"f"(t0));
    t0 = a[0];

    asm volatile("vle16.v v20, (%0);" ::"r"(b));
    b += P;

    asm volatile("vfwmacc.vf v2, %0, v18" ::"f"(t1));
    t1 = a[1];
    asm volatile("vfwmacc.vf v4, %0, v18" ::"f"(t2));
    t2 = a[2];
    asm volatile("vfwmacc.vf v6, %0, v18" ::"f"(t3));
    t3 = a[3];
    asm volatile("vfwmacc.vf v8, %0, v18" ::"f"(t4));
    t4 = a[4];
    asm volatile("vfwmacc.vf v10, %0, v18" ::"f"(t5));
    t5 = a[5];
    asm volatile("vfwmacc.vf v12, %0, v18" ::"f"(t6));
    t6 = a[6];
    asm volatile("vfwmacc.vf v14, %0, v18" ::"f"(t7));
    t7 = a[7];

    a += lda;

    if (n == N)
      break;

    n++;

    asm volatile("vfwmacc.vf v0, %0, v20" ::"f"(t0));
    t0 = a[0];

    asm volatile("vle16.v v18, (%0);" ::"r"(b));
    b += P;

    asm volatile("vfwmacc.vf v2, %0, v20" ::"f"(t1));
    t1 = a[1];
    asm volatile("vfwmacc.vf v4, %0, v20" ::"f"(t2));
    t2 = a[2];
    asm volatile("vfwmacc.vf v6, %0, v20" ::"f"(t3));
    t3 = a[3];
    asm volatile("vfwmacc.vf v8, %0, v20" ::"f"(t4));
    t4 = a[4];
    asm volatile("vfwmacc.vf v10, %0, v20" ::"f"(t5));
    t5 = a[5];
    asm volatile("vfwmacc.vf v12, %0, v20" ::"f"(t6));
    t6 = a[6];
    asm volatile("vfwmacc.vf v14, %0, v20" ::"f"(t7));
    t7 = a[7];

    a += lda;
  }

// Last iteration: final math (Ακόμα σε e16, m1)
  asm volatile("vfwmacc.vf v0, %0, v20" ::"f"(t0));
  asm volatile("vfwmacc.vf v2, %0, v20" ::"f"(t1));
  asm volatile("vfwmacc.vf v4, %0, v20" ::"f"(t2));
  asm volatile("vfwmacc.vf v6, %0, v20" ::"f"(t3));
  asm volatile("vfwmacc.vf v8, %0, v20" ::"f"(t4));
  asm volatile("vfwmacc.vf v10, %0, v20" ::"f"(t5));
  asm volatile("vfwmacc.vf v12, %0, v20" ::"f"(t6));
  asm volatile("vfwmacc.vf v14, %0, v20" ::"f"(t7));

  // --- ΚΡΙΣΙΜΟ CONTEXT SWITCH ---
  asm volatile("vsetvli zero, %0, e32, m2, ta, ma" :: "r"(vl));

  // Memory stores (e32 mode)
  asm volatile("vse32.v v0, (%0);" ::"r"(c));
  c += P;
  asm volatile("vse32.v v2, (%0);" ::"r"(c));
  c += P;
  asm volatile("vse32.v v4, (%0);" ::"r"(c));
  c += P;
  asm volatile("vse32.v v6, (%0);" ::"r"(c));
  c += P;
  asm volatile("vse32.v v8, (%0);" ::"r"(c));
  c += P;
  asm volatile("vse32.v v10, (%0);" ::"r"(c));
  c += P;
  asm volatile("vse32.v v12, (%0);" ::"r"(c));
  c += P;
  asm volatile("vse32.v v14, (%0);" ::"r"(c));
}

// ---------------
// 16x16
// ---------------

void fmatmul_16x16(float *c, const _Float16 *a, const _Float16 *b,
                   unsigned long int M, unsigned long int N,
                   unsigned long int P) {
  // We work on 4 rows of the matrix at once
  const unsigned long int block_size = 16;
  unsigned long int block_size_p;

  // Set the vector configuration
  asm volatile("vsetvli %0, %1, e16, mf2, ta, ma" : "=r"(block_size_p) : "r"(P));

  // Slice the matrix into a manageable number of columns p_
  for (unsigned long int p = 0; p < P; p += block_size_p) {
    // Set the vector length
    const unsigned long int p_ = MIN(P - p, block_size_p);

    // Find pointers to the submatrices
    const _Float16 *b_ = b + p;
    float *c_ = c + p;

    asm volatile("vsetvli zero, %0, e16, mf2, ta, ma" ::"r"(p_));

    // Iterate over the rows
    for (unsigned long int m = 0; m < M; m += block_size) {
      // Find pointer to the submatrices
      const _Float16 *a_ = a + m * N;
      float *c__ = c_ + m * P;

      fmatmul_vec_16x16_slice_init(p_);
      fmatmul_vec_16x16(c__, a_, b_, N, P, p_);
    }
  }
}

void fmatmul_16x16_fused(float *c, const _Float16 *a, const _Float16 *b,
                         const float *bias, unsigned long int M,
                         unsigned long int N, unsigned long int P) {
  // We work on 4 rows of the matrix at once
  const unsigned long int block_size = 16;
  unsigned long int block_size_p;

  // Set the vector configuration
  asm volatile("vsetvli %0, %1, e16, mf2, ta, ma" : "=r"(block_size_p) : "r"(P));

  // Slice the matrix into a manageable number of columns p_
  for (unsigned long int p = 0; p < P; p += block_size_p) {
    // Set the vector length
    const unsigned long int p_ = MIN(P - p, block_size_p);

    // Find pointers to the submatrices
    const _Float16 *b_ = b + p;
    float *c_ = c + p;
    const float *bias_slice = bias + p;

    asm volatile("vsetvli zero, %0, e16, mf2, ta, ma" : : "r"(p_));

    // Iterate over the rows
    for (unsigned long int m = 0; m < M; m += block_size) {
      // Find pointer to the submatrices
      const _Float16 *a_ = a + m * N;
      float *c__ = c_ + m * P;

      fmatmul_vec_16x16_slice_init_fused(bias_slice, p_);
      fmatmul_vec_16x16(c__, a_, b_, N, P, p_);
    }
  }
}

void fmatmul_16x16_nt(float *c, const _Float16 *a, const _Float16 *b,
                      unsigned long int M, unsigned long int N,
                      unsigned long int P) {
  // We work on 4 rows of the matrix at once
  const unsigned long int block_size = 16;
  unsigned long int block_size_p;

  // Set the vector configuration
  asm volatile("vsetvli %0, %1, e16, mf2, ta, ma" : "=r"(block_size_p) : "r"(P));

  // Slice the matrix into a manageable number of columns p_
  for (unsigned long int p = 0; p < P; p += block_size_p) {
    // Set the vector length
    const unsigned long int p_ = MIN(P - p, block_size_p);

    // Find pointers to the submatrices
    const _Float16 *b_ = b + p * N;
    float *c_ = c + p;

    asm volatile("vsetvli zero, %0, e16, mf2, ta, ma" : : "r"(p_));

    // Iterate over the rows
    for (unsigned long int m = 0; m < M; m += block_size) {
      // Find pointer to the submatrices
      const _Float16 *a_ = a + m * N;
      float *c__ = c_ + m * P;

      fmatmul_vec_16x16_slice_init(p_);
      fmatmul_vec_16x16_nt(c__, a_, b_, N, P, p_);
    }
  }
}

void fmatmul_16x16_tn(float *c, const _Float16 *a, const _Float16 *b,
                      unsigned long int M, unsigned long int N,
                      unsigned long int P) {
  const unsigned long int block_size = 16;
  unsigned long int block_size_p;

  asm volatile("vsetvli %0, %1, e16, mf2, ta, ma" : "=r"(block_size_p) : "r"(P));

  for (unsigned long int p = 0; p < P; p += block_size_p) {
    const unsigned long int p_ = MIN(P - p, block_size_p);

    const _Float16 *b_ = b + p;
    float *c_ = c + p;

    asm volatile("vsetvli zero, %0, e16, mf2, ta, ma" : : "r"(p_));

    for (unsigned long int n = 0; n < N; n += block_size) {
      const _Float16 *a_ = a + n;
      float *c__ = c_ + n * P;

      fmatmul_vec_16x16_slice_init(p_);
      fmatmul_vec_16x16_tn(c__, a_, b_, M, P, N, p_);
    }
  }
}

void fmatmul_vec_16x16_slice_init(unsigned long int vl) {
  asm volatile("vsetvli zero, %0, e32, m1, ta, ma" :: "r"(vl));
  asm volatile("vmv.v.i v0,  0");
  asm volatile("vmv.v.i v1,  0");
  asm volatile("vmv.v.i v2,  0");
  asm volatile("vmv.v.i v3,  0");
  asm volatile("vmv.v.i v4,  0");
  asm volatile("vmv.v.i v5,  0");
  asm volatile("vmv.v.i v6,  0");
  asm volatile("vmv.v.i v7,  0");
  asm volatile("vmv.v.i v8,  0");
  asm volatile("vmv.v.i v9,  0");
  asm volatile("vmv.v.i v10, 0");
  asm volatile("vmv.v.i v11, 0");
  asm volatile("vmv.v.i v12, 0");
  asm volatile("vmv.v.i v13, 0");
  asm volatile("vmv.v.i v14, 0");
  asm volatile("vmv.v.i v15, 0");
  asm volatile("vsetvli zero, %0, e16, mf2, ta, ma" :: "r"(vl));
}

void fmatmul_vec_16x16_slice_load_bias(const float *bias_slice, unsigned long int vl) {
  asm volatile("vsetvli zero, %0, e32, m1, ta, ma" :: "r"(vl));
  asm volatile("vle32.v v0, (%0);" ::"r"(bias_slice));
  asm volatile("vmv.v.v v1,  v0");
  asm volatile("vmv.v.v v2,  v0");
  asm volatile("vmv.v.v v3,  v0");
  asm volatile("vmv.v.v v4,  v0");
  asm volatile("vmv.v.v v5,  v0");
  asm volatile("vmv.v.v v6,  v0");
  asm volatile("vmv.v.v v7,  v0");
  asm volatile("vmv.v.v v8,  v0");
  asm volatile("vmv.v.v v9,  v0");
  asm volatile("vmv.v.v v10, v0");
  asm volatile("vmv.v.v v11, v0");
  asm volatile("vmv.v.v v12, v0");
  asm volatile("vmv.v.v v13, v0");
  asm volatile("vmv.v.v v14, v0");
  asm volatile("vmv.v.v v15, v0");
  asm volatile("vsetvli zero, %0, e16, mf2, ta, ma" :: "r"(vl));
}

void fmatmul_vec_16x16_slice_init_fused(const float *bias_slice, unsigned long int vl) {
  asm volatile("vsetvli zero, %0, e32, m1, ta, ma" :: "r"(vl));
  asm volatile("vle32.v v0, (%0);" ::"r"(bias_slice));
  asm volatile("vmv.v.v v1,  v0");
  asm volatile("vmv.v.v v2,  v0");
  asm volatile("vmv.v.v v3,  v0");
  asm volatile("vmv.v.v v4,  v0");
  asm volatile("vmv.v.v v5,  v0");
  asm volatile("vmv.v.v v6,  v0");
  asm volatile("vmv.v.v v7,  v0");
  asm volatile("vmv.v.v v8,  v0");
  asm volatile("vmv.v.v v9,  v0");
  asm volatile("vmv.v.v v10, v0");
  asm volatile("vmv.v.v v11, v0");
  asm volatile("vmv.v.v v12, v0");
  asm volatile("vmv.v.v v13, v0");
  asm volatile("vmv.v.v v14, v0");
  asm volatile("vmv.v.v v15, v0");
  asm volatile("vsetvli zero, %0, e16, mf2, ta, ma" :: "r"(vl));
}

void fmatmul_vec_16x16(float *c, const _Float16 *a, const _Float16 *b,
                       const unsigned long int N, const unsigned long int P,
                       const unsigned long int vl) {
  // Temporary variables
  _Float16 t0, t1, t2, t3, t4, t5, t6, t7, t8, t9, t10, t11, t12, t13, t14, t15;

  // Original pointer
  const _Float16 *a_ = a;

  asm volatile("vsetvli zero, %0, e16, mf2, ta, ma" :: "r"(vl));
  // Prefetch one row of scalar values
  t0 = *a, a += N;
  t1 = *a, a += N;
  t2 = *a, a += N;
  t3 = *a, a += N;
  t4 = *a, a += N;
  t5 = *a, a += N;
  t6 = *a, a += N;
  t7 = *a, a += N;
  t8 = *a, a += N;
  t9 = *a, a += N;
  t10 = *a, a += N;
  t11 = *a, a += N;
  t12 = *a, a += N;
  t13 = *a, a += N;
  t14 = *a, a += N;
  t15 = *a;

  // Prefetch one row of matrix B
  asm volatile("vle16.v v16, (%0);" ::"r"(b));
  b += P;

  // Compute the multiplication
  unsigned long int n = 0;

  while (n != N) {
#ifdef VCD_DUMP
    // Start dumping VCD
    if (n == 8)
      event_trigger = +1;
    // Stop dumping VCD
    if (n == 12)
      event_trigger = -1;
#endif

    // Calculate pointer to the matrix A
    a = a_ + ++n;

    asm volatile("vfwmacc.vf v0, %0, v16" ::"f"(t0));
    t0 = *a, a += N;

    // Load one row of B
    asm volatile("vle16.v v17, (%0);" ::"r"(b));
    b += P;

    asm volatile("vfwmacc.vf v1, %0, v16" ::"f"(t1));
    t1 = *a, a += N;
    asm volatile("vfwmacc.vf v2, %0, v16" ::"f"(t2));
    t2 = *a, a += N;
    asm volatile("vfwmacc.vf v3, %0, v16" ::"f"(t3));
    t3 = *a, a += N;
    asm volatile("vfwmacc.vf v4, %0, v16" ::"f"(t4));
    t4 = *a, a += N;
    asm volatile("vfwmacc.vf v5, %0, v16" ::"f"(t5));
    t5 = *a, a += N;
    asm volatile("vfwmacc.vf v6, %0, v16" ::"f"(t6));
    t6 = *a, a += N;
    asm volatile("vfwmacc.vf v7, %0, v16" ::"f"(t7));
    t7 = *a, a += N;
    asm volatile("vfwmacc.vf v8, %0, v16" ::"f"(t8));
    t8 = *a, a += N;
    asm volatile("vfwmacc.vf v9, %0, v16" ::"f"(t9));
    t9 = *a, a += N;
    asm volatile("vfwmacc.vf v10, %0, v16" ::"f"(t10));
    t10 = *a, a += N;
    asm volatile("vfwmacc.vf v11, %0, v16" ::"f"(t11));
    t11 = *a, a += N;
    asm volatile("vfwmacc.vf v12, %0, v16" ::"f"(t12));
    t12 = *a, a += N;
    asm volatile("vfwmacc.vf v13, %0, v16" ::"f"(t13));
    t13 = *a, a += N;
    asm volatile("vfwmacc.vf v14, %0, v16" ::"f"(t14));
    t14 = *a, a += N;
    asm volatile("vfwmacc.vf v15, %0, v16" ::"f"(t15));
    t15 = *a;

    a = a_ + ++n;

    if (n == N)
      break;

    asm volatile("vfwmacc.vf v0, %0, v17" ::"f"(t0));
    t0 = *a, a += N;

    // Load one row of B
    asm volatile("vle16.v v16, (%0);" ::"r"(b));
    b += P;

    asm volatile("vfwmacc.vf v1, %0, v17" ::"f"(t1));
    t1 = *a, a += N;
    asm volatile("vfwmacc.vf v2, %0, v17" ::"f"(t2));
    t2 = *a, a += N;
    asm volatile("vfwmacc.vf v3, %0, v17" ::"f"(t3));
    t3 = *a, a += N;
    asm volatile("vfwmacc.vf v4, %0, v17" ::"f"(t4));
    t4 = *a, a += N;
    asm volatile("vfwmacc.vf v5, %0, v17" ::"f"(t5));
    t5 = *a, a += N;
    asm volatile("vfwmacc.vf v6, %0, v17" ::"f"(t6));
    t6 = *a, a += N;
    asm volatile("vfwmacc.vf v7, %0, v17" ::"f"(t7));
    t7 = *a, a += N;
    asm volatile("vfwmacc.vf v8, %0, v17" ::"f"(t8));
    t8 = *a, a += N;
    asm volatile("vfwmacc.vf v9, %0, v17" ::"f"(t9));
    t9 = *a, a += N;
    asm volatile("vfwmacc.vf v10, %0, v17" ::"f"(t10));
    t10 = *a, a += N;
    asm volatile("vfwmacc.vf v11, %0, v17" ::"f"(t11));
    t11 = *a, a += N;
    asm volatile("vfwmacc.vf v12, %0, v17" ::"f"(t12));
    t12 = *a, a += N;
    asm volatile("vfwmacc.vf v13, %0, v17" ::"f"(t13));
    t13 = *a, a += N;
    asm volatile("vfwmacc.vf v14, %0, v17" ::"f"(t14));
    t14 = *a, a += N;
    asm volatile("vfwmacc.vf v15, %0, v17" ::"f"(t15));
    t15 = *a;
  }

 // Last iteration: final math (Ακόμα σε e16, mf2)
  asm volatile("vfwmacc.vf v0, %0, v17" ::"f"(t0));
  asm volatile("vfwmacc.vf v1, %0, v17" ::"f"(t1));
  asm volatile("vfwmacc.vf v2, %0, v17" ::"f"(t2));
  asm volatile("vfwmacc.vf v3, %0, v17" ::"f"(t3));
  asm volatile("vfwmacc.vf v4, %0, v17" ::"f"(t4));
  asm volatile("vfwmacc.vf v5, %0, v17" ::"f"(t5));
  asm volatile("vfwmacc.vf v6, %0, v17" ::"f"(t6));
  asm volatile("vfwmacc.vf v7, %0, v17" ::"f"(t7));
  asm volatile("vfwmacc.vf v8, %0, v17" ::"f"(t8));
  asm volatile("vfwmacc.vf v9, %0, v17" ::"f"(t9));
  asm volatile("vfwmacc.vf v10, %0, v17" ::"f"(t10));
  asm volatile("vfwmacc.vf v11, %0, v17" ::"f"(t11));
  asm volatile("vfwmacc.vf v12, %0, v17" ::"f"(t12));
  asm volatile("vfwmacc.vf v13, %0, v17" ::"f"(t13));
  asm volatile("vfwmacc.vf v14, %0, v17" ::"f"(t14));
  asm volatile("vfwmacc.vf v15, %0, v17" ::"f"(t15));

  // --- ΚΡΙΣΙΜΟ CONTEXT SWITCH ---
  // Γυρνάμε σε e32 mode (m1) για να γράψουμε σωστά τα FP32 αποτελέσματα!
  asm volatile("vsetvli zero, %0, e32, m1, ta, ma" :: "r"(vl));

  asm volatile("vse32.v v0, (%0);" ::"r"(c)); c += P;
  asm volatile("vse32.v v1, (%0);" ::"r"(c)); c += P;
  asm volatile("vse32.v v2, (%0);" ::"r"(c)); c += P;
  asm volatile("vse32.v v3, (%0);" ::"r"(c)); c += P;
  asm volatile("vse32.v v4, (%0);" ::"r"(c)); c += P;
  asm volatile("vse32.v v5, (%0);" ::"r"(c)); c += P;
  asm volatile("vse32.v v6, (%0);" ::"r"(c)); c += P;
  asm volatile("vse32.v v7, (%0);" ::"r"(c)); c += P;
  asm volatile("vse32.v v8, (%0);" ::"r"(c)); c += P;
  asm volatile("vse32.v v9, (%0);" ::"r"(c)); c += P;
  asm volatile("vse32.v v10, (%0);" ::"r"(c)); c += P;
  asm volatile("vse32.v v11, (%0);" ::"r"(c)); c += P;
  asm volatile("vse32.v v12, (%0);" ::"r"(c)); c += P;
  asm volatile("vse32.v v13, (%0);" ::"r"(c)); c += P;
  asm volatile("vse32.v v14, (%0);" ::"r"(c)); c += P;
  asm volatile("vse32.v v15, (%0);" ::"r"(c));
}

void fmatmul_vec_16x16_nt(float *c, const _Float16 *a, const _Float16 *b,
                          const unsigned long int N, const unsigned long int P,
                          const unsigned long int vl) {
  // Temporary variables
  _Float16 t0, t1, t2, t3, t4, t5, t6, t7, t8, t9, t10, t11, t12, t13, t14, t15;

  // Original pointer
  const _Float16 *a_ = a;
  long stride_b_bytes = (long)N * (long)sizeof(_Float16);

  asm volatile("vsetvli zero, %0, e16, mf2, ta, ma" :: "r"(vl));
  // Prefetch one column of scalar values
  t0 = *a, a += N;
  t1 = *a, a += N;
  t2 = *a, a += N;
  t3 = *a, a += N;
  t4 = *a, a += N;
  t5 = *a, a += N;
  t6 = *a, a += N;
  t7 = *a, a += N;
  t8 = *a, a += N;
  t9 = *a, a += N;
  t10 = *a, a += N;
  t11 = *a, a += N;
  t12 = *a, a += N;
  t13 = *a, a += N;
  t14 = *a, a += N;
  t15 = *a;

  // Prefetch one column of matrix B (row-major B, strided by N)
  asm volatile("vlse16.v v16, (%0), %1" : : "r"(b), "r"(stride_b_bytes));
  b += 1;

  // Compute the multiplication
  unsigned long int n = 0;

  while (n != N) {
#ifdef VCD_DUMP
    // Start dumping VCD
    if (n == 8)
      event_trigger = +1;
    // Stop dumping VCD
    if (n == 12)
      event_trigger = -1;
#endif

    // Calculate pointer to the matrix A
    a = a_ + ++n;

    asm volatile("vfwmacc.vf v0, %0, v16" ::"f"(t0));
    t0 = *a, a += N;

    // Load next column of B
    asm volatile("vlse16.v v17, (%0), %1" : : "r"(b), "r"(stride_b_bytes));
    b += 1;

    asm volatile("vfwmacc.vf v1, %0, v16" ::"f"(t1));
    t1 = *a, a += N;
    asm volatile("vfwmacc.vf v2, %0, v16" ::"f"(t2));
    t2 = *a, a += N;
    asm volatile("vfwmacc.vf v3, %0, v16" ::"f"(t3));
    t3 = *a, a += N;
    asm volatile("vfwmacc.vf v4, %0, v16" ::"f"(t4));
    t4 = *a, a += N;
    asm volatile("vfwmacc.vf v5, %0, v16" ::"f"(t5));
    t5 = *a, a += N;
    asm volatile("vfwmacc.vf v6, %0, v16" ::"f"(t6));
    t6 = *a, a += N;
    asm volatile("vfwmacc.vf v7, %0, v16" ::"f"(t7));
    t7 = *a, a += N;
    asm volatile("vfwmacc.vf v8, %0, v16" ::"f"(t8));
    t8 = *a, a += N;
    asm volatile("vfwmacc.vf v9, %0, v16" ::"f"(t9));
    t9 = *a, a += N;
    asm volatile("vfwmacc.vf v10, %0, v16" ::"f"(t10));
    t10 = *a, a += N;
    asm volatile("vfwmacc.vf v11, %0, v16" ::"f"(t11));
    t11 = *a, a += N;
    asm volatile("vfwmacc.vf v12, %0, v16" ::"f"(t12));
    t12 = *a, a += N;
    asm volatile("vfwmacc.vf v13, %0, v16" ::"f"(t13));
    t13 = *a, a += N;
    asm volatile("vfwmacc.vf v14, %0, v16" ::"f"(t14));
    t14 = *a, a += N;
    asm volatile("vfwmacc.vf v15, %0, v16" ::"f"(t15));
    t15 = *a;

    a = a_ + ++n;

    if (n == N)
      break;

    asm volatile("vfwmacc.vf v0, %0, v17" ::"f"(t0));
    t0 = *a, a += N;

    // Load next column of B
    asm volatile("vlse16.v v16, (%0), %1" : : "r"(b), "r"(stride_b_bytes));
    b += 1;

    asm volatile("vfwmacc.vf v1, %0, v17" ::"f"(t1));
    t1 = *a, a += N;
    asm volatile("vfwmacc.vf v2, %0, v17" ::"f"(t2));
    t2 = *a, a += N;
    asm volatile("vfwmacc.vf v3, %0, v17" ::"f"(t3));
    t3 = *a, a += N;
    asm volatile("vfwmacc.vf v4, %0, v17" ::"f"(t4));
    t4 = *a, a += N;
    asm volatile("vfwmacc.vf v5, %0, v17" ::"f"(t5));
    t5 = *a, a += N;
    asm volatile("vfwmacc.vf v6, %0, v17" ::"f"(t6));
    t6 = *a, a += N;
    asm volatile("vfwmacc.vf v7, %0, v17" ::"f"(t7));
    t7 = *a, a += N;
    asm volatile("vfwmacc.vf v8, %0, v17" ::"f"(t8));
    t8 = *a, a += N;
    asm volatile("vfwmacc.vf v9, %0, v17" ::"f"(t9));
    t9 = *a, a += N;
    asm volatile("vfwmacc.vf v10, %0, v17" ::"f"(t10));
    t10 = *a, a += N;
    asm volatile("vfwmacc.vf v11, %0, v17" ::"f"(t11));
    t11 = *a, a += N;
    asm volatile("vfwmacc.vf v12, %0, v17" ::"f"(t12));
    t12 = *a, a += N;
    asm volatile("vfwmacc.vf v13, %0, v17" ::"f"(t13));
    t13 = *a, a += N;
    asm volatile("vfwmacc.vf v14, %0, v17" ::"f"(t14));
    t14 = *a, a += N;
    asm volatile("vfwmacc.vf v15, %0, v17" ::"f"(t15));
    t15 = *a;
  }

 // Last iteration: final math (Ακόμα σε e16, mf2)
  asm volatile("vfwmacc.vf v0, %0, v17" ::"f"(t0));
  asm volatile("vfwmacc.vf v1, %0, v17" ::"f"(t1));
  asm volatile("vfwmacc.vf v2, %0, v17" ::"f"(t2));
  asm volatile("vfwmacc.vf v3, %0, v17" ::"f"(t3));
  asm volatile("vfwmacc.vf v4, %0, v17" ::"f"(t4));
  asm volatile("vfwmacc.vf v5, %0, v17" ::"f"(t5));
  asm volatile("vfwmacc.vf v6, %0, v17" ::"f"(t6));
  asm volatile("vfwmacc.vf v7, %0, v17" ::"f"(t7));
  asm volatile("vfwmacc.vf v8, %0, v17" ::"f"(t8));
  asm volatile("vfwmacc.vf v9, %0, v17" ::"f"(t9));
  asm volatile("vfwmacc.vf v10, %0, v17" ::"f"(t10));
  asm volatile("vfwmacc.vf v11, %0, v17" ::"f"(t11));
  asm volatile("vfwmacc.vf v12, %0, v17" ::"f"(t12));
  asm volatile("vfwmacc.vf v13, %0, v17" ::"f"(t13));
  asm volatile("vfwmacc.vf v14, %0, v17" ::"f"(t14));
  asm volatile("vfwmacc.vf v15, %0, v17" ::"f"(t15));

  // --- ΚΡΙΣΙΜΟ CONTEXT SWITCH ---
  // Γυρνάμε σε e32, m1 για να αποθηκεύσουμε τα FP32 αποτελέσματα
  asm volatile("vsetvli zero, %0, e32, m1, ta, ma" :: "r"(vl));

  asm volatile("vse32.v v0, (%0);" ::"r"(c)); c += P;
  asm volatile("vse32.v v1, (%0);" ::"r"(c)); c += P;
  asm volatile("vse32.v v2, (%0);" ::"r"(c)); c += P;
  asm volatile("vse32.v v3, (%0);" ::"r"(c)); c += P;
  asm volatile("vse32.v v4, (%0);" ::"r"(c)); c += P;
  asm volatile("vse32.v v5, (%0);" ::"r"(c)); c += P;
  asm volatile("vse32.v v6, (%0);" ::"r"(c)); c += P;
  asm volatile("vse32.v v7, (%0);" ::"r"(c)); c += P;
  asm volatile("vse32.v v8, (%0);" ::"r"(c)); c += P;
  asm volatile("vse32.v v9, (%0);" ::"r"(c)); c += P;
  asm volatile("vse32.v v10, (%0);" ::"r"(c)); c += P;
  asm volatile("vse32.v v11, (%0);" ::"r"(c)); c += P;
  asm volatile("vse32.v v12, (%0);" ::"r"(c)); c += P;
  asm volatile("vse32.v v13, (%0);" ::"r"(c)); c += P;
  asm volatile("vse32.v v14, (%0);" ::"r"(c)); c += P;
  asm volatile("vse32.v v15, (%0);" ::"r"(c));
}

void fmatmul_vec_16x16_tn(float *c, const _Float16 *a, const _Float16 *b,
                          const unsigned long int N, const unsigned long int P,
                          const unsigned long int lda, const unsigned long int vl) {
  _Float16 t0, t1, t2, t3, t4, t5, t6, t7, t8, t9, t10, t11, t12, t13, t14, t15;

  asm volatile("vsetvli zero, %0, e16, mf2, ta, ma" :: "r"(vl));
  if (N <= 2) {
    const _Float16 *a_row = a;
    for (unsigned long int m = 0; m < N; m++) {
      asm volatile("vle16.v v16, (%0);" ::"r"(b));
      b += P;

      t0 = a_row[0];
      t1 = a_row[1];
      t2 = a_row[2];
      t3 = a_row[3];
      t4 = a_row[4];
      t5 = a_row[5];
      t6 = a_row[6];
      t7 = a_row[7];
      t8 = a_row[8];
      t9 = a_row[9];
      t10 = a_row[10];
      t11 = a_row[11];
      t12 = a_row[12];
      t13 = a_row[13];
      t14 = a_row[14];
      t15 = a_row[15];

      asm volatile("vfwmacc.vf v0, %0, v16" ::"f"(t0));
      asm volatile("vfwmacc.vf v1, %0, v16" ::"f"(t1));
      asm volatile("vfwmacc.vf v2, %0, v16" ::"f"(t2));
      asm volatile("vfwmacc.vf v3, %0, v16" ::"f"(t3));
      asm volatile("vfwmacc.vf v4, %0, v16" ::"f"(t4));
      asm volatile("vfwmacc.vf v5, %0, v16" ::"f"(t5));
      asm volatile("vfwmacc.vf v6, %0, v16" ::"f"(t6));
      asm volatile("vfwmacc.vf v7, %0, v16" ::"f"(t7));
      asm volatile("vfwmacc.vf v8, %0, v16" ::"f"(t8));
      asm volatile("vfwmacc.vf v9, %0, v16" ::"f"(t9));
      asm volatile("vfwmacc.vf v10, %0, v16" ::"f"(t10));
      asm volatile("vfwmacc.vf v11, %0, v16" ::"f"(t11));
      asm volatile("vfwmacc.vf v12, %0, v16" ::"f"(t12));
      asm volatile("vfwmacc.vf v13, %0, v16" ::"f"(t13));
      asm volatile("vfwmacc.vf v14, %0, v16" ::"f"(t14));
      asm volatile("vfwmacc.vf v15, %0, v16" ::"f"(t15));

      a_row += lda;
    }

    asm volatile("vse32.v v0, (%0);" ::"r"(c));
    c += P;
    asm volatile("vse32.v v1, (%0);" ::"r"(c));
    c += P;
    asm volatile("vse32.v v2, (%0);" ::"r"(c));
    c += P;
    asm volatile("vse32.v v3, (%0);" ::"r"(c));
    c += P;
    asm volatile("vse32.v v4, (%0);" ::"r"(c));
    c += P;
    asm volatile("vse32.v v5, (%0);" ::"r"(c));
    c += P;
    asm volatile("vse32.v v6, (%0);" ::"r"(c));
    c += P;
    asm volatile("vse32.v v7, (%0);" ::"r"(c));
    c += P;
    asm volatile("vse32.v v8, (%0);" ::"r"(c));
    c += P;
    asm volatile("vse32.v v9, (%0);" ::"r"(c));
    c += P;
    asm volatile("vse32.v v10, (%0);" ::"r"(c));
    c += P;
    asm volatile("vse32.v v11, (%0);" ::"r"(c));
    c += P;
    asm volatile("vse32.v v12, (%0);" ::"r"(c));
    c += P;
    asm volatile("vse32.v v13, (%0);" ::"r"(c));
    c += P;
    asm volatile("vse32.v v14, (%0);" ::"r"(c));
    c += P;
    asm volatile("vse32.v v15, (%0);" ::"r"(c));
    return;
  }

  t0 = a[0];
  t1 = a[1];
  t2 = a[2];
  t3 = a[3];
  t4 = a[4];
  t5 = a[5];
  t6 = a[6];
  t7 = a[7];
  t8 = a[8];
  t9 = a[9];
  t10 = a[10];
  t11 = a[11];
  t12 = a[12];
  t13 = a[13];
  t14 = a[14];
  t15 = a[15];

  a += lda;

  asm volatile("vle16.v v16, (%0);" ::"r"(b));
  b += P;

  unsigned long int n = 0;

  while (n != N) {
#ifdef VCD_DUMP
    if (n == 8)
      event_trigger = +1;
    if (n == 12)
      event_trigger = -1;
#endif

    n++;

    asm volatile("vfwmacc.vf v0, %0, v16" ::"f"(t0));
    t0 = a[0];

    asm volatile("vle16.v v17, (%0);" ::"r"(b));
    b += P;

    asm volatile("vfwmacc.vf v1, %0, v16" ::"f"(t1));
    t1 = a[1];
    asm volatile("vfwmacc.vf v2, %0, v16" ::"f"(t2));
    t2 = a[2];
    asm volatile("vfwmacc.vf v3, %0, v16" ::"f"(t3));
    t3 = a[3];
    asm volatile("vfwmacc.vf v4, %0, v16" ::"f"(t4));
    t4 = a[4];
    asm volatile("vfwmacc.vf v5, %0, v16" ::"f"(t5));
    t5 = a[5];
    asm volatile("vfwmacc.vf v6, %0, v16" ::"f"(t6));
    t6 = a[6];
    asm volatile("vfwmacc.vf v7, %0, v16" ::"f"(t7));
    t7 = a[7];
    asm volatile("vfwmacc.vf v8, %0, v16" ::"f"(t8));
    t8 = a[8];
    asm volatile("vfwmacc.vf v9, %0, v16" ::"f"(t9));
    t9 = a[9];
    asm volatile("vfwmacc.vf v10, %0, v16" ::"f"(t10));
    t10 = a[10];
    asm volatile("vfwmacc.vf v11, %0, v16" ::"f"(t11));
    t11 = a[11];
    asm volatile("vfwmacc.vf v12, %0, v16" ::"f"(t12));
    t12 = a[12];
    asm volatile("vfwmacc.vf v13, %0, v16" ::"f"(t13));
    t13 = a[13];
    asm volatile("vfwmacc.vf v14, %0, v16" ::"f"(t14));
    t14 = a[14];
    asm volatile("vfwmacc.vf v15, %0, v16" ::"f"(t15));
    t15 = a[15];

    a += lda;

    if (n == N)
      break;

    n++;

    asm volatile("vfwmacc.vf v0, %0, v17" ::"f"(t0));
    t0 = a[0];

    asm volatile("vle16.v v16, (%0);" ::"r"(b));
    b += P;

    asm volatile("vfwmacc.vf v1, %0, v17" ::"f"(t1));
    t1 = a[1];
    asm volatile("vfwmacc.vf v2, %0, v17" ::"f"(t2));
    t2 = a[2];
    asm volatile("vfwmacc.vf v3, %0, v17" ::"f"(t3));
    t3 = a[3];
    asm volatile("vfwmacc.vf v4, %0, v17" ::"f"(t4));
    t4 = a[4];
    asm volatile("vfwmacc.vf v5, %0, v17" ::"f"(t5));
    t5 = a[5];
    asm volatile("vfwmacc.vf v6, %0, v17" ::"f"(t6));
    t6 = a[6];
    asm volatile("vfwmacc.vf v7, %0, v17" ::"f"(t7));
    t7 = a[7];
    asm volatile("vfwmacc.vf v8, %0, v17" ::"f"(t8));
    t8 = a[8];
    asm volatile("vfwmacc.vf v9, %0, v17" ::"f"(t9));
    t9 = a[9];
    asm volatile("vfwmacc.vf v10, %0, v17" ::"f"(t10));
    t10 = a[10];
    asm volatile("vfwmacc.vf v11, %0, v17" ::"f"(t11));
    t11 = a[11];
    asm volatile("vfwmacc.vf v12, %0, v17" ::"f"(t12));
    t12 = a[12];
    asm volatile("vfwmacc.vf v13, %0, v17" ::"f"(t13));
    t13 = a[13];
    asm volatile("vfwmacc.vf v14, %0, v17" ::"f"(t14));
    t14 = a[14];
    asm volatile("vfwmacc.vf v15, %0, v17" ::"f"(t15));
    t15 = a[15];

    a += lda;
  }

// Last iteration: final math (Ακόμα σε e16, mf2)
  asm volatile("vfwmacc.vf v0, %0, v17" ::"f"(t0));
  asm volatile("vfwmacc.vf v1, %0, v17" ::"f"(t1));
  asm volatile("vfwmacc.vf v2, %0, v17" ::"f"(t2));
  asm volatile("vfwmacc.vf v3, %0, v17" ::"f"(t3));
  asm volatile("vfwmacc.vf v4, %0, v17" ::"f"(t4));
  asm volatile("vfwmacc.vf v5, %0, v17" ::"f"(t5));
  asm volatile("vfwmacc.vf v6, %0, v17" ::"f"(t6));
  asm volatile("vfwmacc.vf v7, %0, v17" ::"f"(t7));
  asm volatile("vfwmacc.vf v8, %0, v17" ::"f"(t8));
  asm volatile("vfwmacc.vf v9, %0, v17" ::"f"(t9));
  asm volatile("vfwmacc.vf v10, %0, v17" ::"f"(t10));
  asm volatile("vfwmacc.vf v11, %0, v17" ::"f"(t11));
  asm volatile("vfwmacc.vf v12, %0, v17" ::"f"(t12));
  asm volatile("vfwmacc.vf v13, %0, v17" ::"f"(t13));
  asm volatile("vfwmacc.vf v14, %0, v17" ::"f"(t14));
  asm volatile("vfwmacc.vf v15, %0, v17" ::"f"(t15));

  // --- ΚΡΙΣΙΜΟ CONTEXT SWITCH ---
  // Γυρνάμε σε e32, m1 για να αποθηκεύσουμε τα FP32 αποτελέσματα
  asm volatile("vsetvli zero, %0, e32, m1, ta, ma" :: "r"(vl));

  asm volatile("vse32.v v0, (%0);" ::"r"(c)); c += P;
  asm volatile("vse32.v v1, (%0);" ::"r"(c)); c += P;
  asm volatile("vse32.v v2, (%0);" ::"r"(c)); c += P;
  asm volatile("vse32.v v3, (%0);" ::"r"(c)); c += P;
  asm volatile("vse32.v v4, (%0);" ::"r"(c)); c += P;
  asm volatile("vse32.v v5, (%0);" ::"r"(c)); c += P;
  asm volatile("vse32.v v6, (%0);" ::"r"(c)); c += P;
  asm volatile("vse32.v v7, (%0);" ::"r"(c)); c += P;
  asm volatile("vse32.v v8, (%0);" ::"r"(c)); c += P;
  asm volatile("vse32.v v9, (%0);" ::"r"(c)); c += P;
  asm volatile("vse32.v v10, (%0);" ::"r"(c)); c += P;
  asm volatile("vse32.v v11, (%0);" ::"r"(c)); c += P;
  asm volatile("vse32.v v12, (%0);" ::"r"(c)); c += P;
  asm volatile("vse32.v v13, (%0);" ::"r"(c)); c += P;
  asm volatile("vse32.v v14, (%0);" ::"r"(c)); c += P;
  asm volatile("vse32.v v15, (%0);" ::"r"(c));
}