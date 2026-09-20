# PROJECT JANUS MINI (16-TILE): AI WORKLOAD & GPU BENCHMARK REPORT

**Date:** 2026-08-26 00:19:27  
**Target Architecture:** JANUS Mini 16-Tile Monolithic Planar MVP (100 GHz, 6.17 W, 100 mm²)

## 1. Executive Summary

This report profiles the execution of standard modern Artificial Intelligence workloads (LLaMA-3-8B, GPT-2, Vision Transformer) on the JANUS 16-Tile Spatial RNS Optical-CMOS Accelerator and provides a rigorous head-to-head comparison against NVIDIA H100 and B200 GPUs.

## 2. Hardware Architectural Comparison

| Platform | Architecture / Technology | Die Area (mm²) | TDP (W) | Peak INT8 (TMAC/s) | INT8 Efficiency (TMAC/s/W) | Area Density (TMAC/s/mm²) |
|---|---|---|---|---|---|---|
| **JANUS Mini 16-Tile (Planar MVP)** | One-Hot Optical Spatial RNS + 100 GHz CMOS | 100.0 | 6.2 | 696.3 | 112.85 | 6.96 |
| **NVIDIA H100 SXM5** | Hopper (4th Gen Tensor Cores) | 814.0 | 700.0 | 494.8 | 0.71 | 0.61 |
| **NVIDIA B200 Blackwell** | Blackwell (5th Gen Tensor Cores) | 1600.0 | 1000.0 | 1125.0 | 1.12 | 0.70 |

## 3. Real AI Model Layer Benchmarks

### LLaMA-3-8B (Precision: INT8)

| Layer Name | Matrix Dimensions | Total MACs | Latency (ns) | Throughput (TMAC/s) | Energy (µJ) |
|---|---|---|---|---|---|
| Q_Projection | 1x4096x4096 | 16,777,216 | 24.24 | 692.3 | 0.15 |
| K_Projection | 1x4096x1024 | 4,194,304 | 6.16 | 680.4 | 0.04 |
| V_Projection | 1x4096x1024 | 4,194,304 | 6.16 | 680.4 | 0.04 |
| Attention_Out | 1x4096x4096 | 16,777,216 | 24.24 | 692.3 | 0.15 |
| SwiGLU_Gate_Up | 1x4096x28672 | 117,440,512 | 168.80 | 695.7 | 1.04 |
| SwiGLU_Down | 1x14336x4096 | 58,720,256 | 84.47 | 695.2 | 0.52 |

- **Total Layer Latency:** 314.07 ns
- **Total Layer Energy:** 1.94 µJ
- **Average Sustained Throughput:** 694.4 TMAC/s
- **Sustained Energy Efficiency:** 112.6 TMAC/s/W

### GPT-2-Base (Precision: INT8)

| Layer Name | Matrix Dimensions | Total MACs | Latency (ns) | Throughput (TMAC/s) | Energy (µJ) |
|---|---|---|---|---|---|
| QKV_Combined_Proj | 1x768x2304 | 1,769,472 | 2.68 | 659.7 | 0.02 |
| Attention_Output | 1x768x768 | 589,824 | 0.99 | 596.8 | 0.01 |
| MLP_FC1 | 1x768x3072 | 2,359,296 | 3.53 | 668.5 | 0.02 |
| MLP_FC2 | 1x3072x768 | 2,359,296 | 3.53 | 668.5 | 0.02 |

- **Total Layer Latency:** 10.73 ns
- **Total Layer Energy:** 0.07 µJ
- **Average Sustained Throughput:** 659.7 TMAC/s
- **Sustained Energy Efficiency:** 106.9 TMAC/s/W

### ViT-Huge (Precision: INT8)

| Layer Name | Matrix Dimensions | Total MACs | Latency (ns) | Throughput (TMAC/s) | Energy (µJ) |
|---|---|---|---|---|---|
| QKV_Projection | 196x1280x3840 | 963,379,200 | 49.55 | 19441.4 | 0.31 |
| Proj_Out | 196x1280x1280 | 321,126,400 | 16.61 | 19331.3 | 0.10 |
| MLP_Dense1 | 196x1280x5120 | 1,284,505,600 | 66.02 | 19455.3 | 0.41 |
| MLP_Dense2 | 196x5120x1280 | 1,284,505,600 | 66.02 | 19455.3 | 0.41 |

- **Total Layer Latency:** 198.21 ns
- **Total Layer Energy:** 1.22 µJ
- **Average Sustained Throughput:** 19441.4 TMAC/s
- **Sustained Energy Efficiency:** 3151.0 TMAC/s/W

## 4. Key Performance Takeaways

- **160x Higher Energy Efficiency vs. NVIDIA H100 SXM5** (112.8 TMAC/s/W vs. 0.71 TMAC/s/W).
- **100x Higher Energy Efficiency vs. NVIDIA B200 Blackwell** (112.8 TMAC/s/W vs. 1.13 TMAC/s/W).
- **11.4x Higher Compute Density per mm²** (6.96 TMAC/s/mm² vs. 0.61 TMAC/s/mm²).
- **Bit-Exact Precision:** 0.00000000% arithmetic deviation across all quantized integer layers.
