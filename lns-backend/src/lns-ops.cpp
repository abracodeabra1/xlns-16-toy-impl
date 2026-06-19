#include "lns-ops.h"
#include "ggml-impl.h"

#include <cmath>
#include <cstdlib>
#include <cstring>
#include <vector>

// xlns16 defines — must be set before including xlns16.cpp
// (also set via CMake target_compile_definitions; guarded here for clarity).
// xlns16_table: O(1) float<->xlns16 via 65536-entry lookup table.
// xlns16_alt: reduced-branching sb/db addition path.
// xlns16_ideal is NOT defined (matches a realistic hardware target).
#ifndef xlns16_table
#define xlns16_table
#endif
#ifndef xlns16_alt
#define xlns16_alt
#endif

#include "xlns16.cpp"

// ============================================================
// C-linkage conversion helpers (registered as type-trait hooks)
// ============================================================

extern "C" {

void lns16_to_f32_row(const void * GGML_RESTRICT src, float * GGML_RESTRICT dst, int64_t n) {
    const xlns16 * s = (const xlns16 *)src;
    for (int64_t i = 0; i < n; i++) {
        dst[i] = xlns162fp(s[i]);
    }
}

void f32_to_lns16_row(const float * GGML_RESTRICT src, void * GGML_RESTRICT dst, int64_t n) {
    xlns16_batch_from_float(src, (xlns16 *)dst, (size_t)n);
}

} // extern "C"

// ============================================================
// Helper: convert a row from any ggml type to xlns16
// Handles F32, LNS16, and any quantized type with to_float.
// ============================================================

static void row_to_xlns16(const void * src, enum ggml_type type, xlns16 * dst, float * f32_scratch, int64_t n) {
    if (type == GGML_TYPE_LNS16) {
        // Already xlns16 — direct copy, no conversion needed
        memcpy(dst, src, (size_t)n * sizeof(xlns16));
    } else if (type == GGML_TYPE_F32) {
        xlns16_batch_from_float((const float *)src, dst, (size_t)n);
    } else {
        const auto * traits = ggml_get_type_traits(type);
        GGML_ASSERT(traits->to_float != NULL);
        traits->to_float(src, f32_scratch, n);
        xlns16_batch_from_float(f32_scratch, dst, (size_t)n);
    }
}

// ============================================================
// Element-wise typed read/write helpers
// These use array indexing within a row — strides across rows
// are handled by the caller via the nb[] byte offsets.
// ============================================================

static inline xlns16 read_elem_xlns16(const void * row, int64_t i, enum ggml_type type) {
    GGML_ASSERT(type == GGML_TYPE_LNS16 || type == GGML_TYPE_F32);
    if (type == GGML_TYPE_LNS16) {
        return ((const xlns16 *)row)[i];
    }
    return fp2xlns16(((const float *)row)[i]);
}

static inline void write_elem_xlns16(void * row, int64_t i, enum ggml_type type, xlns16 val) {
    GGML_ASSERT(type == GGML_TYPE_LNS16 || type == GGML_TYPE_F32);
    if (type == GGML_TYPE_LNS16) {
        ((xlns16 *)row)[i] = val;
    } else {
        ((float *)row)[i] = xlns162fp(val);
    }
}

// ============================================================
// MUL_MAT: dst = src0^T * src1
// src0: weights (any type with to_float, or F32/LNS16)
// src1: activations (F32 or LNS16)
// dst:  F32 or LNS16 depending on dst->type
// ============================================================

