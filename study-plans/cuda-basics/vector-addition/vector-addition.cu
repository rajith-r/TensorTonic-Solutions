#include <cuda_runtime.h>

__global__ void vector_add(const float* A, const float* B, float* C, int N) {
    // Write code here
    int i = blockIdx.x*blockDim.x+threadIdx.x;

    while(i<N){
        C[i] = A[i] + B[i];
        i+=gridDim.x*blockDim.x;
    }
}

extern "C" void solve(const float* A, const float* B, float* C, int N) {
    int threads = 256;
    int blocks = (N + threads - 1) / threads;
    vector_add<<<blocks, threads>>>(A, B, C, N);
    cudaDeviceSynchronize();
}