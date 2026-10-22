// src/kernels/cuda/fork/fork_weighted_sum.cuh - weighted_rows_sum: the prompt chunk's top-k mix on the card (MiMo prefill).
// Fork code kept out of upstream's iq_kernels.cu (one #include line there) so upstream merges do not conflict
// on it; included at a fixed point of that translation unit and uses its helpers (not a standalone header).
#pragma once

// out[t][i] = sum_k w[t*K + k] * parts[(t*K + k)][i] - the prompt chunk's top-k mix on the card (MiMo prefill), so
// only n rows come back instead of n*K.  Summed in k order, like the host loop it replaces.
__global__ void weighted_rows_sum_kernel(const float* __restrict__ parts, const float* __restrict__ w, int K,
                                         int64_t H, int64_t n, float* __restrict__ out) {
    const int64_t total = n * H;
    for (int64_t q = (int64_t) blockIdx.x * blockDim.x + threadIdx.x; q < total; q += (int64_t) gridDim.x * blockDim.x) {
        const int64_t t = q / H, i = q - t * H;
        float acc = 0.0f;
        for (int k = 0; k < K; ++k) acc += w[t * K + k] * parts[(t * K + k) * H + i];
        out[q] = acc;
    }
}

void weighted_rows_sum(const float* parts, const float* w, int K, int64_t H, int64_t n, float* out, void* stream) {
    const int64_t total = n * H;
    const unsigned blocks = (unsigned) std::min<int64_t>((total + 255) / 256, 65535);
    weighted_rows_sum_kernel<<<blocks, 256, 0, (cudaStream_t) stream>>>(parts, w, K, H, n, out);
    check("weighted_rows_sum");
}

// Decode (one token): out[i] = sum over k of w[k] * parts[k][i], k in routing order, accumulated in DOUBLE and rounded
// once - the host loop it replaces (ds41_moe gpu_run) bit for bit: a float x float product is exact in double, so
// fused or not the sum is the same; w[k] == 0 (a dropped miss: its row was never computed) is skipped, as there.
__global__ void decode_rows_sum_kernel(const float* __restrict__ parts, const float* __restrict__ w, int K, int64_t H,
                                       float* __restrict__ out) {
    for (int64_t i = (int64_t) blockIdx.x * blockDim.x + threadIdx.x; i < H; i += (int64_t) gridDim.x * blockDim.x) {
        double s = 0.0;
        for (int k = 0; k < K; ++k) {
            const float wk = w[k];
            if (wk == 0.0f) continue;
            s = __dadd_rn(s, __dmul_rn((double) wk, (double) parts[(int64_t) k * H + i]));
        }
        out[i] = (float) s;
    }
}

// STRATA_DEFER (multi-row): out[i] += sum over k of w[k] * parts[k][i] - the previous layer's deferred experts of one
// token added to that token's routed sum (decode_rows_sum has already written it)
__global__ void decode_rows_add_kernel(const float* __restrict__ parts, const float* __restrict__ w, int K, int64_t H,
                                       float* __restrict__ out) {
    for (int64_t i = (int64_t) blockIdx.x * blockDim.x + threadIdx.x; i < H; i += (int64_t) gridDim.x * blockDim.x) {
        double s = (double) out[i];
        for (int k = 0; k < K; ++k) {
            const float wk = w[k];
            if (wk == 0.0f) continue;
            s = __dadd_rn(s, __dmul_rn((double) wk, (double) parts[(int64_t) k * H + i]));
        }
        out[i] = (float) s;
    }
}

void decode_rows_add(const float* parts, const float* w, int K, int64_t H, float* out, void* stream) {
    const unsigned blocks = (unsigned) std::min<int64_t>((H + 255) / 256, 1024);
    decode_rows_add_kernel<<<blocks, 256, 0, (cudaStream_t) stream>>>(parts, w, K, H, out);
    check("decode_rows_add");
}

void decode_rows_sum(const float* parts, const float* w, int K, int64_t H, float* out, void* stream) {
    const unsigned blocks = (unsigned) std::min<int64_t>((H + 255) / 256, 1024);
    decode_rows_sum_kernel<<<blocks, 256, 0, (cudaStream_t) stream>>>(parts, w, K, H, out);
    check("decode_rows_sum");
}
