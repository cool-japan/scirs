# SciRS2 - Scientific Computing and AI in Rust

[![crates.io](https://img.shields.io/crates/v/scirs2.svg)](https://crates.io/crates/scirs2)
[![License](https://img.shields.io/badge/license-MIT%2FApache--2.0-blue.svg)](LICENSE)
![SciRS2 CI](https://github.com/cool-japan/scirs/workflows/SciRS2%20CI/badge.svg)

SciRS2 is a comprehensive scientific computing and AI/ML infrastructure in Rust, providing SciPy-compatible APIs while leveraging Rust's performance, safety, and concurrency features. The project aims to provide a complete ecosystem for scientific computing, data analysis, and machine learning in Rust.

## 🚀 Release Status: v0.1.0-RC.1

**Release Candidate 1** - Ready for testing!

- ✅ **POLICY Compliance Complete**: All 23 crates now follow the unified SciRS2 architecture
- ✅ **Centralized Dependencies**: Only `scirs2-core` manages external dependencies
- ✅ **Full Test Coverage**: 9,800+ tests passing
- ✅ **Zero Warnings Build**: Clean compilation across entire workspace
- 📅 **Release Date**: October 03, 2025

**What's New in RC.1**:
- Complete migration to SciRS2 POLICY architecture
- Unified dependency management through scirs2-core
- Enhanced type safety and API consistency
- Improved maintainability and version control

See [SCIRS2_POLICY.md](SCIRS2_POLICY.md) for architectural details.

## Features

### Scientific Computing
- **Linear Algebra**: Matrix operations, decompositions, eigensolvers, and specialized matrix types
- **Statistics**: Distributions, descriptive statistics, tests, and regression models
- **Optimization**: Unconstrained and constrained optimization, root finding, and least squares
- **Integration**: Numerical integration, ODE solvers, and boundary value problems
- **Interpolation**: Linear, spline, and multi-dimensional interpolation
- **Special Functions**: Mathematical special functions including Bessel, gamma, and elliptic functions
- **Signal Processing**: FFT, wavelet transforms, filtering, and spectral analysis
- **Sparse Matrices**: Multiple sparse matrix formats and operations
- **Spatial Algorithms**: Distance calculations, KD-trees, and spatial data structures

### Advanced Features
- **N-dimensional Image Processing**: Filtering, feature detection, and segmentation
- **Clustering**: K-means, hierarchical, and density-based clustering
- **I/O Utilities**: Scientific data format reading and writing
- **Sample Datasets**: Data generation and loading tools

### AI and Machine Learning
- **Automatic Differentiation**: Reverse-mode and forward-mode autodiff engine
- **Neural Networks**: Layers, optimizers, and model architectures
- **Graph Processing**: Graph algorithms and data structures
- **Data Transformation**: Feature engineering and normalization
- **Metrics**: Evaluation metrics for ML models
- **Text Processing**: Tokenization and text analysis tools
- **Computer Vision**: Image processing and feature detection
- **Time Series**: Analysis and forecasting tools

### Performance and Safety
- **Ultra-Optimized SIMD**: Ecosystem-wide bandwidth-saturated SIMD achieving 10-100x performance improvements
- **Memory Management**: Efficient handling of large datasets with intelligent chunking and caching
- **GPU Acceleration**: CUDA and hardware-agnostic backends for computation
- **Parallelization**: Multi-core processing for compute-intensive operations with work-stealing scheduler
- **Safety**: Memory safety and thread safety through Rust's ownership model
- **Type Safety**: Strong typing and compile-time checks
- **Error Handling**: Comprehensive error system with context and recovery strategies

## Project Scale

This project now contains **over 2 million source lines of code** and runs **9,800+ tests** across all modules (including previous scirs2-optim, currently another project), demonstrating the comprehensive nature of the SciRS2 ecosystem.

## Project Goals

- Create a comprehensive scientific computing and machine learning library in Rust
- Maintain API compatibility with SciPy where reasonable
- Provide specialized tools for AI and machine learning development
- Leverage Rust's performance, safety, and concurrency features
- Build a sustainable open-source ecosystem for scientific and AI computing in Rust
- Offer performance similar to or better than Python-based solutions
- Provide a smooth migration path for SciPy users

## Project Structure

SciRS2 adopts a modular architecture with separate crates for different functional areas, using Rust's workspace feature to manage them:

```
/
# Core Scientific Computing Modules
├── Cargo.toml                # Workspace configuration
├── scirs2-core/              # Core utilities and common functionality
├── scirs2-autograd/          # Automatic differentiation engine
├── scirs2-linalg/            # Linear algebra module
├── scirs2-integrate/         # Numerical integration
├── scirs2-interpolate/       # Interpolation algorithms
├── scirs2-optimize/          # Optimization algorithms
├── scirs2-fft/               # Fast Fourier Transform
├── scirs2-stats/             # Statistical functions
├── scirs2-special/           # Special mathematical functions
├── scirs2-signal/            # Signal processing
├── scirs2-sparse/            # Sparse matrix operations
├── scirs2-spatial/           # Spatial algorithms

# Advanced Modules
├── scirs2-cluster/           # Clustering algorithms
├── scirs2-ndimage/           # N-dimensional image processing
├── scirs2-io/                # Input/output utilities
├── scirs2-datasets/          # Sample datasets and loaders

# AI/ML Modules
├── scirs2-neural/            # Neural network building blocks
# Note: scirs2-optim separated into independent OptiRS project from v0.1.0-beta.2
├── scirs2-graph/             # Graph processing algorithms
├── scirs2-transform/         # Data transformation utilities
├── scirs2-metrics/           # ML evaluation metrics
├── scirs2-text/              # Text processing utilities
├── scirs2-vision/            # Computer vision operations
├── scirs2-series/            # Time series analysis

# Main Integration Crate
└── scirs2/                   # Main integration crate
    ├── Cargo.toml
    └── src/
        └── lib.rs            # Re-exports from all other crates
```

### Architectural Benefits

This modular architecture offers several advantages:
- **Flexible Dependencies**: Users can select only the features they need
- **Independent Development**: Each module can be developed and tested separately
- **Clear Separation**: Each module focuses on a specific functional area
- **No Circular Dependencies**: Clear hierarchy prevents circular dependencies
- **AI/ML Focus**: Specialized modules for machine learning and AI workloads
- **Feature Flags**: Granular control over enabled functionality
- **Memory Efficiency**: Import only what you need to reduce overhead

## Advanced Core Features

The core module (scirs2-core) provides several advanced features that are leveraged across the ecosystem:

### GPU Acceleration

```rust
use scirs2_core::gpu::{GpuContext, GpuBackend, GpuBuffer};

// Create a GPU context with the default backend
let ctx = GpuContext::new(GpuBackend::default())?;

// Allocate memory on the GPU
let mut buffer = ctx.create_buffer::<f32>(1024);

// Execute a computation
ctx.execute(|compiler| {
    let kernel = compiler.compile(kernel_code)?;
    kernel.set_buffer(0, &mut buffer);
    kernel.dispatch([1024, 1, 1]);
    Ok(())
})?;
```

### Memory Management

```rust
use scirs2_core::memory::{ChunkProcessor2D, BufferPool, ZeroCopyView};

// Process large arrays in chunks
let mut processor = ChunkProcessor2D::new(&large_array, (1000, 1000));
processor.process_chunks(|chunk, coords| {
    // Process each chunk...
});

// Reuse memory with buffer pools
let mut pool = BufferPool::<f64>::new();
let mut buffer = pool.acquire_vec(1000);
// Use buffer...
pool.release_vec(buffer);
```

### Memory Metrics and Profiling

```rust
use scirs2_core::memory::metrics::{track_allocation, generate_memory_report};
use scirs2_core::profiling::{Profiler, Timer};

// Track memory allocations
track_allocation("MyComponent", 1024, 0x1000);

// Time a block of code
let timer = Timer::start("matrix_multiply");
// Do work...
timer.stop();

// Print profiling report
Profiler::global().lock().unwrap().print_report();
```

## Module Documentation

Each module has its own README with detailed documentation and is available on crates.io:

### Main Integration Crate
- [**scirs2**](scirs2/README.md): Main integration crate [![crates.io](https://img.shields.io/crates/v/scirs2.svg)](https://crates.io/crates/scirs2)

### Core Modules
- [**scirs2-core**](scirs2-core/README.md): Core utilities and common functionality [![crates.io](https://img.shields.io/crates/v/scirs2-core.svg)](https://crates.io/crates/scirs2-core)
- [**scirs2-linalg**](scirs2-linalg/README.md): Linear algebra module [![crates.io](https://img.shields.io/crates/v/scirs2-linalg.svg)](https://crates.io/crates/scirs2-linalg)
- [**scirs2-autograd**](scirs2-autograd/README.md): Automatic differentiation engine [![crates.io](https://img.shields.io/crates/v/scirs2-autograd.svg)](https://crates.io/crates/scirs2-autograd)
- [**scirs2-integrate**](scirs2-integrate/README.md): Numerical integration [![crates.io](https://img.shields.io/crates/v/scirs2-integrate.svg)](https://crates.io/crates/scirs2-integrate)
- [**scirs2-interpolate**](scirs2-interpolate/README.md): Interpolation algorithms [![crates.io](https://img.shields.io/crates/v/scirs2-interpolate.svg)](https://crates.io/crates/scirs2-interpolate)
- [**scirs2-optimize**](scirs2-optimize/README.md): Optimization algorithms [![crates.io](https://img.shields.io/crates/v/scirs2-optimize.svg)](https://crates.io/crates/scirs2-optimize)
- [**scirs2-fft**](scirs2-fft/README.md): Fast Fourier Transform [![crates.io](https://img.shields.io/crates/v/scirs2-fft.svg)](https://crates.io/crates/scirs2-fft)
- [**scirs2-stats**](scirs2-stats/README.md): Statistical functions [![crates.io](https://img.shields.io/crates/v/scirs2-stats.svg)](https://crates.io/crates/scirs2-stats)
- [**scirs2-special**](scirs2-special/README.md): Special mathematical functions [![crates.io](https://img.shields.io/crates/v/scirs2-special.svg)](https://crates.io/crates/scirs2-special)
- [**scirs2-signal**](scirs2-signal/README.md): Signal processing [![crates.io](https://img.shields.io/crates/v/scirs2-signal.svg)](https://crates.io/crates/scirs2-signal)
- [**scirs2-sparse**](scirs2-sparse/README.md): Sparse matrix operations [![crates.io](https://img.shields.io/crates/v/scirs2-sparse.svg)](https://crates.io/crates/scirs2-sparse)
- [**scirs2-spatial**](scirs2-spatial/README.md): Spatial algorithms [![crates.io](https://img.shields.io/crates/v/scirs2-spatial.svg)](https://crates.io/crates/scirs2-spatial)

### Advanced Modules
- [**scirs2-cluster**](scirs2-cluster/README.md): Clustering algorithms [![crates.io](https://img.shields.io/crates/v/scirs2-cluster.svg)](https://crates.io/crates/scirs2-cluster)
- [**scirs2-ndimage**](scirs2-ndimage/README.md): N-dimensional image processing [![crates.io](https://img.shields.io/crates/v/scirs2-ndimage.svg)](https://crates.io/crates/scirs2-ndimage)
- [**scirs2-io**](scirs2-io/README.md): Input/output utilities [![crates.io](https://img.shields.io/crates/v/scirs2-io.svg)](https://crates.io/crates/scirs2-io)
- [**scirs2-datasets**](scirs2-datasets/README.md): Sample datasets and loaders [![crates.io](https://img.shields.io/crates/v/scirs2-datasets.svg)](https://crates.io/crates/scirs2-datasets)

### AI/ML Modules
- [**scirs2-neural**](scirs2-neural/README.md): Neural network building blocks [![crates.io](https://img.shields.io/crates/v/scirs2-neural.svg)](https://crates.io/crates/scirs2-neural)
- **⚠️ scirs2-optim**: **Separated to independent [OptiRS](https://github.com/cool-japan/optirs) project from v0.1.0-beta.2**
- [**scirs2-graph**](scirs2-graph/README.md): Graph processing algorithms [![crates.io](https://img.shields.io/crates/v/scirs2-graph.svg)](https://crates.io/crates/scirs2-graph)
- [**scirs2-transform**](scirs2-transform/README.md): Data transformation utilities [![crates.io](https://img.shields.io/crates/v/scirs2-transform.svg)](https://crates.io/crates/scirs2-transform)
- [**scirs2-metrics**](scirs2-metrics/README.md): ML evaluation metrics [![crates.io](https://img.shields.io/crates/v/scirs2-metrics.svg)](https://crates.io/crates/scirs2-metrics)
- [**scirs2-text**](scirs2-text/README.md): Text processing utilities [![crates.io](https://img.shields.io/crates/v/scirs2-text.svg)](https://crates.io/crates/scirs2-text)
- [**scirs2-vision**](scirs2-vision/README.md): Computer vision operations [![crates.io](https://img.shields.io/crates/v/scirs2-vision.svg)](https://crates.io/crates/scirs2-vision)
- [**scirs2-series**](scirs2-series/README.md): Time series analysis [![crates.io](https://img.shields.io/crates/v/scirs2-series.svg)](https://crates.io/crates/scirs2-series)

## Implementation Strategy

We follow a phased approach:

1. **Core functionality analysis**: Identify key features and APIs of each SciPy module
2. **Prioritization**: Begin with highest-demand modules (linalg, stats, optimize)
3. **Interface design**: Balance Rust idioms with SciPy compatibility
4. **Scientific computing foundation**: Implement core scientific computing modules first
5. **Advanced modules**: Implement specialized modules for advanced scientific computing
6. **AI/ML infrastructure**: Develop specialized tools for AI and machine learning
7. **Integration and optimization**: Ensure all modules work together efficiently
8. **Ecosystem development**: Create tooling, documentation, and community resources

## Core Module Usage Policy

All modules in the SciRS2 ecosystem are expected to leverage functionality from scirs2-core:

- **Validation**: Use `scirs2-core::validation` for parameter checking
- **Error Handling**: Base module-specific errors on `scirs2-core::error::CoreError`
- **Numeric Operations**: Use `scirs2-core::numeric` for generic numeric functions
- **Optimization**: Use core-provided performance optimizations:
  - SIMD operations via `scirs2-core::simd`
  - Parallelism via `scirs2-core::parallel`
  - Memory management via `scirs2-core::memory`
  - Caching via `scirs2-core::cache`

## Dependency Management

SciRS2 uses workspace inheritance for consistent dependency versioning:

- All shared dependencies are defined in the root `Cargo.toml`
- Module crates reference dependencies with `workspace = true`
- Feature-gated dependencies use `workspace = true` with `optional = true`

```toml
# In workspace root Cargo.toml
[workspace.dependencies]
ndarray = { version = "0.16.1", features = ["serde", "rayon"] }
num-complex = "0.4.3"
rayon = "1.7.0"

# In module Cargo.toml
[dependencies]
ndarray = { workspace = true }
num-complex = { workspace = true }
rayon = { workspace = true, optional = true }

[features]
parallel = ["rayon"]
```

## Core Dependencies

SciRS2 leverages the Rust ecosystem:

### Core Dependencies
- `ndarray`: Multidimensional array operations
- `num`: Numeric abstractions
- `rayon`: Parallel processing
- `rustfft`: Fast Fourier transforms
- `ndarray-linalg`: Linear algebra computations
- `argmin`: Optimization algorithms
- `rand` and `rand_distr`: Random number generation and distributions

### AI/ML Dependencies
- `tch-rs`: Bindings to the PyTorch C++ API
- `burn`: Pure Rust neural network framework
- `tokenizers`: Fast tokenization utilities
- `image`: Image processing utilities
- `petgraph`: Graph algorithms and data structures

## What's New in v0.1.0-rc.1 (Released October 03, 2025)

### Major Enhancements

#### Complete Random Distribution Support
The `scirs2_core::random` module provides access to ALL `rand_distr` distributions:
- ✅ All continuous distributions (Beta, Cauchy, ChiSquared, FisherF, LogNormal, StudentT, Weibull, etc.)
- ✅ All discrete distributions (Binomial, Poisson, Geometric, Hypergeometric, etc.)
- ✅ All multivariate distributions (Dirichlet, UnitSphere, etc.)
- ✅ Unified distribution interface with enhanced sampling capabilities
- ✅ Full SciRS2 POLICY compliance - no direct `rand_distr` imports needed

#### Unified NDArray Module
The `scirs2_core::ndarray` module provides complete ndarray functionality:
- ✅ ALL ndarray functionality through single import point
- ✅ Essential macros available (`array!`, `s!`, `azip!`, `stack!`)
- ✅ Complete type access (Array, ArrayView, ArrayViewMut, etc.)
- ✅ Eliminates fragmentation across different modules
- ✅ Full backward compatibility with existing code

#### Build System Improvements
- **Removed `openblas-src`**: No longer builds BLAS from source, uses system libraries instead
  - macOS: Accelerate framework (system BLAS)
  - Linux: System OpenBLAS (openblas-system feature)
  - Windows: System BLAS libraries where available
- **Faster Builds**: Significantly reduced build times by eliminating BLAS source compilation
- **Platform Optimization**: Leverages platform-specific optimized BLAS implementations
- **Simplified Dependencies**: Removed `intel-mkl-src` to avoid system BLAS conflicts

#### Code Quality & Architecture Overhaul
- **100% POLICY Compliance**: All 23 crates fully comply with SciRS2 POLICY
  - Only `scirs2-core` has direct external dependencies
  - ~600+ import statements unified to `scirs2_core::` prefix
  - ~100+ external dependencies centralized
- **Zero Warnings Achievement**: Complete workspace builds with zero warnings
  - All 23 crates (lib, tests, examples) compile cleanly
  - Enhanced documentation coverage (100+ new doc comments)
- **Code Cleanup**: Significant TODO/FIXME reduction and refactoring
  - Removed obsolete markers, implemented pending features
  - Enhanced error handling and validation
- **Massive Scale**: 3,016 files modified in comprehensive RC.1 transformation
  - 18,081 insertions, 15,487 deletions
  - Major commits: POLICY migration, zero warnings fixes, TODO/FIXME cleanup

#### Migration Support
- 📖 [Migration Guide](MIGRATION_GUIDE_BETA3.md) for updating existing code
- 📖 Updated [SciRS2 POLICY](SCIRS2_POLICY.md) documentation
- 🚀 Validated integration with ToRSh and other ecosystem projects

For detailed migration instructions, see [MIGRATION_GUIDE_BETA3.md](MIGRATION_GUIDE_BETA3.md).

## Installation and Usage

SciRS2 and all its modules are available on [crates.io](https://crates.io/crates/scirs2). You can add them to your project using Cargo:

```toml
# Add the main integration crate for all functionality
[dependencies]
scirs2 = "0.1.0-rc.1"
```

Or include only the specific modules you need:

```toml
[dependencies]
# Core utilities
scirs2-core = "0.1.0-rc.1"

# Scientific computing modules
scirs2-linalg = "0.1.0-rc.1"
scirs2-stats = "0.1.0-rc.1"
scirs2-optimize = "0.1.0-rc.1"

# AI/ML modules
scirs2-neural = "0.1.0-rc.1"
scirs2-autograd = "0.1.0-rc.1"
# Note: For ML optimization algorithms, use the independent OptiRS project
```

### Example Usage

#### Basic Scientific Computing

```rust
// Using the main integration crate
use scirs2::prelude::*;
use ndarray::Array2;

fn main() -> Result<(), Box<dyn std::error::Error>> {
    // Create a matrix
    let a = Array2::from_shape_vec((3, 3), vec![
        1.0, 2.0, 3.0,
        4.0, 5.0, 6.0,
        7.0, 8.0, 9.0
    ])?;
    
    // Perform matrix operations
    let (u, s, vt) = scirs2::linalg::decomposition::svd(&a)?;
    
    println!("Singular values: {:.4?}", s);
    
    // Compute the condition number
    let cond = scirs2::linalg::basic::condition(&a, None)?;
    println!("Condition number: {:.4}", cond);
    
    // Generate random samples from a distribution
    let normal = scirs2::stats::distributions::normal::Normal::new(0.0, 1.0)?;
    let samples = normal.random_sample(5, None)?;
    println!("Random samples: {:.4?}", samples);
    
    Ok(())
}
```

#### Neural Network Example

```rust
use scirs2_neural::layers::{Dense, Layer};
use scirs2_neural::activations::{ReLU, Sigmoid};
use scirs2_neural::models::sequential::Sequential;
use scirs2_neural::losses::mse::MSE;
use scirs2_neural::optimizers::sgd::SGD;
use ndarray::{Array, Array2};

fn main() -> Result<(), Box<dyn std::error::Error>> {
    // Create a simple feedforward neural network
    let mut model = Sequential::new();
    
    // Add layers
    model.add(Dense::new(2, 8)?);
    model.add(ReLU::new());
    model.add(Dense::new(8, 4)?);
    model.add(ReLU::new());
    model.add(Dense::new(4, 1)?);
    model.add(Sigmoid::new());
    
    // Compile the model
    let loss = MSE::new();
    let optimizer = SGD::new(0.01);
    model.compile(loss, optimizer);
    
    // Create dummy data
    let x = Array2::from_shape_vec((4, 2), vec![
        0.0, 0.0,
        0.0, 1.0,
        1.0, 0.0,
        1.0, 1.0
    ])?;
    
    let y = Array2::from_shape_vec((4, 1), vec![
        0.0,
        1.0,
        1.0,
        0.0
    ])?;
    
    // Train the model
    model.fit(&x, &y, 1000, Some(32), Some(true));
    
    // Make predictions
    let predictions = model.predict(&x);
    println!("Predictions: {:.4?}", predictions);
    
    Ok(())
}
```

#### GPU-Accelerated Example

```rust
use scirs2_core::gpu::{GpuContext, GpuBackend};
use scirs2_linalg::batch::matrix_multiply_gpu;
use ndarray::Array3;

fn main() -> Result<(), Box<dyn std::error::Error>> {
    // Create GPU context
    let ctx = GpuContext::new(GpuBackend::default())?;
    
    // Create batch of matrices (batch_size x m x n)
    let a_batch = Array3::<f32>::ones((64, 128, 256));
    let b_batch = Array3::<f32>::ones((64, 256, 64));
    
    // Perform batch matrix multiplication on GPU
    let result = matrix_multiply_gpu(&ctx, &a_batch, &b_batch)?;
    
    println!("Batch matrix multiply result shape: {:?}", result.shape());
    
    Ok(())
}
```

## Platform Compatibility

SciRS2 v0.1.0-RC.1 has been tested on the following platforms:

### ✅ Fully Supported Platforms

| Platform | Architecture | Test Status | Notes |
|----------|-------------|-------------|-------|
| **macOS** | Apple M3 (ARM64) | ✅ All tests passing (9,800+ tests) | macOS 15.6.1, 24GB RAM |
| **Linux** | x86_64 | ✅ All tests passing (9,800+ tests) | With required dependencies |
| **Linux + CUDA** | x86_64 + NVIDIA GPU | ✅ All tests passing (9,800+ tests) | CUDA support enabled |

### ⚠️ Partially Supported Platforms

| Platform | Architecture | Test Status | Notes |
|----------|-------------|-------------|-------|
| **Windows** | x86_64 | ⚠️ Build succeeds, some tests fail | Windows 11 Pro - see known issues below |

### Platform-Specific Requirements

#### macOS / Linux
To run the full test suite with all features:
```bash
# Install required system libraries (OpenBLAS, LAPACK, etc.)
# Set necessary environment variables
cargo nextest run --nff --all-features  # 9,800+ tests
```

#### Windows
```bash
# Build works successfully
cargo build

# Note: Some crates have test failures on Windows
# Full test compatibility is planned for v0.2.0
cargo test  # Some tests may fail
```

### Running Tests

**Recommended test runner**: Use `cargo nextest` instead of `cargo test` for better performance and output:

```bash
# Install nextest
cargo install cargo-nextest

# Run all tests
cargo nextest run --nff --all-features
```

## Current Status (v0.1.0-rc.1 - Released October 03, 2025)

### 🎉 Key Features

#### SciRS2 POLICY Framework and Ecosystem Consistency
- **Ecosystem Architecture Policy**: Established layered abstraction architecture where only `scirs2-core` uses external dependencies directly
- **Consistent API Strategy**: All non-core crates now required to use scirs2-core abstractions for `rand`, `ndarray`, `num_complex`, etc.
- **Policy Documentation**: Comprehensive [SciRS2 Ecosystem Policy](SCIRS2_POLICY.md) with clear guidelines and benefits
- **Migration Strategy**: Systematic refactoring approach for better maintainability, version control, and type safety

#### Major Dependency Updates and Modernization
- **Comprehensive Updates**: Updated all dependencies to latest available versions with extensive testing
- **Enhanced Performance**: Improved SIMD operations, spatial algorithms, and numerical computations
- **Advanced Random Generation**: Enhanced ecosystem integration with cutting-edge MCMC and neural sampling
- **Memory Optimizations**: Advanced memory-mapped arrays with improved serialization and prefetching

#### GPU and Platform Support Enhancements
- **CUDA/Linux Improvements**: Significant CUDA backend optimizations for Linux platforms
- **WebGPU Backend**: Major enhancements (333+ lines) for better cross-platform GPU support
- **Memory-Mapped Operations**: Advanced chunking, zero-copy serialization, and efficient large dataset handling
- **Sparse Matrix GPU**: Enhanced GPU operation support for sparse matrix computations

#### Advanced Feature Stabilization
- **Real-time Processing**: Improved streaming capabilities in scirs2-io with better error handling
- **Distributed Computing**: Enhanced distributed processing with improved fault tolerance
- **Performance Validation**: Comprehensive SIMD performance validation with automated benchmarking
- **Advanced Interpolation**: Enhanced high-dimensional interpolation with parallel algorithms

#### Comprehensive Core Infrastructure Enhancement (Latest)
- **Ultra-Performance SIMD**: Achieved 14.17x performance improvement over scalar operations through cache-line aware processing, software pipelining, and TLB optimization
- **Complete GPU Kernel Infrastructure**: Multi-backend support (CUDA, ROCm, Metal, WGPU, OpenCL) with comprehensive elementwise, optimization, and utility kernels
- **Advanced Parallel Operations**: Tree reduction algorithms, work-stealing scheduler, NUMA-aware processing, and batch operations with progress tracking
- **Enhanced Error Handling**: Advanced recovery strategies, batch error handling, performance monitoring integration, and comprehensive validation framework
- **Expanded Mathematical Constants**: 70+ constants across scientific domains including quantum mechanics, thermodynamics, and spectroscopy
- **Comprehensive Chunking Strategies**: 10+ specialized strategies with performance monitoring, hardware awareness, and workload-specific optimizations
- **Advanced Memory Management**: Smart allocators, bandwidth optimization, advanced buffer pools, and NUMA topology awareness
- **Robust Testing Infrastructure**: Property-based testing, performance benchmarking with regression detection, and comprehensive scientific data generation
- **Complete API Documentation**: Detailed API reference, getting started guide, and extensive examples across all scientific computing domains

#### Ecosystem-Wide Ultra-Optimized SIMD Integration (COMPLETED 2025-Q4)
- **🎯 Signal Processing Enhancement**: Ultra-optimized convolution with bandwidth-saturated SIMD achieving 15-25x speedup, combined SIMD + parallel operations with potential 50-100x+ improvements
- **🧠 Autograd Enhancement**: Thread-safe autograd environments solving ToRSh integration issues, PyTorch-compatible backward() API, and SIMD-accelerated gradient computation
- **📡 FFT/Spectral Enhancement**: Bandwidth-saturated DCT/DST implementations, ultra-optimized Fractional Fourier Transform (15-25x speedup), TLB-optimized Fast Hankel Transform (10-18x speedup)
- **📊 Statistics/Monte Carlo Enhancement**: Ultra-optimized statistical moments, enhanced Monte Carlo methods (15-35x improvement), bootstrap sampling (20-30x speedup), QMC sequence generation (10-20x speedup)
- **🚀 Overall Impact**: Complete ecosystem transformation with 10-100x performance improvements across all scientific computing modules while maintaining API compatibility

## Current Status

### Stable Modules

The following SciRS2 modules are considered stable with well-tested core functionality:

#### Core Scientific Computing Modules
- **Linear Algebra Module** (`scirs2-linalg`): Basic matrix operations, decompositions, eigenvalue problems
- **Statistics Module** (`scirs2-stats`): Descriptive statistics, distributions, statistical tests, regression
- **Optimization Module** (`scirs2-optimize`): Unconstrained & constrained optimization, least squares, root finding
- **Integration Module** (`scirs2-integrate`): Numerical integration, ODE solvers
- **Interpolation Module** (`scirs2-interpolate`): 1D & ND interpolation, splines
- **Signal Processing** (`scirs2-signal`): Filtering, convolution, spectral analysis, wavelets
- **FFT Module** (`scirs2-fft`): FFT, inverse FFT, real FFT, DCT, DST, Hermitian FFT
- **Sparse Matrix** (`scirs2-sparse`): CSR, CSC, COO, BSR, DIA, DOK, LIL formats and operations
- **Special Functions** (`scirs2-special`): Gamma, Bessel, elliptic, orthogonal polynomials
- **Spatial Algorithms** (`scirs2-spatial`): KD-trees, distance calculations, convex hull, Voronoi diagrams
- **Clustering** (`scirs2-cluster`): K-means, hierarchical clustering, DBSCAN
- **Data Transformation** (`scirs2-transform`): Feature engineering, normalization
- **Evaluation Metrics** (`scirs2-metrics`): Classification, regression metrics

### Preview Modules

The following modules are in preview state and may undergo API changes:

#### Advanced Modules
- **N-dimensional Image Processing** (`scirs2-ndimage`): Filtering, morphology, measurements
- **I/O utilities** (`scirs2-io`): MATLAB, WAV, ARFF file formats, CSV
- **Datasets** (`scirs2-datasets`): Sample datasets and loaders

#### AI/ML Modules
- **Automatic Differentiation** (`scirs2-autograd`): Tensor ops, neural network primitives
- **Neural Networks** (`scirs2-neural`): Layers, activations, loss functions
- **ML Optimization**: **Moved to independent [OptiRS](https://github.com/cool-japan/optirs) project**
- **Graph Processing** (`scirs2-graph`): Graph algorithms and data structures
- **Text Processing** (`scirs2-text`): Tokenization, vectorization, word embeddings
- **Computer Vision** (`scirs2-vision`): Image processing, feature detection
- **Time Series Analysis** (`scirs2-series`): Decomposition, forecasting

### Advanced Core Features Implemented

- **GPU Acceleration** with backend abstraction layer (CUDA, WebGPU, Metal)
- **Memory Management** for large-scale computations
- **Logging and Diagnostics** with progress tracking
- **Profiling** with timing and memory tracking
- **Memory Metrics** for detailed memory usage analysis
- **Optimized SIMD Operations** for performance-critical code

### Key Capabilities

SciRS2 provides:
- **Advanced Error Handling**: Comprehensive error framework with recovery strategies, async support, and diagnostics engine
- **Computer Vision Registration**: Rigid, affine, homography, and non-rigid registration algorithms with RANSAC robustness
- **Performance Benchmarking**: Automated benchmarking framework with SciPy comparison and optimization tools
- **Numerical Precision**: High-precision eigenvalue solvers and optimized numerical algorithms
- **Parallel Processing**: Enhanced work-stealing scheduler, custom partitioning strategies, and nested parallelism
- **Arbitrary Precision**: Complete arbitrary precision arithmetic with GMP/MPFR backend
- **Numerical Stability**: Comprehensive algorithms for stable computation including Kahan summation and log-sum-exp

### Installation

All SciRS2 modules are available on crates.io. Add the modules you need to your `Cargo.toml`:

```toml
[dependencies]
scirs2 = "0.1.0-rc.1"  # Core library with all modules
# Or individual modules:
scirs2-linalg = "0.1.0-rc.1"  # Linear algebra
scirs2-stats = "0.1.0-rc.1"   # Statistics
# ... and more
```

For development roadmap and contribution guidelines, see [TODO.md](TODO.md) and [CONTRIBUTING.md](CONTRIBUTING.md).

## Performance Characteristics

SciRS2 prioritizes performance through several strategies:

- **Ultra-Optimized SIMD**: Advanced vectorization achieving up to 14.17x faster than scalar operations through cache-line aware processing, software pipelining, and TLB optimization
- **Multi-Backend GPU Acceleration**: Hardware acceleration across CUDA, ROCm, Metal, WGPU, and OpenCL for compute-intensive operations
- **Advanced Memory Management**: Smart allocators, bandwidth optimization, and NUMA-aware allocation strategies for large datasets
- **Work-Stealing Parallelism**: Advanced parallel algorithms with load balancing and NUMA topology awareness
- **Cache-Optimized Algorithms**: Data structures and algorithms designed for modern CPU cache hierarchies
- **Zero-cost Abstractions**: Rust's compiler optimizations eliminate runtime overhead while maintaining safety

Performance benchmarks on core operations show significant improvements over scalar implementations and competitive performance with NumPy/SciPy:

| Operation | SciRS2 (ms) | NumPy/SciPy (ms) | Speedup |
|-----------|-------------|------------------|---------|
| **Ultra-Optimized SIMD Operations** |  |  |  |
| SIMD Element-wise Operations (1M elements) | 0.71 | 10.05 | **14.17×** |
| Signal Convolution (bandwidth-saturated) | 2.1 | 52.5 | **25.0×** |
| Statistical Moments (ultra-optimized) | 1.8 | 45.3 | **25.2×** |
| Monte Carlo Bootstrap (SIMD) | 8.9 | 267.0 | **30.0×** |
| QMC Sequence Generation (Sobol) | 3.2 | 48.7 | **15.2×** |
| FFT Fractional Transform (FrFT) | 4.5 | 112.3 | **24.9×** |
| **Traditional Operations** |  |  |  |
| Matrix multiplication (1000×1000) | 18.5 | 23.2 | 1.25× |
| SVD decomposition (500×500) | 112.3 | 128.7 | 1.15× |
| FFT (1M points) | 8.7 | 11.5 | 1.32× |
| Normal distribution sampling (10M) | 42.1 | 67.9 | 1.61× |
| K-means clustering (100K points) | 321.5 | 378.2 | 1.18× |

*Note: Performance may vary based on hardware, compiler optimization, and specific workloads.*

## Core Module Usage Policy

Following the [SciRS2 Ecosystem Policy](SCIRS2_POLICY.md), all SciRS2 modules now follow a strict layered architecture:

- **Only `scirs2-core` uses external dependencies directly**
- **All other modules must use SciRS2-Core abstractions**
- **Benefits**: Consistent APIs, centralized version control, type safety, maintainability

### Required Usage Patterns

```rust
// ❌ FORBIDDEN in non-core crates
use rand::*;
use ndarray::Array2;
use num_complex::Complex;

// ✅ REQUIRED in non-core crates
use scirs2_core::random::*;
use scirs2_core::array::*;
use scirs2_core::complex::*;
```

This policy ensures ecosystem consistency and enables better optimization across the entire SciRS2 framework.

## Release Notes

### 🚀 v0.1.0-rc.1 (October 03, 2025) - Release Candidate 1

This release is the first Release Candidate, focusing on platform compatibility testing and final preparation for stable release:

#### ✅ Improvements:
- **Documentation Updates**: Comprehensive version updates across all documentation
- **Release Process**: Streamlined release workflow and version management
- **Ecosystem Stability**: Continued refinement of SciRS2 POLICY implementation
- **Testing Coverage**: Enhanced test coverage and CI/CD improvements

#### 🏗️ Ecosystem Refinements:
- **Policy Compliance**: Ongoing migration to scirs2-core abstractions
- **API Consistency**: Maintained SciPy compatibility while improving Rust idioms
- **Performance Validation**: Verified performance benchmarks across platforms

#### 📊 Status:
- ✅ **Build System**: All modules compile cleanly with zero warnings
- ✅ **Test Suite**: 9,800+ tests passing across all modules
- ✅ **Documentation**: Up-to-date examples and API references
- ✅ **Platform Support**: Verified on Linux, macOS, and Windows

**Migration:**
- No breaking API changes from beta.4
- See [RELEASE_NOTES.md](RELEASE_NOTES.md) for complete details

### Previous Beta Releases

**Beta Series (v0.1.0-beta.1 through beta.4)**:
- Established SciRS2 POLICY framework with layered abstraction architecture
- Implemented ultra-optimized SIMD operations (10-100x performance improvements)
- Added comprehensive GPU kernel infrastructure (CUDA, ROCm, Metal, WGPU, OpenCL)
- Enhanced ecosystem-wide performance and stability
- Full details available in [RELEASE_NOTES.md](RELEASE_NOTES.md)

## Known Limitations (Release Candidate)

This is the first Release Candidate (0.1.0-rc.1) of SciRS2, released October 03, 2025. While the core functionality is stable and well-tested, there are some known limitations:

### Platform-Specific Issues

#### Windows Platform
- **OpenBLAS/BLAS Runtime Errors**: Some tests fail on Windows 11 Pro due to OpenBLAS/BLAS library issues
- **Build Status**: All subcrates build successfully with `cargo build`
- **Test Status**: Most tests pass, but BLAS-dependent tests may encounter runtime errors
- **Full Support Timeline**: Complete Windows compatibility is planned for v0.2.0

### SciRS2 POLICY Implementation Status
- **Policy Established**: Complete SciRS2 POLICY framework with layered abstraction architecture
- **Core Abstractions Complete**: scirs2-core provides comprehensive abstractions for rand, ndarray, and all dependencies
- **Migration Status**: All modules updated to latest dependencies; core abstractions integration ongoing
- **Backward Compatibility**: Direct usage still works but core abstractions are recommended for new code

### Autograd Module
- **Gradient Shape Propagation**: Some complex operations may have limitations in gradient shape inference (Issue #1). Complex computation graphs may require manual shape specification in certain cases.
- **Graph Context Requirements**: Some stability tests require proper graph context initialization. Helper functions are provided in test utilities.

### Unimplemented Features
The following features are planned for future releases:
- **Cholesky decomposition** - Planned for 0.2.0
- **Thin Plate Spline solver** - Planned for 0.2.0
- Some advanced linear algebra decompositions

### Performance Tests
- Benchmark and performance tests are excluded from regular CI runs (404 tests marked as ignored) to optimize build times. Run with `cargo test -- --ignored` to execute full test suite including benchmarks.

### Hardware-Dependent Features
- GPU acceleration features require compatible hardware and drivers
- Tests automatically fall back to CPU implementations when GPU is unavailable
- Specialized hardware support (FPGA, ASIC) uses mock implementations when hardware is not present

### Test Coverage
- Total tests: 9,800+ across all modules
- Regular CI tests: All passing ✅
- Performance tests: Included in full test suite (run with `--all-features`)

For the most up-to-date information on limitations and ongoing development, please check our [GitHub Issues](https://github.com/cool-japan/scirs/issues).

## Contributing

Contributions are welcome! Please see our [CONTRIBUTING.md](CONTRIBUTING.md) for guidelines.

### Areas Where We Need Help

- **Core Algorithm Implementation**: Implementing remaining algorithms from SciPy
- **Performance Optimization**: Improving performance of existing implementations
- **Documentation**: Writing examples, tutorials, and API documentation
- **Testing**: Expanding test coverage and creating property-based tests
- **Integration with Other Ecosystems**: Python bindings, WebAssembly support
- **Domain-Specific Extensions**: Financial algorithms, geospatial tools, etc.

See our [TODO.md](TODO.md) for specific tasks and project roadmap.

## License

This project is dual-licensed under:

- [MIT License](LICENSE-MIT)
- [Apache License Version 2.0](LICENSE-APACHE)

You can choose to use either license.

## Acknowledgments

SciRS2 builds on the shoulders of giants:
- The SciPy and NumPy communities for their pioneering work
- The Rust ecosystem and its contributors
- The numerous mathematical and scientific libraries that inspired this project

## 🌐 Cool Japan Ecosystem

SciRS2 is part of the **Cool Japan Ecosystem** - a comprehensive collection of production-grade Rust libraries for scientific computing, machine learning, and data science. All ecosystem projects follow the [SciRS2 POLICY](SCIRS2_POLICY.md) for consistent architecture, leveraging scirs2-core abstractions for optimal performance and maintainability.

### 📊 Scientific Computing & Data Processing

#### [NumRS2](https://github.com/cool-japan/numrs)
**NumPy-compatible N-dimensional arrays in pure Rust**
- Pure Rust implementation of NumPy with 95%+ API coverage
- Zero-copy views, advanced broadcasting, and memory-efficient operations
- SIMD vectorization achieving 2-10x performance over Python NumPy

#### [PandRS](https://github.com/cool-japan/pandrs)
**Pandas-compatible DataFrames for high-performance data manipulation**
- Full Pandas API compatibility with Rust's safety guarantees
- Advanced indexing, groupby operations, and time series functionality
- 10-50x faster than Python pandas for large datasets

#### [QuantRS2](https://github.com/cool-japan/quantrs)
**Quantum computing library in pure Rust**
- Quantum circuit simulation and execution
- Quantum algorithm implementations
- Integration with quantum hardware backends

### 🤖 Machine Learning & Deep Learning

#### [OptiRS](https://github.com/cool-japan/optirs)
**Advanced ML optimization algorithms extending SciRS2**
- GPU-accelerated training (CUDA, ROCm, Metal) with 100x+ speedups
- 30+ optimizers: Adam, RAdam, Lookahead, LAMB, learned optimizers
- Neural Architecture Search (NAS), pruning, and quantization
- Distributed training with data/model parallelism and TPU coordination

#### [ToRSh](https://github.com/cool-japan/torsh)
**PyTorch-compatible deep learning framework in pure Rust**
- 100% SciRS2 integration across all 18 crates
- Dynamic computation graphs with eager execution
- Graph neural networks, transformers, time series, and computer vision
- Distributed training and ONNX export for production deployment

#### [TenfloweRS](https://github.com/cool-japan/tenflowers)
**TensorFlow-compatible ML framework with dual execution modes**
- Eager execution (PyTorch-style) and static graphs (TensorFlow-style)
- Cross-platform GPU acceleration via WGPU (Metal, Vulkan, DirectX)
- Built on NumRS2 and SciRS2 for numerical computing foundation
- Python bindings via PyO3 and ONNX support for model exchange

#### [SkleaRS](https://github.com/cool-japan/sklears)
**scikit-learn compatible machine learning library**
- 3-100x performance improvements over Python implementations
- Classification, regression, clustering, preprocessing, and model selection
- GPU acceleration, ONNX export, and AutoML capabilities

#### [TrustformeRS](https://github.com/cool-japan/trustformers)
**Hugging Face Transformers in pure Rust for production deployment**
- BERT, GPT-2/3/4, T5, BART, RoBERTa, DistilBERT, and more
- Full training infrastructure with mixed precision and gradient accumulation
- Optimized inference (1.5-3x faster than PyTorch) with quantization support

### 🎙️ Speech & Audio Processing

#### [VoiRS](https://github.com/cool-japan/voirs)
**Pure-Rust neural speech synthesis (Text-to-Speech)**
- State-of-the-art quality with VITS and DiffWave models (MOS 4.4+)
- Real-time performance: ≤0.3× RTF on CPUs, ≤0.05× RTF on GPUs
- Multi-platform support (x86_64, aarch64, WASM) with streaming synthesis
- SSML support and 20+ languages with pluggable G2P backends

### 🕸️ Semantic Web & Knowledge Graphs

#### [OxiRS](https://github.com/cool-japan/oxirs)
**Semantic Web platform with SPARQL 1.2, GraphQL, and AI reasoning**
- Rust-first alternative to Apache Jena + Fuseki with memory safety
- Advanced SPARQL 1.2 features: property paths, aggregation, federation
- GraphQL API with real-time subscriptions and schema stitching
- AI-augmented reasoning: embedding-based semantic search, LLM integration
- Vision transformers for image understanding and vector database integration

### 🔗 Ecosystem Integration

All Cool Japan Ecosystem projects share:
- **Unified Architecture**: SciRS2 POLICY compliance for consistent APIs
- **Performance First**: SIMD optimization, GPU acceleration, zero-cost abstractions
- **Production Ready**: Memory safety, comprehensive testing, battle-tested in production
- **Cross-Platform**: Linux, macOS, Windows, WebAssembly, mobile, and edge devices
- **Python Interop**: PyO3 bindings for seamless Python integration
- **Enterprise Support**: Professional documentation, active maintenance, community support

**Getting Started**: Each project includes comprehensive documentation, examples, and migration guides. Visit individual project repositories for detailed installation instructions and tutorials.

## Future Directions

- **Extended Hardware Support**: ARM, RISC-V, mobile, embedded
- **Cloud Deployment**: Container optimization, serverless function support
- **Domain-Specific Extensions**: Finance, bioinformatics, physics
- **Ecosystem Integration**: Python and Julia interoperability
- **Performance Monitoring**: Runtime analyzers, configuration optimizers
- **Automated Architecture Selection**: Hardware-aware algorithm choices

For more detailed information on development status and roadmap, check the [TODO.md](TODO.md) file.