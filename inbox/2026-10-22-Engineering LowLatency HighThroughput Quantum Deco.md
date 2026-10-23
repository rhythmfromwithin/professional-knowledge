---
interest: medium
link: https://arxiv.org/abs/2610.28867
next_step: skim
priority: medium
slack_ts: '1792729425.811549'
source: cs.DC - Distributed Computing
status: unread
title: Engineering Low-Latency, High-Throughput Quantum Decoders on NVIDIA GPUs
---
# Engineering Low-Latency, High-Throughput Quantum Decoders on NVIDIA GPUs
> 原文: [https://arxiv.org/abs/2610.28867](https://arxiv.org/abs/2610.28867)

arXiv:2610.28867v1 Announce Type: new
Abstract: We design and optimize a quantum error correction (QEC) decoder for NVIDIA GPUs, combining Relay belief propagation, a state-of-the-art message-passing algorithm, with order-zero ordered statistics post-processing. Our implementation uses CUDA Graphs to control GPU execution, stops updates for converged samples, and collects unresolved samples in queues for post-processing. We optimize sparse traversal through coalesced message accesses, prefetching, and register reuse, and accelerate binary post-processing with warp-level collectives. In addition, mixed FP16-FP32 arithmetic and INT8 quantization reduce message storage and traffic while retaining accuracy using accumulators at higher precision. We evaluate surface, hypergraph product, and bivariate bicycle code workloads on NVIDIA A100 and GH200 data-center GPUs and a commodity RTX 5080. On the bivariate bicycle code at error probability 0.003, INT8 halves amortized decoding time relative to independently tuned FP32 with a negligible logical error rate increase on RTX 5080. With independent syndrome batches submitted back-to-back to concurrent decoder instances, RTX 5080 delivers 91% of GH200's highest measured throughput with an 8.9x shorter median submission-to-correction latency. The combination of performance optimization, mixed precision, INT8 quantization, and concurrent decoder instances opens a path toward QEC decoder clusters built from commodity GPUs.