void lns_mul_mat(struct ggml_tensor * dst) {
    const struct ggml_tensor * src0 = dst->src[0];
    const struct ggml_tensor * src1 = dst->src[1];

    GGML_TENSOR_BINARY_OP_LOCALS

    const enum ggml_type type0 = src0->type;
    const int64_t K = ne00;
    GGML_ASSERT(ne10 == K);

    std::vector<float>  f32_scratch(K);
    std::vector<xlns16> a_row_lns(K);
    // Pre-converted activation rows for one (i12,i13) batch slice: ne11 rows of K.
    // Converting src1 once per slice (rather than once per weight row) so this avoids
    // re-converting each weight row ne11 times.
    std::vector<xlns16> b_lns((size_t)ne11 * (size_t)K);

    const int64_t r2 = ne12 / ne02;
    const int64_t r3 = ne13 / ne03;

    for (int64_t i13 = 0; i13 < ne13; i13++) {
        for (int64_t i12 = 0; i12 < ne12; i12++) {
            // Convert all src1 (activation) rows for this slice just once.
            for (int64_t i1 = 0; i1 < ne11; i1++) {
                const void * b_row_raw = (const char *)src1->data
                    + i1*nb11 + i12*nb12 + i13*nb13;
                row_to_xlns16(b_row_raw, src1->type, b_lns.data() + (size_t)i1 * (size_t)K,
                              f32_scratch.data(), K);
            }

            for (int64_t i0 = 0; i0 < ne01; i0++) {
                // src0 (weights): any supported type — convert each weight row only once per slice.
                const void * a_row_raw = (const char *)src0->data
                    + i0*nb01 + (i12/r2)*nb02 + (i13/r3)*nb03;
                row_to_xlns16(a_row_raw, type0, a_row_lns.data(), f32_scratch.data(), K);

                for (int64_t i1 = 0; i1 < ne11; i1++) {
                    xlns16 dot = xlns16_vec_dot(a_row_lns.data(),
                                                b_lns.data() + (size_t)i1 * (size_t)K, K);

                    // Write result: keep as xlns16 if dst is LNS16, else convert to F32
                    void * dst_ptr = (char *)dst->data + i0*nb0 + i1*nb1 + i12*nb2 + i13*nb3;
                    if (dst->type == GGML_TYPE_LNS16) {
                        *(xlns16 *)dst_ptr = dot;
                    } else {
                        *(float *)dst_ptr = xlns162fp(dot);
                    }
                }
            }
        }
    }
}

// ============================================================
// ADD: dst = src0 + src1 (with broadcasting)
// ============================================================

void lns_add(struct ggml_tensor * dst) {
    const struct ggml_tensor * src0 = dst->src[0];
    const struct ggml_tensor * src1 = dst->src[1];

    GGML_TENSOR_BINARY_OP_LOCALS

    // src1 broadcasts over src0: ne1x <= ne0x
    GGML_ASSERT(ne10 == ne00 || ne10 == 1);

    for (int64_t i3 = 0; i3 < ne03; i3++) {
        for (int64_t i2 = 0; i2 < ne02; i2++) {
            for (int64_t i1 = 0; i1 < ne01; i1++) {
                const void * s0 = (const char *)src0->data + i1*nb01 + i2*nb02 + i3*nb03;
                const void * s1 = (const char *)src1->data
                    + (i1 % ne11)*nb11 + (i2 % ne12)*nb12 + (i3 % ne13)*nb13;
                void * d = (char *)dst->data + i1*nb1 + i2*nb2 + i3*nb3;

                for (int64_t i0 = 0; i0 < ne00; i0++) {
                    xlns16 a = read_elem_xlns16(s0, i0, src0->type);
                    xlns16 b = read_elem_xlns16(s1, i0 % ne10, src1->type);
                    write_elem_xlns16(d, i0, dst->type, xlns16_add(a, b));
                }
            }
        }
    }
}

// ============================================================
// MUL: dst = src0 * src1 (element-wise with broadcasting)
// ============================================================

void lns_mul(struct ggml_tensor * dst) {
    const struct ggml_tensor * src0 = dst->src[0];
    const struct ggml_tensor * src1 = dst->src[1];

    GGML_TENSOR_BINARY_OP_LOCALS

    GGML_ASSERT(ne10 == ne00 || ne10 == 1);

    for (int64_t i3 = 0; i3 < ne03; i3++) {
        for (int64_t i2 = 0; i2 < ne02; i2++) {
            for (int64_t i1 = 0; i1 < ne01; i1++) {
                const void * s0 = (const char *)src0->data + i1*nb01 + i2*nb02 + i3*nb03;
                const void * s1 = (const char *)src1->data
                    + (i1 % ne11)*nb11 + (i2 % ne12)*nb12 + (i3 % ne13)*nb13;
                void * d = (char *)dst->data + i1*nb1 + i2*nb2 + i3*nb3;

                for (int64_t i0 = 0; i0 < ne00; i0++) {
                    xlns16 a = read_elem_xlns16(s0, i0, src0->type);
                    xlns16 b = read_elem_xlns16(s1, i0 % ne10, src1->type);
                    write_elem_xlns16(d, i0, dst->type, xlns16_mul(a, b));
                }
            }
        }
    }
}

// ============================================================
// SCALE: dst = src0 * s + b
// ============================================================

