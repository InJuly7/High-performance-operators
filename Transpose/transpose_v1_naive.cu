#include <iostream>
#include <cuda_runtime.h>

__global__ void transpose_naive(float *input, float *output, const int M, const int N) {
    int x = blockIdx.x * blockDim.x + threadIdx.x;
    int y = blockIdx.y * blockDim.y + threadIdx.y;

    int idx = y * N + x;
    int trans_idx = x * M + y;
    output[trans_idx] = input[idx];
}

int main(int argc, char *argv[]) {
    const int MATRIX_M = 2048;
    const int MATRIX_N = 512;
    const size_t size = MATRIX_M * MATRIX_N;

    float *input_host = (float *)malloc(size * sizeof(float));
    float *output_host_cpu_calc = (float *)malloc(size * sizeof(float));
    float *output_host_gpu_calc = (float *)malloc(size * sizeof(float));

    for (int i = 0; i < size; i++) {
        input_host[i] = 2.0 * (float)drand48() - 1.0;
    }

    transpose_cpu(input_host, output_host_cpu_calc, MATRIX_M, MATRIX_N);
    float *input_device, *output_device;

    cudaMalloc(&input_device, size * sizeof(float));
    cudaMemcpy(input_device, input_host, size * sizeof(float), cudaMemcpyHostToDevice);
    cudaMalloc(&output_device, size * sizeof(float));

    // ==================
    cudaMemset(output_device, 0, size * sizeof(float));
    for (int i = 0; i < 5; i++) {
        Perf perf("transpose_32_8");
        dim3 block_size(32, 8);
        dim3 grid_size((MATRIX_N - 1) / block_size.x + 1, (MATRIX_M - 1) / block_size.y + 1);
        transpose_naive<<<grid_size, block_size>>>(input_device, output_device, MATRIX_M, MATRIX_N);
        cudaDeviceSynchronize();
    }

    cudaMemcpy(output_host_gpu_calc, output_device, size * sizeof(float), cudaMemcpyDeviceToHost);
    if (check(output_host_cpu_calc, output_host_gpu_calc, MATRIX_M, MATRIX_N)) {
        std::cout << "right!" << std::endl;
    }

    // ==================
    cudaMemset(output_device, 0, size * sizeof(float));
    for (int i = 0; i < 5; i++) {
        Perf perf("transpose_16_16");
        dim3 block_size(16, 16);
        dim3 grid_size((MATRIX_N - 1) / block_size.x + 1, (MATRIX_M - 1) / block_size.y + 1);
        transpose_naive<<<grid_size, block_size>>>(input_device, output_device, MATRIX_M, MATRIX_N);
        cudaDeviceSynchronize();
    }

    cudaMemcpy(output_host_gpu_calc, output_device, size * sizeof(float), cudaMemcpyDeviceToHost);
    if (check(output_host_cpu_calc, output_host_gpu_calc, MATRIX_M, MATRIX_N)) {
        std::cout << "right!" << std::endl;
    }

    // ==================
    cudaMemset(output_device, 0, size * sizeof(float));
    for (int i = 0; i < 5; i++) {
        Perf perf("transpose_8_32");
        dim3 block_size(8, 32);
        dim3 grid_size((MATRIX_N - 1) / block_size.x + 1, (MATRIX_M - 1) / block_size.y + 1);
        transpose_naive<<<grid_size, block_size>>>(input_device, output_device, MATRIX_M, MATRIX_N);
        cudaDeviceSynchronize();
    }

    cudaMemcpy(output_host_gpu_calc, output_device, size * sizeof(float), cudaMemcpyDeviceToHost);
    if (check(output_host_cpu_calc, output_host_gpu_calc, MATRIX_M, MATRIX_N)) {
        std::cout << "right!" << std::endl;
    }

    return 0;
}