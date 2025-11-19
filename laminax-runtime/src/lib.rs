//! Laminax Runtime - Execution Engine and Computational Graph Management
//!
//! This crate provides the runtime execution capabilities for Laminax,
//! including computational graph representation, device abstraction, memory
//! management, and kernel execution.

use laminax_lcir::{self as lcir, MemoryScope};
use std::collections::HashMap;
use std::sync::Arc;

pub mod device;
pub mod execution;
pub mod graph;
pub mod memory;

pub use execution::{Executor, KernelInstance};
pub use graph::{ComputationGraph, Edge, ExecutionPlan, Node};
pub use memory::{Buffer, MemoryManager};

// Re-export device abstraction layer
pub use device::*;
use crate::cpu::CpuDevice;

/// Runtime error types
#[derive(Debug)]
pub enum RuntimeError {
    /// Error occurred because of device internal failure.
    Device(String),
    /// Error occurred because of memory failure such as double free or out of memory.
    Memory(String),
    /// Error occurred because of invalid graph topology.
    Graph(String),
    /// Error occurred because requested operation was illegal.
    Execution(String),
    /// Error occurred because of failed compilation
    Compilation(String),
}

impl std::fmt::Display for RuntimeError {
    fn fmt(&self, f: &mut std::fmt::Formatter<'_>) -> std::fmt::Result {
        match self {
            RuntimeError::Device(msg) => write!(f, "Device error: {}", msg),
            RuntimeError::Memory(msg) => write!(f, "Memory error: {}", msg),
            RuntimeError::Graph(msg) => write!(f, "Graph error: {}", msg),
            RuntimeError::Execution(msg) => write!(f, "Execution error: {}", msg),
            RuntimeError::Compilation(msg) => write!(f, "Compilation error: {}", msg),
        }
    }
}

impl std::error::Error for RuntimeError {}

pub type Result<T> = std::result::Result<T, RuntimeError>;

pub enum SupportedRuntime {
    Cpu(Arc<CpuDevice>),
    #[cfg(feature = "vulkan")]
    Vulkan(Arc<vulkan::VulkanDevice>),
}

/// Main runtime context managing devices, memory, and execution
pub struct Runtime {
    supported: Vec<SupportedRuntime>,
}

impl Runtime {
    /// Create a new runtime with available devices
    pub fn new(requirements: DeviceCapabilities) -> Result<Self> {
        let devices = enumerate_devices(requirements)?;

        Ok(Self {
            supported: devices,
        })
    }

    /// Get all available devices
    pub fn devices(&self) -> &[SupportedRuntime] {
        &self.supported
    }

    /// Get the default CPU device
    pub fn host_device(&self) -> Option<&Arc<CpuDevice>> {
        self.supported
            .iter()
            .find_map(|d| match d {
                SupportedRuntime::Cpu(d) => Some(d),
                _ => None,
            })
    }

    /// Create an executor for running computations
    pub fn executor<D: Device>(&self) -> Option<Executor<D>> {
        unimplemented!("Device Lookup is not implemented")
        // Executor::new(device, Arc::clone(&self.memory_manager))
    }