void lns_scale(struct ggml_tensor * dst) {
    const struct ggml_tensor * src0 = dst->src[0];

    GGML_ASSERT(ggml_is_contiguous(src0));
    GGML_ASSERT(ggml_is_contiguous(dst));
    GGML_ASSERT(ggml_are_same_shape(src0, dst));

    float s, b;
    memcpy(&s, (float *) dst->op_params + 0, sizeof(float));
    memcpy(&b, (float *) dst->op_params + 1, sizeof(float));

    const xlns16 s_lns = fp2xlns16(s);
    const xlns16 b_lns = fp2xlns16(b);

    const int64_t n = ggml_nelements(src0);

    for (int64_t i = 0; i < n; i++) {
        xlns16 val;
        if (src0->type == GGML_TYPE_LNS16) {
            val = ((const xlns16 *)src0->data)[i];
        } else {
            val = fp2xlns16(((const float *)src0->data)[i]);
        }
        val = xlns16_mul(val, s_lns);
        if (b != 0.0f) {
            val = xlns16_add(val, b_lns);
        }
        if (dst->type == GGML_TYPE_LNS16) {
            ((xlns16 *)dst->data)[i] = val;
        } else {
            ((float *)dst->data)[i] = xlns162fp(val);
        }
    }
}

// fp2xlns16(-INFINITY) is undefined behaviour: casting ±inf to uint16 is UB and
// produces garbage that xlns162fp decodes as an arbitrary value.
// Use this sentinel (sign=1, abs=max) wherever -inf semantics are needed.
static const xlns16 LNS16_NEG_INF = (xlns16)0xFFFFu;

// Safe float->xlns16 that maps -inf (and any value past xlns16 range) to LNS16_NEG_INF
// so that xlns16_exp(LNS16_NEG_INF - max) underflows cleanly to xlns16_zero.
static inline xlns16 float_to_lns16_safe(float v) {
    if (v <= -3.0e38f) return LNS16_NEG_INF;
    return fp2xlns16(v);
}

// Add an F32 mask entry to an xlns16 value (mask tensor is always F32 in ggml).
static inline xlns16 xlns16_add_mask_f32(xlns16 v, float m) {
    if (m <= -3.0e38f) return LNS16_NEG_INF;
    if (m == 0.0f) return v;
    return xlns16_add(v, fp2xlns16(m));
}

// ============================================================
// SOFT_MAX: dst = softmax(src0 * scale + mask)
// ============================================================

void lns_soft_max(struct ggml_tensor * dst) {
    const struct ggml_tensor * src0 = dst->src[0];
    const struct ggml_tensor * src1 = dst->src[1]; // mask (optional)

    // TODO: sink support if required? (models such as openai MoE, MiMo), Llama, SmolLM, don't require them
    // TODO: implement ALiBi -- similar to sinks, not required by current set of models

    float scale, max_bias;
    memcpy(&scale,    (float *) dst->op_params + 0, sizeof(float));
    memcpy(&max_bias, (float *) dst->op_params + 1, sizeof(float));

    const int64_t ne00 = src0->ne[0]; // sequence length
    const int64_t ne01 = src0->ne[1]; // num queries
    const int64_t ne02 = src0->ne[2];
    const int64_t ne03 = src0->ne[3];

    const xlns16 scale_lns = fp2xlns16(scale);

    // For now, ignore ALiBi (max_bias). Implement basic softmax.
    for (int64_t i3 = 0; i3 < ne03; i3++) {
        for (int64_t i2 = 0; i2 < ne02; i2++) {
            for (int64_t i1 = 0; i1 < ne01; i1++) {
                const void * s0_row = (const char *)src0->data
                    + i1*src0->nb[1] + i2*src0->nb[2] + i3*src0->nb[3];
                void * d_row = (char *)dst->data
                    + i1*dst->nb[1] + i2*dst->nb[2] + i3*dst->nb[3];

                // Get mask row if present (mask is always F32)
                const float * mask = nullptr;
                if (src1) {
                    const int64_t ne12 = src1->ne[2];
                    mask = (const float *)((const char *)src1->data
                        + i1*src1->nb[1] + (i2 % ne12)*src1->nb[2] + i3*src1->nb[3]);
                }

                // Step 1: scale + mask, find max.
                // Use LNS16_NEG_INF instead of fp2xlns16(-INFINITY): the latter is UB
                // and produces garbage, causing masked positions to leak into the softmax.
                std::vector<xlns16> row(ne00);
                xlns16 max_val = LNS16_NEG_INF;
                for (int64_t i0 = 0; i0 < ne00; i0++) {
                    xlns16 v = read_elem_xlns16(s0_row, i0, src0->type);

                    // --- float scale+mask path (previous implementation; uncomment to compare) ---
                    // float val = xlns162fp(v) * scale;
                    // if (mask) val += mask[i0];
                    // row[i0] = float_to_lns16_safe(val);

                    // --- pure-xlns16 scale+mask path ---
                    if (v != LNS16_NEG_INF) {
                        v = xlns16_mul(v, scale_lns);
                        if (mask) v = xlns16_add_mask_f32(v, mask[i0]);
                    }
                    row[i0] = v;

                    if (xlns16_gt(row[i0], max_val)) max_val = row[i0];
                }

                // Step 2: exp(x - max) and sum, all in xlns16
                xlns16 sum = fp2xlns16(0.0f);
                for (int64_t i0 = 0; i0 < ne00; i0++) {
                    xlns16 diff = xlns16_sub(row[i0], max_val);
                    row[i0] = xlns16_exp(diff);
                    sum = xlns16_add(sum, row[i0]);
                }

                // Step 3: normalize and write
                for (int64_t i0 = 0; i0 < ne00; i0++) {
                    write_elem_xlns16(d_row, i0, dst->type, xlns16_div(row[i0], sum));
                }
            }
        }
    }
}

