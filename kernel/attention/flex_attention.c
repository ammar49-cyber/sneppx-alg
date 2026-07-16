#ifdef SNEPPX_HAS_CUDA
#include "../../include/neural_core/architecture/advanced_arch.h"
#include <cuda_runtime.h>
#include <cublas_v2.h>
#include <stdlib.h>
#include <string.h>
#include <math.h>

// ============================================================================
// FlexAttention: Block-sparse attention with mask modulation
// ============================================================================

int sneppx_flex_attn_forward(const float* q, const float* k, const float* v,
                              float* output, const SNEPPX_FlexAttnMask* mask,
                              int batch, int heads, int dim, float scale) {
    if (!q || !k || !v || !output || !mask) return -1;
    int seq = mask->seq_len;
    int bs = mask->block_size;
    int nb = (seq + bs - 1) / bs;
    cublasHandle_t h; cublasCreate(&h);
    float one = 1.0f, zero = 0.0f;
    float* scores; cudaMalloc(&scores, bs * bs * sizeof(float));
    for (int b = 0; b < batch; b++) {
        for (int hd = 0; hd < heads; hd++) {
            float* out_head = output + ((b * heads + hd) * seq) * dim;
            for (int qi = 0; qi < nb; qi++) {
                for (int kj = 0; kj < nb; kj++) {
                    if (mask->block_mask[qi * nb + kj]) {
                        int q_off = (b * heads + hd) * seq * dim + qi * bs * dim;
                        int k_off = (b * heads + hd) * seq * dim + kj * bs * dim;
                        cublasSgemm(h, CUBLAS_OP_T, CUBLAS_OP_N, bs, bs, dim,
                                    &scale, k + k_off, dim, q + q_off, dim,
                                    &zero, scores, bs);
                        // Apply mask modulation function
                        if (mask->modulate_fn) {
                            for (int i = 0; i < bs && qi * bs + i < seq; i++) {
                                int q_idx = qi * bs + i;
                                for (int j = 0; j < bs && kj * bs + j < seq; j++) {
                                    int kv_idx = kj * bs + j;
                                    float mod = mask->modulate_fn(q_idx, kv_idx, hd, mask->mod_ctx);
                                    scores[i * bs + j] += mod;
                                }
                            }
                        }
                        // Softmax and V accumulation
                        float* vs = scores;
                        for (int i = 0; i < bs; i++) {
                            float maxv = -1e30f, sum = 0.0f;
                            for (int j = 0; j < bs; j++) {
                                if (vs[i * bs + j] > maxv) maxv = vs[i * bs + j];
                            }
                            for (int j = 0; j < bs; j++) {
                                vs[i * bs + j] = expf(vs[i * bs + j] - maxv);
                                sum += vs[i * bs + j];
                            }
                            if (sum > 0) for (int j = 0; j < bs; j++) vs[i * bs + j] /= sum;
                        }
                        int v_off = (b * heads + hd) * seq * dim + kj * bs * dim;
                        cublasSgemm(h, CUBLAS_OP_N, CUBLAS_OP_N, dim, bs, bs,
                                    &one, v + v_off, dim, scores, bs,
                                    &one, out_head + qi * bs * dim, dim);
                    }
                }
            }
        }
    }
    cublasDestroy(h);
    cudaFree(scores);
    return 0;
}

// ============================================================================
// Multi-modal Cross-Attention (Text as Q, Vision as KV)
// ============================================================================

int sneppx_multimodal_cross_attn(const float* text_q, const float* vision_k,
                                  const float* vision_v, float* output,
                                  int text_len, int vision_len, int heads, int dim) {
    if (!text_q || !vision_k || !vision_v || !output) return -1;
    cublasHandle_t h; cublasCreate(&h);
    float scale = 1.0f / sqrtf(dim / heads);
    float one = 1.0f, zero = 0.0f;
    int head_dim = dim / heads;
    float* scores; cudaMalloc(&scores, heads * text_len * vision_len * sizeof(float));
    for (int hd = 0; hd < heads; hd++) {
        cublasSgemm(h, CUBLAS_OP_T, CUBLAS_OP_N, vision_len, text_len, head_dim,
                    &scale, vision_k + hd * vision_len * head_dim, head_dim,
                    text_q + hd * text_len * head_dim, head_dim,
                    &zero, scores + hd * text_len * vision_len, vision_len);
    }
    for (int b = 0; b < heads; b++) {
        for (int t = 0; t < text_len; t++) {
            float maxv = -1e30f, sum = 0.0f;
            for (int v = 0; v < vision_len; v++) {
                float s = scores[(b * text_len + t) * vision_len + v];
                if (s > maxv) maxv = s;
            }
            for (int v = 0; v < vision_len; v++) {
                float s = scores[(b * text_len + t) * vision_len + v];
                s = expf(s - maxv); sum += s;
                scores[(b * text_len + t) * vision_len + v] = s;
            }
            if (sum > 0) for (int v = 0; v < vision_len; v++)
                scores[(b * text_len + t) * vision_len + v] /= sum;
        }
    }
    for (int hd = 0; hd < heads; hd++) {
        cublasSgemm(h, CUBLAS_OP_N, CUBLAS_OP_N, head_dim, text_len, vision_len,
                    &one, vision_v + hd * vision_len * head_dim, head_dim,
                    scores + hd * text_len * vision_len, vision_len,
                    &zero, output + hd * text_len * head_dim, head_dim);
    }
    cublasDestroy(h);
    cudaFree(scores);
    return 0;
}

