#include <algorithm>
#include <cmath>
#include "../../../include/common/benign_runtime.cuh"

// Benign standalone CUDA workload with fixed-size deterministic work only.

__global__ void dgemm_tiled_kernel(const uint32_t* input, uint32_t* output, uint32_t* checksum, size_t n, size_t span) {
    size_t tid = blockIdx.x * blockDim.x + threadIdx.x;
    if (tid >= n) return;
    uint32_t x = input[tid];
    uint32_t y = input[(tid * 41u + 345u) % span];
    uint32_t z = static_cast<uint32_t>(tid) ^ 0x9e3779b9u;
    __shared__ uint32_t a[256]; int lane=threadIdx.x&255; a[lane]=x; __syncthreads(); double acc=0.0; for(int k=0;k<24;k++){ acc+=double(a[(lane+k)&255]&1023u)*double(y&1023u); } x=uint32_t(acc)^z;
    output[tid] = x;
    atomicAdd(checksum, x ^ z ^ static_cast<uint32_t>(1549107668u));
}

int main(int argc, char** argv) {
    BenignOptions options;
    if (!parse_benign_args(argc, argv, options)) {
        print_benign_usage(argv[0]);
        return 1;
    }

    size_t n = (options.size * options.size);
    n = std::max<size_t>(n, static_cast<size_t>(options.cli.blocks) * static_cast<size_t>(options.cli.threads));
    size_t span = std::max<size_t>(n, 1024);

    uint32_t* d_input = nullptr;
    uint32_t* d_output = nullptr;
    uint32_t* d_checksum = nullptr;
    CUDA_CHECK(cudaMalloc(reinterpret_cast<void**>(&d_input), sizeof(uint32_t) * span));
    CUDA_CHECK(cudaMalloc(reinterpret_cast<void**>(&d_output), sizeof(uint32_t) * n));
    CUDA_CHECK(cudaMalloc(reinterpret_cast<void**>(&d_checksum), sizeof(uint32_t)));
    CUDA_CHECK(cudaMemset(d_checksum, 0, sizeof(uint32_t)));
    CUDA_CHECK(cudaMemset(d_output, 0, sizeof(uint32_t) * n));

    int init_blocks = static_cast<int>((span + options.cli.threads - 1) / options.cli.threads);
    benign_init_u32<<<init_blocks, options.cli.threads>>>(d_input, span, options.cli.seed + 1549107668u);
    CUDA_CHECK(cudaGetLastError());
    CUDA_CHECK(cudaDeviceSynchronize());

    auto start = std::chrono::steady_clock::now();
    auto end_time = start + std::chrono::seconds(options.cli.runtime_seconds);
    uint64_t total_launches = 0;
    uint64_t total_elements = 0;

    while (std::chrono::steady_clock::now() < end_time) {
        dgemm_tiled_kernel<<<options.cli.blocks, options.cli.threads>>>(d_input, d_output, d_checksum, n, span);
        CUDA_CHECK(cudaGetLastError());
        total_launches++;
        total_elements += n;
        if (options.cli.sync_every > 0 && total_launches % options.cli.sync_every == 0) {
            CUDA_CHECK(cudaDeviceSynchronize());
        }
    }
    CUDA_CHECK(cudaDeviceSynchronize());

    uint32_t h_checksum = 0;
    CUDA_CHECK(cudaMemcpy(&h_checksum, d_checksum, sizeof(uint32_t), cudaMemcpyDeviceToHost));
    print_benign_summary("hpc", "dgemm_tiled", options, total_launches, total_elements, h_checksum);

    CUDA_CHECK(cudaFree(d_input));
    CUDA_CHECK(cudaFree(d_output));
    CUDA_CHECK(cudaFree(d_checksum));
    return 0;
}