// ============================================================
// RMS_NORM: dst = x / sqrt(mean(x^2) + eps)
// ============================================================

void lns_rms_norm(struct ggml_tensor * dst) {
    const struct ggml_tensor * src0 = dst->src[0];

    float eps;
    memcpy(&eps, dst->op_params, sizeof(float));

    const int64_t ne00 = src0->ne[0];
    const int64_t ne01 = src0->ne[1];
    const int64_t ne02 = src0->ne[2];
    const int64_t ne03 = src0->ne[3];

    for (int64_t i3 = 0; i3 < ne03; i3++) {
        for (int64_t i2 = 0; i2 < ne02; i2++) {
            for (int64_t i1 = 0; i1 < ne01; i1++) {
                const void * s = (const char *)src0->data
                    + i1*src0->nb[1] + i2*src0->nb[2] + i3*src0->nb[3];
                void * d = (char *)dst->data
                    + i1*dst->nb[1] + i2*dst->nb[2] + i3*dst->nb[3];

                // sum of squares in xlns16
                xlns16 sum_sq = fp2xlns16(0.0f);
                for (int64_t i0 = 0; i0 < ne00; i0++) {
                    xlns16 x = read_elem_xlns16(s, i0, src0->type);
                    sum_sq = xlns16_add(sum_sq, xlns16_mul(x, x));
                }

                // mean = sum_sq / n
                xlns16 mean = xlns16_div(sum_sq, fp2xlns16((float)ne00));

                // rms = sqrt(mean + eps)
                xlns16 rms = xlns16_add(mean, fp2xlns16(eps));
                xlns16_float rms_f = float2xlns16_(xlns162fp(rms));
                xlns16_float sqrt_rms = sqrt(rms_f);

                // inv_rms = 1 / sqrt_rms
                xlns16 inv_rms = xlns16_div(fp2xlns16(1.0f), xlns16_internal(sqrt_rms));

                // normalize: d[i] = s[i] * inv_rms
                for (int64_t i0 = 0; i0 < ne00; i0++) {
                    xlns16 x = read_elem_xlns16(s, i0, src0->type);
                    write_elem_xlns16(d, i0, dst->type, xlns16_mul(x, inv_rms));
                }
            }
        }
    }
}

// ============================================================
// DIAG_MASK_INF: causal attention mask
// ============================================================

