#include <bits/stdc++.h>
#include <cuda_runtime.h>

__global__ void matrixAdd(
    const float *A,
    const float *B,
    float *C,
    int width,
    int height)
{
    int col =
        blockIdx.x * blockDim.x +
        threadIdx.x;

    int row =
        blockIdx.y * blockDim.y +
        threadIdx.y;

    if (row < height && col < width)
    {
        int index = row * width + col;

        C[index] = A[index] + B[index];
    }
}

int main()
{
    const int width = 512;
    const int height = 512;

    size_t bytes = width * height * sizeof(float);

    float *A = (float *)malloc(bytes);
    float *B = (float *)malloc(bytes);
    float *C = (float *)malloc(bytes);

    for (int row = 0; row < height; ++row)
    {
        for (int col = 0; col < width; ++col)
        {
            A[row * width + col] = (float)(row + col);
            B[row * width + col] = (float)(2 * row - col);
        }
    }

    float *dev_A;
    float *dev_B;
    float *dev_C;

    cudaMalloc((void **)&dev_A, bytes);
    cudaMalloc((void **)&dev_B, bytes);
    cudaMalloc((void **)&dev_C, bytes);

    cudaMemcpy(dev_A, A, bytes, cudaMemcpyHostToDevice);
    cudaMemcpy(dev_B, B, bytes, cudaMemcpyHostToDevice);

    dim3 threads(16, 16);

    dim3 blocks(
        (width + threads.x - 1) / threads.x,
        (height + threads.y - 1) / threads.y);

    matrixAdd<<<blocks, threads>>>(
        dev_A,
        dev_B,
        dev_C,
        width,
        height);

    cudaDeviceSynchronize();

    cudaMemcpy(C, dev_C, bytes, cudaMemcpyDeviceToHost);

    printf("Grid: %d x %d blocks, block: %d x %d threads\n",
           blocks.x, blocks.y, threads.x, threads.y);

    int check[5][2] = {{0, 0}, {0, 511}, {10, 20}, {256, 100}, {511, 511}};

    for (int k = 0; k < 5; ++k)
    {
        int row = check[k][0];
        int col = check[k][1];
        printf("C[%d][%d] = %f (expected %f)\n",
               row, col, C[row * width + col], (float)(3 * row));
    }

    int errors = 0;

    for (int i = 0; i < width * height; ++i)
    {
        if (C[i] != A[i] + B[i])
        {
            errors++;
        }
    }

    printf("Mismatches: %d of %d elements\n", errors, width * height);

    cudaFree(dev_A);
    cudaFree(dev_B);
    cudaFree(dev_C);

    free(A);
    free(B);
    free(C);

    return 0;
}
