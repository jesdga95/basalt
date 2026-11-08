// src/prefill/moe_mmq.cu - see include/basalt/prefill/moe_mmq.hpp.  llama.cpp's MMQ (ggml-cuda, MIT) lives in
// src/prefill/mmq/; mmq_host.cu supplies the host symbols it references.
#include "basalt/prefill/moe_mmq.hpp"

#include "mmq/mmq.cuh"
#include "mmq/quantize.cuh"

#include <cstdio>
#include <cstdlib>
#include <type_traits>
#include "basalt/log.hpp"

namespace basalt::prefill::mmq {
namespace {

void ck(cudaError_t e, const char* what) {
    if (e != cudaSuccess) {
        basalt::log::error("basalt", "prefill mmq: %s: %s", what, cudaGetErrorString(e));
        std::exit(1);
    }
}

int64_t pad512(int64_t n) { return (n + 511) / 512 * 512; }

// `t` (optional): 16 more bytes (an NVFP4 expert's scale tail) to t_dst
__global__ void copy16_kernel(const uint4* __restrict__ a, int64_t na, const uint4* __restrict__ b, int64_t nb,
                              uint4* __restrict__ ab_dst, const uint4* __restrict__ c, int64_t nc, uint4* __restrict__ c_dst,
                              const uint4* __restrict__ t, uint4* __restrict__ t_dst) {
    const int64_t i = (int64_t) blockIdx.x * blockDim.x + threadIdx.x;
    if (i < na) ab_dst[i] = a[i];
    else if (i < na + nb) ab_dst[i] = b[i - na];
    else if (i < na + nb + nc) c_dst[i - na - nb] = c[i - na - nb];
    else if (i == na + nb + nc && t != nullptr) *t_dst = *t;
}
// copy16_kernel for an MMQ group: blockIdx.y is the expert (first + y)
struct GroupArgs {
    const uint8_t* blob[kGatherGroupMax];
    int64_t up_off, down_off, gu_stride, d_stride;   // in uint4
    int64_t tail_off;                                // in uint4; with tail_dst, the blob's 16-byte scale tail
    uint4* tail_dst;                                 // ... to tail_dst[q] (nullptr: none)
};
__global__ void copy16_group_kernel(GroupArgs ga, int first, int64_t na, int64_t nb, int64_t nc,
                                    uint4* __restrict__ gu_dst, uint4* __restrict__ d_dst) {
    const int q = first + (int) blockIdx.y;
    const uint4* src = (const uint4*) ga.blob[q];
    uint4* ab = gu_dst + (int64_t) q * ga.gu_stride;
    uint4* cd = d_dst + (int64_t) q * ga.d_stride;
    const int64_t i = (int64_t) blockIdx.x * blockDim.x + threadIdx.x;
    if (i < na) ab[i] = src[i];
    else if (i < na + nb) ab[i] = src[ga.up_off + (i - na)];
    else if (i < na + nb + nc) cd[i - na - nb] = src[ga.down_off + (i - na - nb)];
    else if (i == na + nb + nc && ga.tail_dst != nullptr) ga.tail_dst[q] = src[ga.tail_off];
}
__global__ void copy1_kernel(const uint8_t* __restrict__ a, int64_t na, const uint8_t* __restrict__ b, int64_t nb,
                             uint8_t* __restrict__ ab_dst, const uint8_t* __restrict__ c, int64_t nc, uint8_t* __restrict__ c_dst,
                             const uint8_t* __restrict__ t, uint8_t* __restrict__ t_dst) {
    const int64_t i = (int64_t) blockIdx.x * blockDim.x + threadIdx.x;
    if (i < na) ab_dst[i] = a[i];
    else if (i < na + nb) ab_dst[i] = b[i - na];
    else if (i < na + nb + nc) c_dst[i - na - nb] = c[i - na - nb];
    else if (i < na + nb + nc + 16 && t != nullptr) t_dst[i - na - nb - nc] = t[i - na - nb - nc];
}

// Pack blob: gate/up codes [1280][640 B], down codes [2560][160 B], gate/up scales [1280][40] f16, down scales
// [2560][10] f16 (the layout of prefill/kernels.cu's blob_dequant_kernel).  A GGUF Q2_0 block is {f16 d; 16 code
// bytes} with the same 2-bit codes in the same order, so a block is a scale and a 16-byte run of codes.
__global__ void q2_kernel(const uint8_t* __restrict__ blob, uint16_t* __restrict__ gu, uint16_t* __restrict__ dn) {
    constexpr size_t O_D_CODES = (size_t) 1280 * 640, O_GU_SC = O_D_CODES + (size_t) 2560 * 160,
                     O_D_SC = O_GU_SC + (size_t) 1280 * 40 * 2;
    const int64_t i = (int64_t) blockIdx.x * blockDim.x + threadIdx.x;   // one GGUF block
    const int64_t n_gu = 1280LL * 40, n_d = 2560LL * 10;
    const uint8_t* codes;
    const uint16_t* scale;
    uint16_t* out;
    if (i < n_gu) {
        const int64_t row = i / 40, b = i % 40;
        codes = blob + row * 640 + b * 16;
        scale = (const uint16_t*) (blob + O_GU_SC) + row * 40 + b;
        out = gu + i * 9;
    } else if (i < n_gu + n_d) {
        const int64_t j = i - n_gu, row = j / 10, b = j % 10;
        codes = blob + O_D_CODES + row * 160 + b * 16;
        scale = (const uint16_t*) (blob + O_D_SC) + row * 10 + b;
        out = dn + j * 9;
    } else {
        return;
    }
    const uint4 q = *(const uint4*) codes;
    const uint16_t* qh = (const uint16_t*) &q;
    out[0] = *scale;
#pragma unroll
    for (int k = 0; k < 8; ++k) out[1 + k] = qh[k];
}

__global__ void swiglu_kernel(const float* __restrict__ gu, float* __restrict__ h, int64_t rows, int64_t n_ff,
                              bool interleaved, const float4* __restrict__ tail, const int32_t* __restrict__ bounds, int n) {
    const int64_t i = (int64_t) blockIdx.x * blockDim.x + threadIdx.x;
    if (i >= rows * n_ff) return;
    const int64_t r = i / n_ff, k = i % n_ff;
    const float* row = gu + r * 2 * n_ff;
    float g = interleaved ? row[2 * k] : row[k], u = interleaved ? row[2 * k + 1] : row[n_ff + k];
    if (tail == nullptr) {
        h[i] = g / (1.0f + __expf(-g)) * u;
        return;
    }
    // the row's expert: the last q with bounds[q] <= r
    int q = 0;
    while (q + 1 < n && bounds[q + 1] <= r) ++q;
    const float4 s = tail[q];   // {s_gate, s_up, s_down, -}
    g *= s.x;
    u *= s.y;
    h[i] = g / (1.0f + __expf(-g)) * u * s.z;
}

__global__ void iota_kernel(int32_t* dst, int64_t n) {
    const int64_t i = (int64_t) blockIdx.x * blockDim.x + threadIdx.x;
    if (i < n) dst[i] = (int32_t) i;
}

// Word `w` (16 bytes) of row `r` of a gathered q8_1 buffer: the activation blocks lie block-column by block-column, each
// column holding one block of every row, so row r of `dst` takes the blocks of row ids[r] of `src`.
__device__ __forceinline__ void gather_q8_stage(const uint4* __restrict__ src, int64_t src_rows, const int32_t* __restrict__ ids,
                                                uint4* __restrict__ dst, int64_t rows, int64_t r, int64_t w) {
    constexpr int64_t kWords = sizeof(block_q8_1_mmq) / sizeof(uint4);
    const int64_t kb = w / kWords, j = w - kb * kWords;
    dst[(kb * rows + r) * kWords + j] = src[(kb * src_rows + ids[r]) * kWords + j];
}

__global__ void gather_q8_kernel(const uint4* __restrict__ src, int64_t src_rows, const int32_t* __restrict__ ids,
                                 uint4* __restrict__ dst, int64_t rows, int64_t words) {
    const int64_t w = (int64_t) blockIdx.y * blockDim.x + threadIdx.x;
    if (w < words) gather_q8_stage(src, src_rows, ids, dst, rows, blockIdx.x, w);
}

unsigned blocks(int64_t n) { return (unsigned) ((n + 255) / 256); }

// f(std::integral_constant<ggml_type, t>) for a type `supported` names.
template <class F>
void with_type(ggml_type t, F&& f) {
    switch (t) {
        case GGML_TYPE_Q2_0: f(std::integral_constant<ggml_type, GGML_TYPE_Q2_0>{}); break;
        case GGML_TYPE_IQ1_S: f(std::integral_constant<ggml_type, GGML_TYPE_IQ1_S>{}); break;
        case GGML_TYPE_IQ1_M: f(std::integral_constant<ggml_type, GGML_TYPE_IQ1_M>{}); break;
        case GGML_TYPE_IQ2_XXS: f(std::integral_constant<ggml_type, GGML_TYPE_IQ2_XXS>{}); break;
        case GGML_TYPE_IQ2_XS: f(std::integral_constant<ggml_type, GGML_TYPE_IQ2_XS>{}); break;
        case GGML_TYPE_IQ2_S: f(std::integral_constant<ggml_type, GGML_TYPE_IQ2_S>{}); break;
        case GGML_TYPE_IQ3_XXS: f(std::integral_constant<ggml_type, GGML_TYPE_IQ3_XXS>{}); break;
        case GGML_TYPE_IQ3_S: f(std::integral_constant<ggml_type, GGML_TYPE_IQ3_S>{}); break;
        case GGML_TYPE_IQ4_NL: f(std::integral_constant<ggml_type, GGML_TYPE_IQ4_NL>{}); break;
        case GGML_TYPE_IQ4_XS: f(std::integral_constant<ggml_type, GGML_TYPE_IQ4_XS>{}); break;
        case GGML_TYPE_Q8_0: f(std::integral_constant<ggml_type, GGML_TYPE_Q8_0>{}); break;
        case GGML_TYPE_Q5_1: f(std::integral_constant<ggml_type, GGML_TYPE_Q5_1>{}); break;
        case GGML_TYPE_Q5_0: f(std::integral_constant<ggml_type, GGML_TYPE_Q5_0>{}); break;
        case GGML_TYPE_Q2_K: f(std::integral_constant<ggml_type, GGML_TYPE_Q2_K>{}); break;
        case GGML_TYPE_Q3_K: f(std::integral_constant<ggml_type, GGML_TYPE_Q3_K>{}); break;
        case GGML_TYPE_Q4_K: f(std::integral_constant<ggml_type, GGML_TYPE_Q4_K>{}); break;
        case GGML_TYPE_Q5_K: f(std::integral_constant<ggml_type, GGML_TYPE_Q5_K>{}); break;
        case GGML_TYPE_Q6_K: f(std::integral_constant<ggml_type, GGML_TYPE_Q6_K>{}); break;
        case GGML_TYPE_NVFP4: f(std::integral_constant<ggml_type, GGML_TYPE_NVFP4>{}); break;
        default:
            basalt::log::error("basalt", "prefill mmq: type %d is not covered", (int) t);
            std::exit(1);
    }
}

}  // namespace

bool built() { return true; }

bool supported(int t) {
    switch ((ggml_type) t) {
        case GGML_TYPE_Q2_0:
        case GGML_TYPE_IQ1_S: case GGML_TYPE_IQ1_M:
        case GGML_TYPE_IQ2_XXS: case GGML_TYPE_IQ2_XS: case GGML_TYPE_IQ2_S:
        case GGML_TYPE_IQ3_XXS: case GGML_TYPE_IQ3_S: case GGML_TYPE_IQ4_NL: case GGML_TYPE_IQ4_XS:
        case GGML_TYPE_Q8_0:   // the draft layer's dense matrices (E-9)
        case GGML_TYPE_Q4_K: case GGML_TYPE_Q5_K: case GGML_TYPE_Q5_1:   // the UD-Q4_K_XL experts
        case GGML_TYPE_Q5_0:   // the UD packs' down layers that keep 5 bits
        case GGML_TYPE_Q2_K: case GGML_TYPE_Q3_K:   // the UD packs' 2- and 3-bit K-quant layers
        case GGML_TYPE_Q6_K:   // the UD-Q5_K_XL and UD-Q6_K_XL gate/up
        case GGML_TYPE_NVFP4:  // the products leave out the per-expert tail scales (see swiglu)
            return true;
        default:
            return false;
    }
}

bool fits(int t, int64_t w_rows) {
    if (!supported(t)) return false;
    // mul_mat_q_case's choice: the "fallback" configs when the rows are not a multiple of 128; then
    // mul_mat_q_switch_J's loop - a tile size whose config exists for this card and fits its shared memory
    const bool fallback = w_rows % 128 != 0;
    const ggml_cuda_device_info& info = ggml_cuda_info();
    for (int id = 0; id < info.device_count; ++id) {
        const size_t smpbo = info.devices[id].smpbo;
        bool any = false;
        for (int J = 8; J <= 128 && !any; J += 8) {
            const ggml_cuda_mmq_config c = ggml_cuda_mmq_get_config((ggml_type) t, J, fallback);
            any = c.type != GGML_TYPE_COUNT && mmq_get_nbytes_shared(c) <= smpbo;
        }
        if (!any) {
            static bool said[GGML_TYPE_COUNT] = {};
            if (t >= 0 && t < GGML_TYPE_COUNT && !said[t]) {
                said[t] = true;
                basalt::log::warn("basalt", "prompt kernels: llama.cpp's MMQ has no tile for %s (%lld rows) on GPU %d "
                                     "(%zu bytes of shared memory per block): that product takes the non-MMQ path ", ggml_type_name((ggml_type) t), (long long) w_rows, id, smpbo);
            }
            return false;
        }
    }
    return true;
}

size_t matrix_bytes(int t, int64_t rows, int64_t cols) {
    return (size_t) rows * (size_t) (cols / ggml_blck_size((ggml_type) t)) * ggml_type_size((ggml_type) t);
}

size_t gu_slot_bytes(int gate_type, int up_type, int64_t n_ff, int64_t n_embd) {
    if (up_type == gate_type) return matrix_bytes(gate_type, 2 * n_ff, n_embd);
    const size_t a = ggml_type_size((ggml_type) gate_type), b = ggml_type_size((ggml_type) up_type);
    size_t l = a, x = a, y = b;
    while (y != 0) { const size_t t = x % y; x = y; y = t; }
    l = a / x * b;                                    // lcm of the two block sizes
    while (l % 16 != 0) l *= 2;
    const size_t raw = matrix_bytes(gate_type, n_ff, n_embd) + matrix_bytes(up_type, n_ff, n_embd);
    return (raw + l - 1) / l * l;
}

size_t q8_bytes(int64_t rows, int64_t cols) {
    return (size_t) rows * (size_t) pad512(cols) * sizeof(block_q8_1_mmq) / (4 * QK8_1) + 128 * sizeof(block_q8_1_mmq);
}

int64_t q8_blocks(int64_t cols) { return pad512(cols) / (4 * QK8_1); }

void quantize(const float* x, const int32_t* ids, void* xq, int t, int64_t cols, int64_t ld, int64_t rows, void* stream) {
    if (rows <= 0) return;
    quantize_mmq_q8_1_cuda(x, ids, xq, (ggml_type) t, cols, ld, rows * ld, rows * ld, pad512(cols), rows, 1, 1,
                           (cudaStream_t) stream);
    ck(cudaGetLastError(), "quantize");
}

Context::Context() {
    int dev = 0;
    cudaGetDevice(&dev);
    ctx_ = new ggml_backend_cuda_context(dev);
}
Context::~Context() { delete (ggml_backend_cuda_context*) ctx_; }

void Context::run(const Product& p, void* stream) {
    if (p.n <= 0 || p.max_rows <= 0) return;
    const ggml_type t = (ggml_type) p.type;
    const int64_t qk = ggml_blck_size(t), bpr = p.w_cols / qk;
    // the grid always covers max_rows; opt_rows only picks the tile width
    const int64_t opt = p.opt_rows > 0 && p.opt_rows < p.max_rows ? p.opt_rows : p.max_rows;
    const mmq_args a = {(const char*) p.w, t, (const int*) p.xq, p.ids, p.bounds, p.dst,
                        p.w_cols, p.w_rows, p.total_rows, bpr, p.total_rows, p.ld_dst,
                        p.n, p.n, (int64_t) (p.expert_bytes / ggml_type_size(t)), 0, 0,
                        1, 1, 0, 0, 0,
                        p.max_rows, opt};
    auto& ctx = *(ggml_backend_cuda_context*) ctx_;
    const cudaStream_t s = (cudaStream_t) stream;
    with_type(t, [&](auto c) { mul_mat_q_case<decltype(c)::value>(ctx, a, s); });
    ck(cudaGetLastError(), "mul_mat_q");
}

void load(int t, int64_t w_rows) {
    with_type((ggml_type) t, [&](auto c) { mul_mat_q_load<decltype(c)::value>(w_rows); });
}

void gather_native(const void* gate, const void* up, size_t gate_bytes, const void* down, size_t d_bytes,
                   void* gu_dst, void* d_dst, void* stream, const void* tail, void* tail_dst, size_t up_bytes) {
    const cudaStream_t s = (cudaStream_t) stream;
    if (tail_dst == nullptr) tail = nullptr;
    if (up_bytes == 0) up_bytes = gate_bytes;
    const bool a16 = ((uintptr_t) gate | (uintptr_t) up | (uintptr_t) down | (uintptr_t) gu_dst | (uintptr_t) d_dst |
                      (uintptr_t) tail | (uintptr_t) tail_dst | gate_bytes | up_bytes | d_bytes) % 16 == 0;
    if (a16) {
        const int64_t na = (int64_t) gate_bytes / 16, nb = (int64_t) up_bytes / 16, nc = (int64_t) d_bytes / 16;
        copy16_kernel<<<blocks(na + nb + nc + 1), 256, 0, s>>>((const uint4*) gate, na, (const uint4*) up, nb,
                                                               (uint4*) gu_dst, (const uint4*) down, nc, (uint4*) d_dst,
                                                               (const uint4*) tail, (uint4*) tail_dst);
    } else {
        const int64_t na = (int64_t) gate_bytes, nb = (int64_t) up_bytes, nc = (int64_t) d_bytes;
        copy1_kernel<<<blocks(na + nb + nc + 16), 256, 0, s>>>((const uint8_t*) gate, na, (const uint8_t*) up, nb,
                                                              (uint8_t*) gu_dst, (const uint8_t*) down, nc, (uint8_t*) d_dst,
                                                              (const uint8_t*) tail, (uint8_t*) tail_dst);
    }
    ck(cudaGetLastError(), "gather_native");
}

bool gather_native_group(const GatherGroup& g, size_t up_off, size_t gate_bytes, size_t down_off, size_t d_bytes,
                         void* gu_dst, size_t gu_stride, void* d_dst, size_t d_stride, void* stream, size_t tail_off,
                         void* tail_dst, size_t up_bytes) {
    if (g.first < 0 || g.n <= g.first || g.n > kGatherGroupMax) return false;
    if (up_bytes == 0) up_bytes = gate_bytes;
    uintptr_t a = (uintptr_t) gu_dst | (uintptr_t) d_dst | up_off | gate_bytes | up_bytes | down_off | d_bytes | gu_stride |
                  d_stride | tail_off | (uintptr_t) tail_dst;
    for (int q = g.first; q < g.n; ++q) a |= (uintptr_t) g.blob[q];
    if (a % 16 != 0) return false;
    GroupArgs ga{};
    for (int q = g.first; q < g.n; ++q) ga.blob[q] = g.blob[q];
    ga.up_off = (int64_t) up_off / 16;
    ga.down_off = (int64_t) down_off / 16;
    ga.gu_stride = (int64_t) gu_stride / 16;
    ga.d_stride = (int64_t) d_stride / 16;
    ga.tail_off = (int64_t) tail_off / 16;
    ga.tail_dst = (uint4*) tail_dst;
    const int64_t na = (int64_t) gate_bytes / 16, nb = (int64_t) up_bytes / 16, nc = (int64_t) d_bytes / 16;
    copy16_group_kernel<<<dim3(blocks(na + nb + nc + 1), (unsigned) (g.n - g.first)), 256, 0, (cudaStream_t) stream>>>(
        ga, g.first, na, nb, nc, (uint4*) gu_dst, (uint4*) d_dst);
    ck(cudaGetLastError(), "gather_native_group");
    return true;
}

void gather_q2(const uint8_t* blob, void* gu_dst, void* d_dst, void* stream) {
    q2_kernel<<<blocks(1280LL * 40 + 2560LL * 10), 256, 0, (cudaStream_t) stream>>>(blob, (uint16_t*) gu_dst,
                                                                                         (uint16_t*) d_dst);
    ck(cudaGetLastError(), "gather_q2");
}

void swiglu(const float* gu, float* h, int64_t rows, int64_t n_ff, bool interleaved, void* stream, const float* tail,
            const int32_t* bounds, int n) {
    if (rows <= 0) return;
    if (bounds == nullptr || n <= 0) tail = nullptr;
    swiglu_kernel<<<blocks(rows * n_ff), 256, 0, (cudaStream_t) stream>>>(gu, h, rows, n_ff, interleaved,
                                                                           (const float4*) tail, bounds, n);
    ck(cudaGetLastError(), "swiglu");
}

void gather_q8(const void* xq, int64_t src_rows, const int32_t* ids, void* dst, int64_t rows, int64_t cols, void* stream) {
    if (rows <= 0) return;
    static_assert(sizeof(block_q8_1_mmq) % sizeof(uint4) == 0, "q8_1 blocks are whole 16-byte words");
    const int64_t words = pad512(cols) / (4 * QK8_1) * (int64_t) (sizeof(block_q8_1_mmq) / sizeof(uint4));
    gather_q8_kernel<<<dim3((unsigned) rows, (unsigned) ((words + 127) / 128)), 128, 0, (cudaStream_t) stream>>>(
        (const uint4*) xq, src_rows, ids, (uint4*) dst, rows, words);
    ck(cudaGetLastError(), "gather_q8");
}

void iota(int32_t* dst, int64_t n, void* stream) {
    if (n <= 0) return;
    iota_kernel<<<blocks(n), 256, 0, (cudaStream_t) stream>>>(dst, n);
    ck(cudaGetLastError(), "iota");
}

}  // namespace basalt::prefill::mmq