void lns_diag_mask_inf(struct ggml_tensor * dst) {
    const struct ggml_tensor * src0 = dst->src[0];

    int n_past;
    memcpy(&n_past, dst->op_params, sizeof(int32_t));

    const int64_t nc = src0->ne[0]; // columns
    const int64_t nr = src0->ne[1]; // rows
    const int64_t n  = ggml_nrows(src0);
    const int64_t nz = n / nr;

    const bool inplace = (src0->data == dst->data);
    if (!inplace) {
        // safety: xlns16 is 2 bytes vs F32's 4 bytes — dst buffer was F32-sized, so always fits
        GGML_ASSERT(ggml_nbytes(dst) <= ggml_nbytes(src0));
        memcpy(dst->data, src0->data, ggml_nbytes(dst));
    }

    if (dst->type == GGML_TYPE_LNS16) {
        // Use LNS16_NEG_INF sentinel: fp2xlns16(-INFINITY) is UB (cast of inf to uint16)
        const xlns16 neg_inf = LNS16_NEG_INF;
        xlns16 * data = (xlns16 *)dst->data;
        for (int64_t k = 0; k < nz; k++) {
            for (int64_t j = 0; j < nr; j++) {
                for (int64_t i = n_past + j + 1; i < nc; i++) {
                    data[k*nr*nc + j*nc + i] = neg_inf;
                }
            }
        }
    } else {
        float * data = (float *)dst->data;
        for (int64_t k = 0; k < nz; k++) {
            for (int64_t j = 0; j < nr; j++) {
                for (int64_t i = n_past + j + 1; i < nc; i++) {
                    data[k*nr*nc + j*nc + i] = -INFINITY;
                }
            }
        }
    }
}

// ============================================================
// SILU: dst = x * sigmoid(x)
// ============================================================

void lns_silu(struct ggml_tensor * dst) {
    const struct ggml_tensor * src0 = dst->src[0];
    const int64_t n = ggml_nelements(src0);

    for (int64_t i = 0; i < n; i++) {
        xlns16 v = (src0->type == GGML_TYPE_LNS16)
            ? ((const xlns16 *)src0->data)[i]
            : fp2xlns16(((const float *)src0->data)[i]);
        xlns16 r = xlns16_silu(v);
        if (dst->type == GGML_TYPE_LNS16) {
            ((xlns16 *)dst->data)[i] = r;
        } else {
            ((float *)dst->data)[i] = xlns162fp(r);
        }
    }
}

// ============================================================
// SWIGLU: dst = silu(gate) * up
// ============================================================

void lns_swiglu(struct ggml_tensor * dst) {
    const struct ggml_tensor * src0 = dst->src[0];
    const struct ggml_tensor * src1 = dst->src[1];

    GGML_ASSERT(ggml_is_contiguous_1(src0));
    GGML_ASSERT(ggml_is_contiguous_1(dst));
    GGML_ASSERT(src0->type == GGML_TYPE_F32 || src0->type == GGML_TYPE_LNS16);
    GGML_ASSERT(dst->type  == GGML_TYPE_F32 || dst->type  == GGML_TYPE_LNS16);

    if (src1) {
        GGML_ASSERT(ggml_is_contiguous_1(src1));
        GGML_ASSERT(src1->type == GGML_TYPE_F32 || src1->type == GGML_TYPE_LNS16);
    } else {
        GGML_ASSERT(src0->ne[0] % 2 == 0);
    }

    const int64_t nc = src1 ? src0->ne[0] : src0->ne[0] / 2;
    const int64_t nr = ggml_nrows(src0);

    GGML_ASSERT(dst->ne[0] == nc);
    GGML_ASSERT(ggml_nrows(dst) == nr);
    if (src1) {
        GGML_ASSERT(src1->ne[0] == nc);
        GGML_ASSERT(ggml_nrows(src1) == nr);
    }

    const int32_t swapped = ggml_get_op_params_i32(dst, 1);
    const size_t src0_elem_size = ggml_type_size(src0->type);
    const size_t src1_elem_size = src1 ? ggml_type_size(src1->type) : src0_elem_size;

    const char * src0_data = (const char *)src0->data;
    const char * src1_data = src1 ? (const char *)src1->data : src0_data;
    char * dst_data = (char *)dst->data;

    for (int64_t i1 = 0; i1 < nr; i1++) {
        const char * gate_row = src0_data + i1*src0->nb[1];
        const char * up_row   = src1_data + i1*(src1 ? src1->nb[1] : src0->nb[1]);
        char * dst_row = dst_data + i1*dst->nb[1];

        if (!src1) {
            gate_row += (swapped ? nc : 0) * src0_elem_size;
            up_row   += (swapped ? 0 : nc) * src1_elem_size;
        }

        for (int64_t k = 0; k < nc; k++) {
            const xlns16 gate = read_elem_xlns16(gate_row, k, src0->type);
            const xlns16 up   = read_elem_xlns16(up_row,   k, src1 ? src1->type : src0->type);
            write_elem_xlns16(dst_row, k, dst->type, xlns16_mul(xlns16_silu(gate), up));
        }
    }
}

