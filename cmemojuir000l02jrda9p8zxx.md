---
title: "CUDA Thread Hierarchy and Kernel Launch"
datePublished: Fri Aug 22 2025 10:20:55 GMT+0000 (Coordinated Universal Time)
cuid: cmemojuir000l02jrda9p8zxx
slug: cuda-thread-hierarchy-and-kernel-launch
tags: cuda, thread-layout

---

## **1\. Thread Layout Configuration and Kernel Launch**

The **thread layout** refers to the arrangement of threads, which is defined in terms of the **grid** and **block** structure.

The syntax is as follows:

```cpp
Kernel<<<grid,block>>()
```

* **gridDim**: the overall grid size (number of blocks)
    
* **blockDim**: the number of threads within each block
    

## 2.Example

```cpp
// thread_layout.cu
#include <stdio.h>

__global__ void printThreadInfo() {
    // ==============================
    // Thread ID inside the block (local coordinates)
    // ==============================
    int tx = threadIdx.x;  // thread x-coordinate
    int ty = threadIdx.y;  // thread y-coordinate
    int tz = threadIdx.z;  // thread z-coordinate

    // ==============================
    // Block ID inside the grid (block coordinates)
    // ==============================
    int bx = blockIdx.x;   // block x-coordinate
    int by = blockIdx.y;   // block y-coordinate
    int bz = blockIdx.z;   // block z-coordinate

    // ==============================
    // Block dimensions (blockDim)
    // ==============================
    int bdx = blockDim.x;  // number of threads in x within a block
    int bdy = blockDim.y;  // number of threads in y within a block
    int bdz = blockDim.z;  // number of threads in z within a block

    // ==============================
    // Grid dimensions (gridDim)
    // ==============================
    int gdx = gridDim.x;   // number of blocks in x within a grid
    int gdy = gridDim.y;   // number of blocks in y within a grid
    // gridDim.z is not used, so omitted

    // ==============================
    // Global thread ID calculation (flatten 3D → 1D)
    // ==============================
    int globalThreadId =
        tx +                                   // local x position
        ty * bdx +                             // add y offset
        tz * bdx * bdy +                       // add z offset
        bx * bdx * bdy * bdz +                 // block offset in x
        by * (bdx * bdy * bdz * gdx) +         // block offset in y
        bz * (bdx * bdy * bdz * gdx * gdy);    // block offset in z

    // ==============================
    // Print results
    // ==============================
    printf("Grid(%d,%d,%d) Block(%d,%d,%d) Thread(%d,%d,%d) GlobalId=%d\n",
           bx, by, bz, tx, ty, tz, tx, ty, tz, globalThreadId);
}

int main() {
    // ===========================
    // Thread layout configuration
    // ===========================
    dim3 grid(3,2,2);   // Grid size = (3,2,2) → 12 blocks
    dim3 block(2,2,2);  // Block size = (2,2,2) → 8 threads per block
    // Total number of threads = 12 × 8 = 96

    // ===========================
    // Kernel launch
    // ===========================
    printThreadInfo<<<grid, block>>>();
    cudaDeviceSynchronize();

    return 0;
}
```

![](https://cdn.hashnode.com/res/hashnode/image/upload/v1755857586266/8c035ae6-be24-41d4-90b6-3040463bb363.png align="center")

## 3.ceil()

### Why do we need `ceil()`? (people analogy)

* **Thread = a worker (person)**
    
* **Block = a group of workers**
    

Example:

* Total tasks to do: **1000**
    
* Workers per block: **256**
    

👉 1000 ÷ 256 = 3.9

* If we only use 3 blocks: 3 × 256 = **768 workers** → **232 tasks remain** ❌
    
* If we use 4 blocks: 4 × 256 = **1024 workers** → all tasks are covered ✅
    

So, we must **always round up** to ensure all tasks are processed.

---

### Code Example (C/C++)

```cpp
#include <stdio.h>
#include <math.h>

int main() {
    int N = 1000;        // total number of tasks
    int blockSize = 256; // number of threads per block

    // calculate the number of blocks using ceil
    int gridSize = (int)ceil((double)N / blockSize);

    printf("Total work = %d\n", N);
    printf("Threads per block = %d\n", blockSize);
    printf("Blocks needed = %d\n", gridSize);
    printf("Total threads allocated = %d\n", gridSize * blockSize);

    return 0;
}
```

---

### Output

```cpp
Total work = 1000
Threads per block = 256
Blocks needed = 4
Total threads allocated = 1024
```

👉 In practice, 1024 threads are launched, but the extra 24 threads simply **do nothing** if we guard with `if (idx < N)` inside the kernel.

---

### Common CUDA Pattern

```cpp
int gridSize = (int)ceil((double)N / blockSize);
// Or using integer arithmetic (faster and safer)
int gridSize = (N + blockSize - 1) / blockSize;
```

---

✅ Summary: `ceil()` ensures that **all tasks are covered** when computing the grid size.  
It’s essential in CUDA for grid/block configuration.