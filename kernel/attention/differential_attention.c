#ifdef SNEPPX_HAS_CUDA
#include "../../include/neural_core/architecture/advanced_arch.h"
#include <cuda_runtime.h>
#include <cublas_v2.h>
#include <stdlib.h>
#include <string.h>
#include <math.h>

// ============================================================================
// Differential Attention: attn = (QK^T - lambda * rotated_Q * rotated_K^T) / sqrt(d)
// ============================================================================

struct SNEPPX_DifferentialAttn {
    float* q_proj; float* k_proj; float* v_proj; float* o_proj;
    float lambda_q, lambda_k;
    int heads, dim, head_dim;
};

int sneppx_diff_attn_init(SNEPPX_DifferentialAttn** da, int heads, int dim) {
    if (!da) return -1;
    SNEPPX_DifferentialAttn* d = (SNEPPX_DifferentialAttn*)calloc(1, sizeof(SNEPPX_DifferentialAttn));
    if (!d) return -1;
    d->heads = heads; d->dim = dim; d->head_dim = dim / heads;
    d->lambda_q = 0.9f; d->lambda_k = 0.9f;
    size_t proj_size = (size_t)dim * heads * d->head_dim * sizeof(float);
    cudaMalloc(&d->q_proj, proj_size); cudaMalloc(&d->k_proj, proj_size);
    cudaMalloc(&d->v_proj, proj_size); cudaMalloc(&d->o_proj, proj_size);
    *da = d;
    return 0;
}

int sneppx_diff_attn_forward(SNEPPX_DifferentialAttn* da, const float* x,
                              float* output, int batch, int seq_len) {
    if (!da || !x || !output) return -1;
    int M = batch * seq_len, N = da->heads * da->head_dim;
    float* q; cudaMalloc(&q, M * N * sizeof(float));
    float* k; cudaMalloc(&k, M * N * sizeof(float));
    float* v; cudaMalloc(&v, M * N * sizeof(float));
    // QKV projection (simplified - assumes weights are identity)
    cudaMemcpy(q, x, M * N * sizeof(float), cudaMemcpyDeviceToDevice);
    cudaMemcpy(k, x, M * N * sizeof(float), cudaMemcpyDeviceToDevice);
    cudaMemcpy(v, x, M * N * sizeof(float), cudaMemcpyDeviceToDevice);
    // Differential scores = Q*K^T - lambda * Q_rot * K_rot^T
    // For now: standard attention with diff scale (full impl needs rotation)
    float* scores; cudaMalloc(&scores, M * seq_len * sizeof(float));
    cublasHandle_t h; cublasCreate(&h);
    float alpha = 1.0f / sqrtf(da->head_dim), beta = 0.0f, one = 1.0f;
    cublasSgemmStridedBatched(h, CUBLAS_OP_T, CUBLAS_OP_N, seq_len, seq_len, da->head_dim,
        &alpha, k, da->head_dim, seq_len * da->head_dim, q, da->head_dim, seq_len * da->head_dim,
        &beta, scores, seq_len, seq_len * seq_len, da->heads * batch);
    // Softmax
    for (int i = 0; i < M; i++) {
        float maxv = -1e30f, sum = 0.0f;
        for (int j = 0; j < seq_len; j++) {
            if (scores[i * seq_len + j] > maxv) maxv = scores[i * seq_len + j];
        }
        for (int j = 0; j < seq_len; j++) {
            scores[i * seq_len + j] = expf(scores[i * seq_len + j] - maxv);
            sum += scores[i * seq_len + j];
        }
        if (sum > 0) for (int j = 0; j < seq_len; j++) scores[i * seq_len + j] /= sum;
    }
    cublasSgemmStridedBatched(h, CUBLAS_OP_N, CUBLAS_OP_N, da->head_dim, seq_len, seq_len,
        &one, v, da->head_dim, seq_len * da->head_dim, scores, seq_len, seq_len * seq_len,
        &beta, output, da->head_dim, seq_len * da->head_dim, da->heads * batch);
    cublasDestroy(h);
    cudaFree(q); cudaFree(k); cudaFree(v); cudaFree(scores);
    return 0;
}

