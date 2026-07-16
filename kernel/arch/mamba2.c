#ifdef SNEPPX_HAS_CUDA
#include "../../include/neural_core/architecture/advanced_arch.h"
#include <cuda_runtime.h>
#include <cublas_v2.h>
#include <stdlib.h>
#include <string.h>
#include <math.h>

// ============================================================================
// Mamba-2: Selective State Space Model
// torch.nn.Conv1d + selective scan with discretized SSM
// ============================================================================

struct SNEPPX_Mamba2Block {
    float *in_proj, *conv1d, *out_proj, *A_log, *D;
    int dim, d_state, d_conv;
    int use_fp32;
};

int sneppx_mamba2_init(SNEPPX_Mamba2Block** mb, int dim, int d_state, int d_conv) {
    if (!mb) return -1;
    SNEPPX_Mamba2Block* m = (SNEPPX_Mamba2Block*)calloc(1, sizeof(SNEPPX_Mamba2Block));
    if (!m) return -1;
    m->dim = dim; m->d_state = d_state; m->d_conv = d_conv; m->use_fp32 = 1;
    size_t proj_size = (size_t)dim * (dim + 2 * d_state) * sizeof(float);
    cudaMalloc(&m->in_proj, proj_size);
    cudaMalloc(&m->conv1d, (size_t)d_conv * dim * sizeof(float));
    cudaMalloc(&m->out_proj, (size_t)dim * dim * sizeof(float));
    cudaMalloc(&m->A_log, (size_t)dim * d_state * sizeof(float));
    cudaMalloc(&m->D, (size_t)dim * sizeof(float));
    // Initialize A_log (HiPPO-like)
    float* h_A = (float*)malloc(dim * d_state * sizeof(float));
    for (int d = 0; d < dim; d++)
        for (int s = 0; s < d_state; s++)
            h_A[d * d_state + s] = logf(1.0f);  // A = 1.0
    cudaMemcpy(m->A_log, h_A, dim * d_state * sizeof(float), cudaMemcpyHostToDevice);
    free(h_A);
    float* h_D = (float*)malloc(dim * sizeof(float));
    for (int d = 0; d < dim; d++) h_D[d] = 1.0f;
    cudaMemcpy(m->D, h_D, dim * sizeof(float), cudaMemcpyHostToDevice);
    free(h_D);
    *mb = m;
    return 0;
}

// Mamba-2 forward:
// 1. Linear projection: x -> z, x', B, C
// 2. 1D convolution over x'
// 3. Selective scan: h = A_bar * h + B_bar * x'
// 4. y = C * h + D * x'
// 5. Output: y * SiLU(z)
int sneppx_mamba2_forward(SNEPPX_Mamba2Block* mb, const float* x,
                           float* output, int batch, int seq_len) {
    if (!mb || !x || !output) return -1;
    int m = batch * seq_len;
    int total_dim = mb->dim + 2 * mb->d_state;
    cublasHandle_t h; cublasCreate(&h);
    float one = 1.0f, zero = 0.0f;
    // Step 1: Input projection
    float* proj_out; cudaMalloc(&proj_out, m * total_dim * sizeof(float));
    cublasSgemm(h, CUBLAS_OP_N, CUBLAS_OP_N, total_dim, m, mb->dim,
                &one, mb->in_proj, total_dim, x, mb->dim, &zero, proj_out, total_dim);
    // Split: z = proj_out[0:dim], x_proj = proj_out[dim:dim+d_state*2], 
    // B = proj_out[dim:dim+d_state], C = proj_out[dim+d_state:dim+2*d_state]
    float *z = proj_out, *x_proj = proj_out + mb->dim, *B = x_proj, *C = x_proj + mb->d_state;
    // Step 2: 1D convolution (simplified - just copy)
    float* x_conv; cudaMalloc(&x_conv, m * sizeof(float));
    cudaMemcpy(x_conv, x_proj, m * sizeof(float), cudaMemcpyDeviceToDevice);
    // Step 3: Selective scan
    float* h_state; cudaMalloc(&h_state, (size_t)batch * mb->d_state * sizeof(float));
    cudaMemset(h_state, 0, batch * mb->d_state * sizeof(float));
    float* y; cudaMalloc(&y, m * sizeof(float));
    for (int s = 0; s < seq_len; s++) {
        for (int b = 0; b < batch; b++) {
            float dt = expf(proj_out[(b * seq_len + s) * total_dim + mb->dim]);  // delta
            float* A_h = (float*)malloc(mb->d_state * sizeof(float));
            cudaMemcpy(A_h, mb->A_log, mb->d_state * sizeof(float), cudaMemcpyDeviceToHost);
            float acc = 0.0f;
            for (int d = 0; d < mb->d_state; d++) {
                float A = expf(-expf(A_h[d]) * dt);  // discretized A
                float B_val = B[(b * seq_len + s) * mb->d_state + d];
                float x_val = x_conv[(b * seq_len + s)];
                float* h_b = (float*)malloc(batch * mb->d_state * sizeof(float));
                cudaMemcpy(h_b, h_state, batch * mb->d_state * sizeof(float), cudaMemcpyDeviceToHost);
                h_b[b * mb->d_state + d] = A * h_b[b * mb->d_state + d] + B_val * x_val;
                cudaMemcpy(h_state, h_b, batch * mb->d_state * sizeof(float), cudaMemcpyHostToDevice);
                float C_val = C[(b * seq_len + s) * mb->d_state + d];
                acc += C_val * h_b[b * mb->d_state + d];
                free(h_b);
            }
            float D_val; cudaMemcpy(&D_val, mb->D, sizeof(float), cudaMemcpyDeviceToHost);
            acc += D_val * x_conv[(b * seq_len + s)];
            y[(b * seq_len + s)] = acc;
            free(A_h);
        }
    }
    // Step 4: Output gate with SiLU
    for (int i = 0; i < m; i++) {
        float siLU = z[i] / (1.0f + expf(-z[i]));
        output[i] = y[i] * siLU;
    }
    // Step 5: Output projection
    cublasSgemm(h, CUBLAS_OP_N, CUBLAS_OP_N, mb->dim, m, 1,
                &one, mb->out_proj, mb->dim, output, 1, &zero, output, mb->dim);
    cublasDestroy(h);
    cudaFree(proj_out); cudaFree(x_conv); cudaFree(h_state); cudaFree(y);
    return 0;
}

int sneppx_mamba2_destroy(SNEPPX_Mamba2Block* mb) {
    if (!mb) return -1;
    if (mb->in_proj) cudaFree(mb->in_proj); if (mb->conv1d) cudaFree(mb->conv1d);
    if (mb->out_proj) cudaFree(mb->out_proj); if (mb->A_log) cudaFree(mb->A_log);
    if (mb->D) cudaFree(mb->D);
    free(mb);
    return 0;
}
#endif