    /// Execute a kernel directly (convenience method)
    pub fn execute_kernel(
        &self,
        kernel: &lcir::Kernel,
        inputs: HashMap<String, Vec<u8>>,
    ) -> Result<HashMap<String, Vec<u8>>> {
        let graph = ComputationGraph::from_lcir(kernel)?;
        let device = self
            .host_device()
            .ok_or_else(|| RuntimeError::Device("No CPU device available".to_string()))?
            .clone();

        let mut executor = self.executor(device)?;
        let plan = ExecutionPlan::from_graph(&graph)?;

        // Allocate buffers and transfer input data
        let mut buffers = HashMap::new();
        for (tensor_id, tensor_info) in &kernel.tensors {
            let buffer = if let Some(input_data) = inputs.get(&tensor_info.name) {
                executor.allocate_buffer_with_data(
                    tensor_info.shape.clone(),
                    tensor_info.dtype,
                    input_data.clone(),
                )?
            } else {
                executor.allocate_buffer(tensor_info.shape.clone(), tensor_info.dtype)?
            };
            buffers.insert(*tensor_id, buffer);
        }

        // Execute the plan
        executor.execute_plan(&plan, &buffers)?;

        // Extract output data
        let mut outputs = HashMap::new();
        for (tensor_id, tensor_info) in &kernel.tensors {
            if tensor_info.scope == MemoryScope::Global {
                // Assume outputs are tensors that aren't in inputs
                if !inputs.contains_key(&tensor_info.name) {
                    let buffer = buffers.get(tensor_id).unwrap();
                    let data = executor.read_buffer(buffer)?;
                    outputs.insert(tensor_info.name.clone(), data);
                }
            }
        }

        Ok(outputs)
    }
}

/// Convenience function to run a simple kernel (for examples/demos)
pub fn execute_simple_kernel(
    kernel: &lcir::Kernel,
    inputs: HashMap<String, Vec<u8>>,
) -> Result<HashMap<String, Vec<u8>>> {
    let runtime = Runtime::new()?;
    runtime.execute_kernel(kernel, inputs)
}

impl From<Arc<CpuDevice>> for SupportedRuntime {
    fn from(value: Arc<CpuDevice>) -> Self {
        Self::Cpu(value)
    }
}

#[cfg(feature = "vulkan")]
impl From<Arc<vulkan::VulkanDevice>> for SupportedRuntime {
    fn from(value: Arc<vulkan::VulkanDevice>) -> Self {
        Self::Vulkan(value)
    }
}

#[cfg(test)]
mod tests {
    use super::*;
    use laminax_lcir::{KernelBuilder, MemoryScope, access, index};
    use laminax_types::{I32, Shape};

    #[test]
    fn test_end_to_end_execution() {
        // Create a simple kernel: C = A + B (element-wise addition)
        let mut builder = KernelBuilder::new("add_kernel");

        let a_id = builder.add_tensor("A", Shape::from([4]), I32, MemoryScope::Global);
        let b_id = builder.add_tensor("B", Shape::from([4]), I32, MemoryScope::Global);
        let c_id = builder.add_tensor("C", Shape::from([4]), I32, MemoryScope::Global);

        // Simple loop over elements (simplified - real version would have proper nested loops)
        let i_loop = builder.add_loop("i", 0, 4, 1);

        let a_access = access::global(a_id, vec![index::loop_var(i_loop)]);
        let b_access = access::global(b_id, vec![index::loop_var(i_loop)]);
        let c_access = access::global(c_id, vec![index::loop_var(i_loop)]);

        builder.add_binary_op(c_access, a_access, lcir::BinaryOp::Add, b_access);

        let kernel = builder.build();

        // Prepare input data
        let a_data = vec![1i32, 2, 3, 4];
        let b_data = vec![10i32, 20, 30, 40];
        let expected_c = vec![11i32, 22, 33, 44];

        let mut inputs = HashMap::new();
        inputs.insert("A".to_string(), unsafe {
            std::slice::from_raw_parts(a_data.as_ptr() as *const u8, a_data.len() * 4).to_vec()
        });
        inputs.insert("B".to_string(), unsafe {
            std::slice::from_raw_parts(b_data.as_ptr() as *const u8, b_data.len() * 4).to_vec()
        });

        // Execute the kernel
        let outputs = execute_simple_kernel(&kernel, inputs).unwrap();

        // Check the result
        let c_result = outputs.get("C").unwrap();
        let c_values: Vec<i32> = c_result.chunks(4)
            .map(|chunk| i32::from_le_bytes(chunk.try_into().unwrap()))
            .collect();

        assert_eq!(c_values, expected_c);
        println!("Execution successful! Result: {:?}", c_values);
    }
}