int sneppx_diff_attn_destroy(SNEPPX_DifferentialAttn* da) {
    if (!da) return -1;
    if (da->q_proj) cudaFree(da->q_proj); if (da->k_proj) cudaFree(da->k_proj);
    if (da->v_proj) cudaFree(da->v_proj); if (da->o_proj) cudaFree(da->o_proj);
    free(da);
    return 0;
}

// ============================================================================
// Latent Attention (DeepSeek MLA)
// ============================================================================

struct SNEPPX_LatentAttn {
    float *w_kv, *w_q, *w_o, *w_kv_proj;
    int heads, kv_heads, dim, head_dim;
    int use_rope;
};

int sneppx_latent_attn_init(SNEPPX_LatentAttn** la, int heads, int kv_heads, int dim) {
    if (!la) return -1;
    SNEPPX_LatentAttn* l = (SNEPPX_LatentAttn*)calloc(1, sizeof(SNEPPX_LatentAttn));
    if (!l) return -1;
    l->heads = heads; l->kv_heads = kv_heads; l->dim = dim; l->head_dim = dim / heads;
    l->use_rope = 1;
    size_t kv_size = (size_t)dim * (kv_heads + 1) * l->head_dim * sizeof(float);
    size_t q_size = (size_t)dim * heads * l->head_dim * sizeof(float);
    cudaMalloc(&l->w_kv, kv_size); cudaMalloc(&l->w_q, q_size);
    cudaMalloc(&l->w_o, q_size); cudaMalloc(&l->w_kv_proj, kv_size);
    *la = l;
    return 0;
}

int sneppx_latent_attn_forward(SNEPPX_LatentAttn* la, const float* x,
                                float* output, int batch, int seq_len) {
    if (!la || !x || !output) return -1;
    // MLA: Q with absorbed RoPE, KV via latent compressed representation
    // Full implementation requires fused kernel with 4x GEMM reduction
    // Simplified: standard MHA with GQA for now
    int m = batch * seq_len;
    cublasHandle_t h; cublasCreate(&h);
    float one = 1.0f, zero = 0.0f, scale = 1.0f / sqrtf(la->head_dim);
    float *q, *k, *v;
    cudaMalloc(&q, m * la->heads * la->head_dim * sizeof(float));
    cudaMalloc(&k, m * la->kv_heads * la->head_dim * sizeof(float));
    cudaMalloc(&v, m * la->kv_heads * la->head_dim * sizeof(float));
    cublasSgemm(h, CUBLAS_OP_N, CUBLAS_OP_N, la->heads * la->head_dim, m, la->dim,
                &one, la->w_q, la->heads * la->head_dim, x, la->dim, &zero, q, la->heads * la->head_dim);
    cublasSgemm(h, CUBLAS_OP_N, CUBLAS_OP_N, la->kv_heads * la->head_dim, m, la->dim,
                &one, la->w_kv, la->kv_heads * la->head_dim, x, la->dim, &zero, k, la->kv_heads * la->head_dim);
    cudaMemcpy(v, k, m * la->kv_heads * la->head_dim * sizeof(float), cudaMemcpyDeviceToDevice);
    // GQA forward
    int g = la->heads / la->kv_heads;
    for (int h = 0; h < la->heads; h++) {
        int kv = h / g;
        cublasSgemm(h, CUBLAS_OP_T, CUBLAS_OP_N, seq_len, seq_len, la->head_dim,
                    &scale, k + kv * seq_len * la->head_dim, la->head_dim,
                    q + h * seq_len * la->head_dim, la->head_dim,
                    &zero, output + h * seq_len * seq_len, seq_len);
    }
    cublasDestroy(h);
    cudaFree(q); cudaFree(k); cudaFree(v);
    return 0;
}

int sneppx_latent_attn_destroy(SNEPPX_LatentAttn* la) {
    if (!la) return -1;
    if (la->w_kv) cudaFree(la->w_kv); if (la->w_q) cudaFree(la->w_q);
    if (la->w_o) cudaFree(la->w_o); if (la->w_kv_proj) cudaFree(la->w_kv_proj);
    free(la);
    return 0;
}
#endif