#ifndef MA_GPU_SIMULATION_H
#define MA_GPU_SIMULATION_H
#include <chrono>
#include <thread>
#include <assert.h>
#include <climits>
#include <fstream>
#include <iostream>
#include <limits>
#include <omp.h>
#include <queue>
#include <string>
#include <vector>
#include <list>
#include <set>
#include <cmath>
#include <stdio.h>
#include <stddef.h>
#include <stdint.h>
#include <unordered_set>
#include <utility> 
#include <algorithm>
#include <cstddef>  // For int and SIZE_MAX
#include <cstdio>
#include <cuda.h>
#include <cuda_runtime.h>
#include <cuda_runtime_api.h>
#include <cublas_v2.h>
#include <set>
#include <cassert>
#include <cstdio>
#include <fsim/fsim.hpp>

// error checking macro
#define cudaCheckErrors(msg) \
    do { \
        cudaError_t __err = cudaGetLastError(); \
        if (__err != cudaSuccess) { \
            fprintf(stderr, "Fatal error: %s (%s at %s:%d)\n", \
                msg, cudaGetErrorString(__err), \
                __FILE__, __LINE__); \
            fprintf(stderr, "*** FAILED - ABORTING\n"); \
            exit(1); \
        } \
    } while (0)

// GPU functions pre-declarations
__device__ __forceinline__ void _apply_INV(const int gate_idx, const int *_invAdj_gpu, 
  const int *_invAdj_index_table_gpu, uint32_t *_pi_gate_po_output_res_gpu);
__device__ __forceinline__ void _apply_AND(const int gate_idx, const int *_invAdj_gpu, 
  const int *_invAdj_index_table_gpu, uint32_t *_pi_gate_po_output_res_gpu);
__device__ __forceinline__ void _apply_OR(const int gate_idx, const int *_invAdj_gpu, 
  const int *_invAdj_index_table_gpu, uint32_t *_pi_gate_po_output_res_gpu);
__device__ __forceinline__ void _apply_XOR(const int gate_idx, const int *_invAdj_gpu, 
  const int *_invAdj_index_table_gpu, uint32_t *_pi_gate_po_output_res_gpu);
__device__ __forceinline__ void _apply_NAND(const int gate_idx, const int *_invAdj_gpu, 
  const int *_invAdj_index_table_gpu, uint32_t *_pi_gate_po_output_res_gpu);
__device__ __forceinline__ void _apply_NOR(const int gate_idx, const int *_invAdj_gpu, 
  const int *_invAdj_index_table_gpu, uint32_t *_pi_gate_po_output_res_gpu);
__device__ __forceinline__ void _apply_XNOR(const int gate_idx, const int *_invAdj_gpu, 
  const int *_invAdj_index_table_gpu, uint32_t *_pi_gate_po_output_res_gpu);
__device__ __forceinline__ void _apply_MUX(const int gate_idx, const int *_invAdj_gpu, 
  const int *_invAdj_index_table_gpu, uint32_t *_pi_gate_po_output_res_gpu);
__device__ __forceinline__ void _apply_CLKBUF(const int gate_idx, const int *_invAdj_gpu, 
  const int *_invAdj_index_table_gpu, uint32_t *_pi_gate_po_output_res_gpu);
__device__ __forceinline__ void _apply_PI(const int gate_idx, const int *_invAdj_gpu, 
  const int *_invAdj_index_table_gpu, uint32_t *_pi_gate_po_output_res_gpu, const uint32_t pattern_val);
__device__ __forceinline__ void _apply_PO(const int gate_idx, const int *_invAdj_gpu, 
  const int *_invAdj_index_table_gpu, uint32_t *_pi_gate_po_output_res_gpu);
__global__ void _run_gate_DSP(const int num_accumGates, const int *_numGates_per_level_gpu,
  const int *_invAdj_gpu, const int *_invAdj_index_table_gpu, 
  const int *_pi_gate_po_gate_type_gpu, uint32_t *_pi_gate_po_output_res_gpu, 
  const uint32_t *_patterns_gpu, const size_t rd, 
  const int num_gates_per_level, 
  const int _num_PIs);
__global__ void _write_and_shift_to_array_gpu(const size_t bits, 
  uint32_t *_pi_gate_po_output_res_gpu, const int total_num_gates);
// print function 
__global__ void _print_simulation_results(const uint32_t *_pi_gate_po_output_res_gpu, const int total_num_gates);


// Forward declaration of CUDAMAPartitioner
class CUDAMAPartitioner;

class GPUSimulator {
  friend class CUDAMAPartitioner;

public:
  void run_gpu_simulator_DSP_gpu(const int num_PIs, 
    const int num_inner_gates,
    const int num_POs, 
    const int sum_pi_gates_pos,
    const int num_pattern, 
    const size_t num_rounds,
    const int num_fault, 
    const int *_pi_gate_po_gate_type_gpu,
    const uint32_t *_patterns_gpu,
    uint32_t *_pi_gate_po_output_res_gpu,
    std::vector<int> &_numGates_per_level,
    const int *_numGates_per_level_gpu,
    const int _total_num_levels,
    const int *_invAdj_gpu,
    const int *_invAdj_index_table_gpu,
    const std::vector<Pattern> _patterns,
    const size_t NUM_SIMULATION_RDS) 
  {
    // Get vars   
    _num_PIs = num_PIs;
    _num_inner_gates = num_inner_gates;
    _num_POs = num_POs;
    _sum_pi_gates_pos = sum_pi_gates_pos;
    _num_pattern = num_pattern;
    _num_rounds = num_rounds;
    _num_fault = num_fault;
    // printf("Get inside run_gpu_simulator_DSP_gpu\n");
    
    // Run simulation - Levelization part 
    for (size_t rd = 0; rd < NUM_SIMULATION_RDS; rd++) {
      _run_gates_DSP_gpu(_total_num_levels, 
                        _numGates_per_level,
                        _numGates_per_level_gpu,
                        _invAdj_gpu,
                        _invAdj_index_table_gpu,
                        _pi_gate_po_gate_type_gpu, 
                        _patterns_gpu,
                        _patterns,
                        _pi_gate_po_output_res_gpu);
    } // NUM_SIMULATION_RDS
  }

private:
  // vars
  int _num_PIs; 
  int _num_inner_gates;
  int _num_POs; 
  int _sum_pi_gates_pos;
  int _num_pattern; 
  size_t _num_rounds; 
  int _num_fault; 
  int _used_num_blocks;
  int _num_threads;

  // DSP simulation
  void _run_gates_DSP_gpu(const int _total_num_levels, 
    const std::vector<int> &_numGates_per_level,
    const int *_numGates_per_level_gpu,
    const int *_invAdj_gpu,
    const int *_invAdj_index_table_gpu,
    const int *_pi_gate_po_gate_type_gpu,
    const uint32_t *_patterns_gpu,
    const std::vector<Pattern> _patterns,
    uint32_t *_pi_gate_po_output_res_gpu);   
};

#endif  // MA_GPU_SIMULATION_H