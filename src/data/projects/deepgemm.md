---
title: DeepGEMM
description: >-
  Clean and efficient FP8 GEMM kernels with fine-grained scaling to support
  accurate and performant low-precision matrix computations.
date: 2025-10-06T02:08:18.535Z
oss_date: 2025-02-13T09:09:21.000Z
website: ''
github: 'https://github.com/deepseek-ai/DeepGEMM'
author: DeepSeek
tags: []
featured: false
thumbnail: 'https://opengraph.githubassets.com/1/deepseek-ai/DeepGEMM'
category: AI Infra
---

## Overview

DeepGEMM provides efficient FP8 and low-precision GEMM kernels focused on balancing numerical stability and performance. Fine-grained scaling strategies and optimized GPU kernels help reduce numerical errors while leveraging low-precision speedups.

## Key Features

- High-performance FP8 GEMM implementations optimized for deep learning training and inference.
- Fine-grained scaling strategies to improve numerical stability while maintaining performance.
- CUDA-based kernels designed for real-world GPU acceleration.

## Use Cases

- Using low-precision matrix operations to save memory and increase throughput in model training and inference.
- Replacing default GEMM operators with custom kernels to optimize hotspot performance.
- Integrating as a low-precision computation library when trading off precision and speed.

## Technical Details

- Fine-grained scaling to mitigate FP8 numerical bias.
- Optimized CUDA kernels and memory layouts for parallel efficiency on GPUs.
- Integration-friendly interfaces for PyTorch and other frameworks.
