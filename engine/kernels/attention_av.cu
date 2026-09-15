#include <cuda_runtime.h>

#include "kernels.cuh"
#include "llm/cuda_check.h"
#include "llm/kernels.h"

namespace llm {
namespace {

// probs * V. Mirror image of attention_qk: the probability row is reused across
// every column of head_dim, and the V reads -- the other half of the KV cache
// traffic -- are the bandwidth cost that matters.
//
// One block per (head, query), one thread per output column, accumulating
// across keys. Each thread walks V down the key axis; consecutive threads read
// consecutive columns of the same V row, so the access is coalesced even though
// the loop is over keys.
__global__ void attention_av_kernel(const float* __restrict__ probs, const float* __restrict__ v,
                                    float* __restrict__ out, int n_query, int n_keys, int n_heads,
                                    int n_kv_heads, int head_dim) {
  const int query = blockIdx.x;
  const int head = blockIdx.y;
  const int kv_head = head / (n_heads / n_kv_heads);

  const float* prob_row = probs + (static_cast<std::size_t>(head) * n_query + query) * n_keys;
  float* out_row = out + (static_cast<std::size_t>(query) * n_heads + head) * head_dim;

  for (int d = threadIdx.x; d < head_dim; d += blockDim.x) {
    // Masked keys carry probability exactly 0 out of the softmax, so this walks
    // every key with no causal test of its own. Consecutive threads hold
    // consecutive d, so each step of the loop is one coalesced read of a V row;
    // prob_row[j] is the same address for the whole block and broadcasts.
    float acc = 0.0f;
    for (int key = 0; key < n_keys; ++key) {
      acc += prob_row[key] *
             v[(static_cast<std::size_t>(key) * n_kv_heads + kv_head) * head_dim + d];
    }
    out_row[d] = acc;
  }
}

}  // namespace

void launch_attention_av(const float* probs, const float* v, float* out, int n_query, int n_keys,
                         int n_heads, int n_kv_heads, int head_dim, void* stream) {
  if (n_query == 0 || n_keys == 0 || n_heads == 0) return;
  const dim3 grid(n_query, n_heads);
  const int block = head_dim <= kDefaultBlockSize ? head_dim : kDefaultBlockSize;
  attention_av_kernel<<<grid, block, 0, static_cast<cudaStream_t>(stream)>>>(
      probs, v, out, n_query, n_keys, n_heads, n_kv_heads, head_dim);
  LLM_CUDA_CHECK(cudaGetLastError());
}

}  // namespace llm