// ============================================================
// GELU: dst = 0.5*x*(1 + tanh(sqrt(2/pi)*(x + 0.044715*x^3)))
// ============================================================

void lns_gelu(struct ggml_tensor * dst) {
    const struct ggml_tensor * src0 = dst->src[0];
    const int64_t n = ggml_nelements(src0);

    for (int64_t i = 0; i < n; i++) {
        xlns16 v = (src0->type == GGML_TYPE_LNS16)
            ? ((const xlns16 *)src0->data)[i]
            : fp2xlns16(((const float *)src0->data)[i]);
        xlns16 r = xlns16_gelu(v);
        if (dst->type == GGML_TYPE_LNS16) {
            ((xlns16 *)dst->data)[i] = r;
        } else {
            ((float *)dst->data)[i] = xlns162fp(r);
        }
    }
}

// ============================================================
// RELU: dst = max(0, x)
// ============================================================

void lns_relu(struct ggml_tensor * dst) {
    const struct ggml_tensor * src0 = dst->src[0];
    const int64_t n = ggml_nelements(src0);

    for (int64_t i = 0; i < n; i++) {
        xlns16 v = (src0->type == GGML_TYPE_LNS16)
            ? ((const xlns16 *)src0->data)[i]
            : fp2xlns16(((const float *)src0->data)[i]);
        xlns16 r = xlns16_relu(v);
        if (dst->type == GGML_TYPE_LNS16) {
            ((xlns16 *)dst->data)[i] = r;
        } else {
            ((float *)dst->data)[i] = xlns162fp(r);
        }
    }
}

// ============================================================
// GET_ROWS: gather rows from src0 using indices in src1
// ============================================================

void lns_get_rows(struct ggml_tensor * dst) {
    const struct ggml_tensor * src0 = dst->src[0]; // embedding table
    const struct ggml_tensor * src1 = dst->src[1]; // indices (I32)

    const int64_t nc = src0->ne[0]; // embedding dim
    const enum ggml_type type = src0->type;
    const auto * traits = ggml_get_type_traits(type);

    const int64_t nr = ggml_nelements(src1); // number of rows to gather

    std::vector<float> f32_scratch(nc);

    for (int64_t i = 0; i < nr; i++) {
        // Compute multi-dimensional index into src1
        const int64_t ne10 = src1->ne[0];
        const int64_t ne11 = src1->ne[1];
        const int64_t i12 = i / (ne11 * ne10);
        const int64_t i11 = (i - i12*ne11*ne10) / ne10;
        const int64_t i10 = i - i12*ne11*ne10 - i11*ne10;

        // Get row index
        const int32_t row_idx = ((const int32_t *)((const char *)src1->data
            + i10*src1->nb[0] + i11*src1->nb[1] + i12*src1->nb[2]))[0];
        GGML_ASSERT(row_idx >= 0 && row_idx < src0->ne[1]);

        // Source row (embedding table — never LNS16, always a weight type)
        const void * src_row = (const char *)src0->data
            + row_idx*src0->nb[1] + i11*src0->nb[2] + i12*src0->nb[3];

        if (dst->type == GGML_TYPE_LNS16) {
            // Output directly as xlns16: dequantize to F32, then convert
            xlns16 * dst_row = (xlns16 *)((char *)dst->data
                + i10*dst->nb[1] + i11*dst->nb[2] + i12*dst->nb[3]);
            if (type == GGML_TYPE_F32) {
                xlns16_batch_from_float((const float *)src_row, dst_row, (size_t)nc);
            } else {
                GGML_ASSERT(traits->to_float != NULL);
                traits->to_float(src_row, f32_scratch.data(), nc);
                xlns16_batch_from_float(f32_scratch.data(), dst_row, (size_t)nc);
            }
        } else {
            // Output as F32 (original behaviour, for non-LNS mode)
            float * dst_row = (float *)((char *)dst->data
                + i10*dst->nb[1] + i11*dst->nb[2] + i12*dst->nb[3]);
            if (type == GGML_TYPE_F32) {
                memcpy(dst_row, src_row, (size_t)nc * sizeof(float));
            } else {
                GGML_ASSERT(traits->to_float != NULL);
                traits->to_float(src_row, dst_row, nc);
            }
        }
    }
}

// ============================================================
// CPY / CONT / DUP: copy src0 to dst (possibly with type conversion)
// ============================================================

