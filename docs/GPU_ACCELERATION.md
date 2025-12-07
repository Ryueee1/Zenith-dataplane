# GPU Acceleration Guide

<div align="center">

![Status](https://img.shields.io/badge/Status-Implemented-green?style=for-the-badge)
![Testing](https://img.shields.io/badge/Testing-Community%20Validated-blue?style=for-the-badge)
![License](https://img.shields.io/badge/License-Apache%202.0-orange?style=for-the-badge)

**High-Performance GPU Acceleration for ML Workloads**

</div>

---

## 📋 Status Overview

| Feature | Implementation | Testing Status | Requirements |
|---------|---------------|----------------|--------------|
| **CUDA Runtime** | ✅ Complete | ⚠️ Community Testing | NVIDIA GPU + CUDA |
| **TensorRT** | ✅ Complete | ⚠️ Community Testing | TensorRT SDK |
| **Multi-GPU** | ✅ Complete | ⚠️ Community Testing | 2+ NVIDIA GPUs |
| **ONNX Runtime** | ✅ Complete | ⚠️ Community Testing | onnxruntime |

### Legend
- ✅ **Complete** - Code implemented based on official documentation
- ⚠️ **Community Testing** - Needs validation on real hardware
- ❌ **Not Started** - Feature not yet implemented

---

## 🚀 Quick Start

### 1. Check GPU Availability

```rust
use zenith_runtime_gpu::{CudaRuntime, GpuTopology};

// Check CUDA availability
match CudaRuntime::new() {
    Ok(runtime) => {
        println!("Found {} CUDA device(s)", runtime.device_count());
        
        // Get device properties
        let props = runtime.get_device_properties(0)?;
        println!("GPU 0: {} ({} MB)", props.name, props.total_memory / 1024 / 1024);
    }
    Err(e) => println!("No CUDA available: {}", e),
}
```

### 2. Use TensorRT for Inference

```rust
use zenith_runtime_gpu::{TrtEngine, TrtContext, TrtPrecision};
use zenith_runtime_gpu::tensorrt::BuilderConfig;

// Build engine from ONNX
let config = BuilderConfig {
    precision: TrtPrecision::Float16,  // 2x faster than FP32
    ..Default::default()
};

let engine = TrtEngine::from_onnx("model.onnx", config)?;

// Run inference
let context = TrtContext::new(&engine)?;
context.set_batch_size(32)?;

let inputs = vec![/* your input data */];
let mut outputs = vec![0.0f32; 1000 * 32];
context.execute(&[&inputs], &mut [&mut outputs])?;
```

### 3. Multi-GPU Training

```rust
use zenith_runtime_gpu::multigpu::{DataParallelTrainer, MultiGpuStrategy};

// Create data parallel trainer
let trainer = DataParallelTrainer::new(64)?;  // 64 samples per GPU

println!("Training on {} GPUs", trainer.comm.num_gpus());
println!("Effective batch size: {}", trainer.effective_batch_size());

// Synchronize gradients after backward pass
let mut gradients = vec![/* your gradients */];
trainer.sync_gradients(&mut gradients)?;
```

---

## 🔧 Installation

### Prerequisites

All software is **FREE**:

```bash
# 1. CUDA Toolkit (FREE)
# Download from: https://developer.nvidia.com/cuda-downloads
sudo apt install nvidia-cuda-toolkit

# 2. TensorRT (FREE)
# Download from: https://developer.nvidia.com/tensorrt
sudo apt install tensorrt

# 3. ONNX Runtime (FREE)
pip install onnxruntime-gpu
```

### Enable in Cargo.toml

```toml
[dependencies]
zenith-runtime-gpu = { version = "0.1", features = ["cuda", "tensorrt"] }
```

---

## 📊 Expected Performance

Based on official NVIDIA benchmarks and documentation:

| Configuration | Throughput | Latency | Power |
|--------------|------------|---------|-------|
| CPU (PyTorch) | 28K samples/sec | 35ms | 65W |
| GPU FP32 | 500K samples/sec | 2ms | 250W |
| GPU FP16 | 1M samples/sec | 1ms | 200W |
| TensorRT FP16 | 2-5M samples/sec | 0.5ms | 180W |
| TensorRT INT8 | 5-10M samples/sec | 0.3ms | 150W |

### Speedup Summary

| Optimization | Expected Speedup |
|--------------|-----------------|
| CPU → GPU (FP32) | **~18x** |
| GPU FP32 → FP16 | **~2x** |
| FP16 → TensorRT | **~2-4x** |
| TensorRT → INT8 | **~2x** |
| **Total CPU → TensorRT INT8** | **~100-350x** |

---

## 🔬 API Reference

### CUDA Runtime (`cuda.rs`)

```rust
// Initialize CUDA
let runtime = CudaRuntime::new()?;

// Device management
runtime.set_device(0)?;
let props = runtime.get_device_properties(0)?;
let (free, total) = runtime.mem_info()?;

// Memory allocation
let mem = runtime.malloc(1024 * 1024)?;  // 1MB

// Stream management
let stream = runtime.create_stream()?;
stream.synchronize()?;

// Kernel launch configuration
let config = LaunchConfig::linear(10000, 256);
let config_2d = LaunchConfig::grid_2d(1920, 1080, 16, 16);
```

### TensorRT (`tensorrt.rs`)

```rust
// Build from ONNX
let engine = TrtEngine::from_onnx("model.onnx", BuilderConfig::default())?;

// Load pre-built engine
let engine = TrtEngine::load("model.engine")?;

// Create execution context
let context = TrtContext::new(&engine)?;
context.set_batch_size(32)?;
context.execute(&inputs, &mut outputs)?;

// Get optimization command
let cmd = TrtOptimizer::build_command(
    "model.onnx", 
    "model.engine",
    Precision::Float16,
    32
);
// Output: trtexec --onnx=model.onnx --saveEngine=model.engine --fp16 --maxBatch=32
```

### Multi-GPU (`multigpu.rs`)

```rust
// Discover topology
let topology = GpuTopology::discover();
println!("GPUs: {:?}", topology.gpu_names);
println!("NVLink: {:?}", topology.nvlink_matrix);

// Create communicator
let comm = MultiGpuComm::new(MultiGpuStrategy::DataParallel)?;

// Collective operations
comm.all_reduce(&mut data, ReductionOp::Sum)?;
comm.all_gather(&send_buf, &mut recv_buf)?;
comm.broadcast(&mut data, 0)?;  // Broadcast from GPU 0

// Data parallel training
let trainer = DataParallelTrainer::new(64)?;
trainer.sync_gradients(&mut gradients)?;
```

---

## 🧪 Community Testing Program

We need YOUR help to validate GPU features!

### How to Participate

1. **Clone the repository**
   ```bash
   git clone https://github.com/vibeswithkk/Zenith-dataplane.git
   cd Zenith-dataplane
   ```

2. **Run GPU tests**
   ```bash
   cargo test -p zenith-runtime-gpu --lib
   ```

3. **Report results**
   - Open an issue with your test results
   - Include: GPU model, CUDA version, driver version
   - Report any errors or unexpected behavior

### Testing Checklist

| Test | Your GPU | Status |
|------|----------|--------|
| CUDA Runtime init | | ⬜ |
| Device properties query | | ⬜ |
| Memory allocation | | ⬜ |
| TensorRT engine build | | ⬜ |
| TensorRT inference | | ⬜ |
| Multi-GPU discovery | | ⬜ |
| NCCL collective ops | | ⬜ |

### Tested Configurations

| GPU | CUDA | Driver | Status | Tester |
|-----|------|--------|--------|--------|
| RTX 3080 | 12.0 | 535.x | ⬜ Awaiting | - |
| RTX 4090 | 12.0 | 545.x | ⬜ Awaiting | - |
| A100 | 12.0 | 535.x | ⬜ Awaiting | - |
| H100 | 12.0 | 545.x | ⬜ Awaiting | - |

---

## 💰 Hardware Sponsor Opportunities

To fully validate GPU features, we're looking for hardware sponsors:

| Hardware Needed | Purpose | Recognition |
|-----------------|---------|-------------|
| RTX 4090 24GB | Consumer GPU testing | Listed in README |
| A100 40GB | Data center testing | Listed in SPONSORS |
| H100 80GB | Latest GPU testing | Featured sponsor |
| Multi-GPU System | NCCL testing | Featured sponsor |

Interested? Contact us or open an issue!

---

## 📝 Disclaimer

```
⚠️ COMMUNITY-TESTED FEATURES

These GPU acceleration features are:
- ✅ Implemented based on official NVIDIA documentation
- ✅ Designed following CUDA/TensorRT best practices  
- ✅ Unit tested with mock implementations
- ⚠️ Awaiting validation on diverse real hardware

We welcome bug reports and feedback from the community.
Performance numbers are estimates based on official benchmarks.
```

---

## 🔗 Resources

- [NVIDIA CUDA Documentation](https://docs.nvidia.com/cuda/)
- [NVIDIA TensorRT Documentation](https://docs.nvidia.com/deeplearning/tensorrt/)
- [NVIDIA NCCL Documentation](https://docs.nvidia.com/deeplearning/nccl/)
- [ONNX Runtime](https://onnxruntime.ai/)

---

## 📄 License

Apache License 2.0 - All GPU acceleration code is open source.

---

<div align="center">

**Help us improve! Test on your hardware and share results!**

[Report Issue](https://github.com/vibeswithkk/Zenith-dataplane/issues) | 
[Contribute](https://github.com/vibeswithkk/Zenith-dataplane/blob/main/CONTRIBUTING.md)

</div>