// ============================================================================
// Mixture of Depth (token-level routing, skipping computation)
// ============================================================================

int sneppx_mixture_of_depth(const float* x, float* output,
                             const float* router_weights,
                             int* selected_indices,
                             int batch, int seq, int dim,
                             int num_experts, int top_k) {
    if (!x || !output || !router_weights || !selected_indices) return -1;
    int total = batch * seq;
    cublasHandle_t h; cublasCreate(&h);
    float one = 1.0f, zero = 0.0f;
    // For each token, select top-k experts (routing)
    // Apply selected experts to corresponding tokens
    // Expert computation (simplified: just copy)
    for (int t = 0; t < total; t++) {
        for (int e = 0; e < top_k; e++) {
            int expert = selected_indices[t * top_k + e];
            float weight = router_weights[t * num_experts + expert];
            for (int d = 0; d < dim; d++) {
                output[t * dim + d] += weight * x[t * dim + d];
            }
        }
    }
    cublasDestroy(h);
    return 0;
}

// ============================================================================
// Gated Activations: SwiGLU = SiLU(x) * gate, GeGLU = GELU(x) * gate, ReGLU = ReLU(x) * gate
// ============================================================================

int sneppx_gated_activation_forward(const float* x, const float* gate,
                                     float* output, SNEPPX_GatedActType act,
                                     int numel) {
    if (!x || !gate || !output) return -1;
    for (int i = 0; i < numel; i++) {
        float xv = x[i], gv = gate[i];
        float act_val;
        switch (act) {
            case SNEPPX_GATED_SWIGLU:
                act_val = xv / (1.0f + expf(-xv));  // SiLU
                break;
            case SNEPPX_GATED_GEGLU: {
                float c = 0.7978845608028654f;
                float x3 = xv * xv * xv;
                act_val = 0.5f * xv * (1.0f + tanhf(c * (xv + 0.044715f * x3)));
                break;
            }
            case SNEPPX_GATED_REGLU:
                act_val = fmaxf(0.0f, xv);
                break;
            default:
                act_val = xv;
        }
        output[i] = act_val * gv;
    }
    return 0;
}

// ============================================================================
// YaRN NTK-Aware RoPE Scaling
// ============================================================================

int sneppx_yarn_rope_forward(const float* x, float* output,
                              const float* cos_cache, const float* sin_cache,
                              int batch, int seq, int heads, int dim,
                              float scale, float alpha, float beta) {
    if (!x || !output || !cos_cache || !sin_cache) return -1;
    int half_dim = dim / 2;
    for (int b = 0; b < batch; b++) {
        for (int s = 0; s < seq; s++) {
            for (int h = 0; h < heads; h++) {
                int base = ((b * heads + h) * seq + s) * dim;
                for (int d = 0; d < half_dim; d++) {
                    float x0 = x[base + 2 * d];
                    float x1 = x[base + 2 * d + 1];
                    float cos_v = cos_cache[s * half_dim + d];
                    float sin_v = sin_cache[s * half_dim + d];
                    // YaRN: interpolation + NTK-aware scaling
                    float t = (float)s / (float)seq;
                    float ram = (1.0f - t) * alpha + t * beta;
                    float cos_scaled = cosf(ram * acosf(cos_v));
                    float sin_scaled = sinf(ram * asinf(sin_v));
                    output[base + 2 * d] = x0 * cos_scaled - x1 * sin_scaled;
                    output[base + 2 * d + 1] = x0 * sin_scaled + x1 * cos_scaled;
                }
            }
        }
    }
    return 0;
}

int sneppx_yarn_precompute_cache(float* cos, float* sin,
                                  int max_seq, int dim, float base,
                                  float scale, float alpha, float beta) {
    if (!cos || !sin) return -1;
    int half_dim = dim / 2;
    for (int pos = 0; pos < max_seq; pos++) {
        for (int d = 0; d < half_dim; d++) {
            float theta = pos / powf(base, 2.0f * d / dim);
            cos[pos * half_dim + d] = cosf(theta);
            sin[pos * half_dim + d] = sinf(theta);
        }
    }
    return 0;
}

// ============================================================================
// ALiBi Position Encoding
// ============================================================================

int sneppx_alibi_forward(float* attn_scores, int batch, int heads,
                          int seq_q, int seq_k, float slope_base) {
    if (!attn_scores) return -1;
    for (int h = 0; h < heads; h++) {
        float slope = 1.0f / powf(slope_base, h + 1);
        for (int b = 0; b < batch; b++) {
            for (int qi = 0; qi < seq_q; qi++) {
                for (int kj = 0; kj < seq_k; kj++) {
                    int idx = ((b * heads + h) * seq_q + qi) * seq_k + kj;
                    attn_scores[idx] += slope * (kj - qi);
                }
            }
        }
    }
    return 0;
}
#endif