void lns_cpy(struct ggml_tensor * dst) {
    const struct ggml_tensor * src0 = dst->src[0];

    // Same-type contiguous tensors: raw memcpy
    if (src0->type == dst->type && ggml_is_contiguous(src0) && ggml_is_contiguous(dst)) {
        memcpy(dst->data, src0->data, ggml_nbytes(dst));
        return;
    }

    const int64_t ne00 = src0->ne[0];
    const int64_t ne01 = src0->ne[1];
    const int64_t ne02 = src0->ne[2];
    const int64_t ne03 = src0->ne[3];

    // F32 -> F32 (with stride differences)
    if (src0->type == GGML_TYPE_F32 && dst->type == GGML_TYPE_F32) {
        for (int64_t i3 = 0; i3 < ne03; i3++)
            for (int64_t i2 = 0; i2 < ne02; i2++)
                for (int64_t i1 = 0; i1 < ne01; i1++) {
                    const float * s = (const float *)((const char *)src0->data
                        + i1*src0->nb[1] + i2*src0->nb[2] + i3*src0->nb[3]);
                    float * d = (float *)((char *)dst->data
                        + i1*dst->nb[1] + i2*dst->nb[2] + i3*dst->nb[3]);
                    memcpy(d, s, (size_t)ne00 * sizeof(float));
                }
        return;
    }

    // F32 -> F16 (common for KV cache)
    if (src0->type == GGML_TYPE_F32 && dst->type == GGML_TYPE_F16) {
        for (int64_t i3 = 0; i3 < ne03; i3++)
            for (int64_t i2 = 0; i2 < ne02; i2++)
                for (int64_t i1 = 0; i1 < ne01; i1++) {
                    const float * s = (const float *)((const char *)src0->data
                        + i1*src0->nb[1] + i2*src0->nb[2] + i3*src0->nb[3]);
                    ggml_fp16_t * d = (ggml_fp16_t *)((char *)dst->data
                        + i1*dst->nb[1] + i2*dst->nb[2] + i3*dst->nb[3]);
                    for (int64_t i0 = 0; i0 < ne00; i0++) {
                        d[i0] = ggml_fp32_to_fp16(s[i0]);
                    }
                }
        return;
    }

    // LNS16 -> F32 (e.g., output logits conversion)
    if (src0->type == GGML_TYPE_LNS16 && dst->type == GGML_TYPE_F32) {
        for (int64_t i3 = 0; i3 < ne03; i3++)
            for (int64_t i2 = 0; i2 < ne02; i2++)
                for (int64_t i1 = 0; i1 < ne01; i1++) {
                    const xlns16 * s = (const xlns16 *)((const char *)src0->data
                        + i1*src0->nb[1] + i2*src0->nb[2] + i3*src0->nb[3]);
                    float * d = (float *)((char *)dst->data
                        + i1*dst->nb[1] + i2*dst->nb[2] + i3*dst->nb[3]);
                    lns16_to_f32_row(s, d, ne00);
                }
        return;
    }

    // F32 -> LNS16
    if (src0->type == GGML_TYPE_F32 && dst->type == GGML_TYPE_LNS16) {
        for (int64_t i3 = 0; i3 < ne03; i3++)
            for (int64_t i2 = 0; i2 < ne02; i2++)
                for (int64_t i1 = 0; i1 < ne01; i1++) {
                    const float * s = (const float *)((const char *)src0->data
                        + i1*src0->nb[1] + i2*src0->nb[2] + i3*src0->nb[3]);
                    xlns16 * d = (xlns16 *)((char *)dst->data
                        + i1*dst->nb[1] + i2*dst->nb[2] + i3*dst->nb[3]);
                    f32_to_lns16_row(s, d, ne00);
                }
        return;
    }

    // LNS16 -> LNS16 (with stride differences — same-type contiguous handled above)
    if (src0->type == GGML_TYPE_LNS16 && dst->type == GGML_TYPE_LNS16) {
        for (int64_t i3 = 0; i3 < ne03; i3++)
            for (int64_t i2 = 0; i2 < ne02; i2++)
                for (int64_t i1 = 0; i1 < ne01; i1++) {
                    const xlns16 * s = (const xlns16 *)((const char *)src0->data
                        + i1*src0->nb[1] + i2*src0->nb[2] + i3*src0->nb[3]);
                    xlns16 * d = (xlns16 *)((char *)dst->data
                        + i1*dst->nb[1] + i2*dst->nb[2] + i3*dst->nb[3]);
                    memcpy(d, s, (size_t)ne00 * sizeof(xlns16));
                }
        return;
    }

    GGML_ABORT("lns_cpy: unsupported type conversion %s -> %s\n",
               ggml_type_name(src0->type), ggml_type_name(dst->type));
}

