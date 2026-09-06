# AI Systems Performance Engineering

- [Chapter 1: Introduction and AI System Overview](./chap01/README.md)
- [Chapter 2: AI System Hardware Overview](./chap02/README.md)
- [Chapter 3: OS, Docker, and Kubernetes Tuning for GPU-Based Environments](./chap03/README.md)
- [Chapter 4: Tuning Distributed Networking Communication](./chap04/README.md)
- [Chapter 5: GPU-Based Storage I/O Optimizations](./chap05/README.md)
- [Chapter 6: GPU Architecture, CUDA Programming, and Maximizing Occupancy](./chap06/README.md)

## Resources

### Books

- [AI Systems Performance Engineering: Optimizing Model Training and Inference Workloads with GPUs, CUDA, and PyTorch](https://www.amazon.com/Systems-Performance-Engineering-Optimizing-Inference/dp/B0F47689K8) (2025.12)
  - [Code](https://github.com/cfregly/ai-performance-engineering)

### Articles

- [Making Deep Learning Go Brrrr From First Principles](https://horace.io/brrr_intro.html)
- [Hardware Architectures for LLM Inference](../inference/efficient-llm-inference-systems/appendix/hardware-architectures/README.md)
- [Never Underestimate Memory Architecture](./articles/never-underestimate-memory-architecture.ko.md): NUMA, cloud VM topology, Kubernetes CPU Manager, uncore bottlenecks
- [Keeping GPU Workloads NUMA-Local in Kubernetes](./articles/keeping-gpu-workloads-numa-local-in-kubernetes.ko.md): GPU-local CPU placement, kubelet topology policies, NUMA-aware scheduling

### Talks

- [The Engineering Behind Training a 2 Trillion Parameter LLM](https://www.youtube.com/watch?v=yn4GGAtZ7QE) (2026.04)
- [Never Underestimate Memory Architecture - Bryan Boreham, Grafana Labs](https://www.youtube.com/watch?v=C6aBa1vnYT4)

### GPU

- [H100 Tensor Core GPU Architecture](https://resources.nvidia.com/en-us-hopper-architecture/nvidia-h100-tensor-c)
- [NVIDIA Blackwell Architecture Technical Brief](https://resources.nvidia.com/en-us-blackwell-architecture)
- [NVFP4 Trains with Precision of 16-Bit and Speed and Efficiency of 4-Bit](https://developer.nvidia.com/blog/nvfp4-trains-with-precision-of-16-bit-and-speed-and-efficiency-of-4-bit/?ncid=no-ncid) (2025.08)
- [Using FP8 and FP4 with Transformer Engine](https://docs.nvidia.com/deeplearning/transformer-engine/user-guide/examples/fp8_primer.html)
- [NCCL and Communication Collectives](https://roycho96.github.io/posts/nccl-collectives/)
- [NCCL Algorithms](https://roycho96.github.io/posts/nccl-algorithms/)
