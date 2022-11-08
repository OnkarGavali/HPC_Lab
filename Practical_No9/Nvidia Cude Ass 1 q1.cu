#include <stdio.h>
 
void initWith(int num, int *a, int N)
{
  for(int i = 0; i < N; ++i)
  {
    a[i] = num;
  }
}
 
__global__
void addVectorsInto(int *result, int *a, int *b, int N)
{
  int index = threadIdx.x + blockIdx.x * blockDim.x;
  int stride = blockDim.x * gridDim.x;
 
  for(int i = index; i < N; i += stride)
  {
    result[i] = a[i] + b[i];
  }
}
 
void checkElementsAre(int target, int *array, int N)
{
  for(int i = 0; i < N; i++)
  {
    if(array[i] != target)
    {
      printf("FAIL: array[%d] - %d does not equal %d\n", i, array[i], target);
      exit(1);
    }
  }
  printf("SUCCESS! All values added correctly.\n");
}
 
int main()
{
  const int N = 2<<20;
  size_t size = N * sizeof(int);
 
  int *a;
  int *b;
  int *c;
 
  cudaMallocManaged(&a, size);
  cudaMallocManaged(&b, size);
  cudaMallocManaged(&c, size);
 
  initWith(3, a, N);
  initWith(4, b, N);
  initWith(0, c, N);
 
  size_t threadsPerBlock;
  size_t numberOfBlocks;
 
  threadsPerBlock = 256;
  numberOfBlocks = (N + threadsPerBlock - 1) / threadsPerBlock;
 
  addVectorsInto<<<numberOfBlocks, threadsPerBlock>>>(c, a, b, N);
 
  cudaDeviceSynchronize();
 
  checkElementsAre(7, c, N);
 
  cudaFree(a);
  cudaFree(b);
  cudaFree(c);
}