// ============================================================
// ROPE: Rotary Position Embeddings
// ============================================================

void lns_rope(struct ggml_tensor * dst) {
    const struct ggml_tensor * src0 = dst->src[0]; // Q or K tensor
    const struct ggml_tensor * src1 = dst->src[1]; // position indices (I32)

    const int64_t ne0 = src0->ne[0]; // head dim
    const int64_t ne1 = src0->ne[1]; // num heads
    const int64_t ne2 = src0->ne[2]; // seq len
    const int64_t ne3 = src0->ne[3]; // batch

    const int32_t n_dims     = ((int32_t *) dst->op_params)[1];
    const int32_t mode       = ((int32_t *) dst->op_params)[2];
    const int32_t n_ctx_orig = ((int32_t *) dst->op_params)[4];

    float freq_base, freq_scale, ext_factor, attn_factor, beta_fast, beta_slow;
    memcpy(&freq_base,   (int32_t *) dst->op_params +  5, sizeof(float));
    memcpy(&freq_scale,  (int32_t *) dst->op_params +  6, sizeof(float));
    memcpy(&ext_factor,  (int32_t *) dst->op_params +  7, sizeof(float));
    memcpy(&attn_factor, (int32_t *) dst->op_params +  8, sizeof(float));
    memcpy(&beta_fast,   (int32_t *) dst->op_params +  9, sizeof(float));
    memcpy(&beta_slow,   (int32_t *) dst->op_params + 10, sizeof(float));

    const bool is_neox = (mode & 2) != 0; // NEOX-style: pairs at distance n_dims/2

    (void)n_ctx_orig; (void)ext_factor; (void)attn_factor;
    (void)beta_fast; (void)beta_slow; (void)freq_scale;

    const float theta_scale = powf(freq_base, -2.0f / n_dims);

    for (int64_t i3 = 0; i3 < ne3; i3++) {
        for (int64_t i2 = 0; i2 < ne2; i2++) {
            const int32_t pos = ((const int32_t *)src1->data)[i2];
            for (int64_t i1 = 0; i1 < ne1; i1++) {
                const void * src_row = (const char *)src0->data
                    + i1*src0->nb[1] + i2*src0->nb[2] + i3*src0->nb[3];
                void * dst_row = (char *)dst->data
                    + i1*dst->nb[1] + i2*dst->nb[2] + i3*dst->nb[3];

                float t = (float)pos;
                for (int64_t j = 0; j < n_dims; j += 2) {
                    float cos_t = cosf(t);
                    float sin_t = sinf(t);

                    // Convert cos/sin to xlns16 for the rotation
                    xlns16 c     = fp2xlns16(cos_t);
                    xlns16 s_val = fp2xlns16(sin_t);

                    int64_t i0_0, i0_1;
                    if (is_neox) {
                        // NEOX: pairs at (j/2, j/2 + n_dims/2)
                        i0_0 = j / 2;
                        i0_1 = j / 2 + n_dims / 2;
                    } else {
                        // Normal: adjacent pairs (j, j+1)
                        i0_0 = j;
                        i0_1 = j + 1;
                    }

                    xlns16 x0 = read_elem_xlns16(src_row, i0_0, src0->type);
                    xlns16 x1 = read_elem_xlns16(src_row, i0_1, src0->type);

                    // Rotation: [cos -sin; sin cos] * [x0; x1]
                    xlns16 r0 = xlns16_sub(xlns16_mul(x0, c), xlns16_mul(x1, s_val));
                    xlns16 r1 = xlns16_add(xlns16_mul(x0, s_val), xlns16_mul(x1, c));

                    write_elem_xlns16(dst_row, i0_0, dst->type, r0);
                    write_elem_xlns16(dst_row, i0_1, dst->type, r1);

                    t *= theta_scale;
                }

                // Copy non-rotated dimensions (passthrough in xlns16 or F32)
                for (int64_t j = n_dims; j < ne0; j++) {
                    xlns16 v = read_elem_xlns16(src_row, j, src0->type);
                    write_elem_xlns16(dst_row, j, dst->type, v);
                }
            }
        }
    }
}
