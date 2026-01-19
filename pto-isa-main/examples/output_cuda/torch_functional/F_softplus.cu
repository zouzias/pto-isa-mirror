// PTO Program: F_softplus
// Auto-generated CUDA code from PTO ISA Compiler
#include <cuda_runtime.h>
#include <cuda_fp16.h>
#include <cuda_bf16.h>
#include <mma.h>
#include <cooperative_groups.h>
#include <math.h>
#include <stdint.h>
#include <stdio.h>

namespace cg = cooperative_groups;

__device__ float x[8][8];
__device__ float beta_x[8][8];
__device__ float exp_bx[8][8];
__device__ float one_plus[8][8];
__device__ float log_val[8][8];
__device__ float result[8][8];

__global__ void F_softplus_kernel(float* input, float* output) {
    int _row = threadIdx.y + blockIdx.y * blockDim.y;
    int _col = threadIdx.x + blockIdx.x * blockDim.x;

    // Loop fusion: 6 loop overheads saved

    // FUSED (7 ops): x=TLOAD(...); beta_x=TMULS(...); exp_bx=TEXP(...); one_plus=TADDS(...); log_val=TLOG(...); result=TDIVS(...); output=TSTORE(...)
    if (_row < 8 && _col < 8) {
        x[_row][_col] = input[_row * 8 + _col];
        beta_x[_row][_col] = x[_row][_col] * 1.0f;
        exp_bx[_row][_col] = __expf(beta_x[_row][_col]);
        one_plus[_row][_col] = exp_bx[_row][_col] + 1.0f;
        log_val[_row][_col] = __logf(one_plus[_row][_col]);
        result[_row][_col] = log_val[_row][_col] / 1.0f;
        output[_row * 8 + _col] = result[_row][_col];
    }

}

void F_softplus(float* input, float* output) {
    dim3 block(8, 8);
    dim3 grid(1, 1);
    F_softplus_kernel<<<grid, block>>>(input, output);
    cudaDeviceSynchronize();
}