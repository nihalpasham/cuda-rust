/*
 * SPDX-FileCopyrightText: Copyright (c) 2026 NVIDIA CORPORATION & AFFILIATES. All rights reserved.
 * SPDX-License-Identifier: Apache-2.0
 */

//! End-to-end Lean 4 verified vector addition (`c[i] = a[i] + b[i]`).
//!
//! Build and run with:
//!   cargo oxide run verified_vecadd

use cuda_core::{CudaContext, DeviceBuffer, LaunchConfig1D};
use cuda_device::{DisjointSlice, cuda_module, kernel, launch_contract, thread, verify};

/// Verified 1D vector addition module.
#[cuda_module]
mod kernels {
    use super::*;

    /// Vector addition kernel verified by Lean 4 at `PostMem2Reg`:
    /// - `no_oob_idx(a, b, c)`: every slice access stays within `0..len`
    /// - `disjoint_writes(c)`: distinct 1D threads never write the same slot
    /// - `writes_all_elems(c)`: every element in `0..c.len()` has a writer
    #[launch_contract(
        domain = 1,
        block = (256, 1, 1),
        requires = (a.len() >= c.len(), b.len() >= c.len()),
    )]
    #[verify(no_oob_idx(a, b, c), disjoint_writes(c), writes_all_elems(c))]
    #[kernel]
    pub fn vecadd(a: &[f32], b: &[f32], mut c: DisjointSlice<f32>) {
        let idx = thread::index_1d();
        let idx_raw = idx.get();
        if let Some(c_elem) = c.get_mut(idx) {
            *c_elem = a[idx_raw] + b[idx_raw];
        }
    }
}

fn main() -> Result<(), Box<dyn std::error::Error>> {
    println!("=== Lean-Verified Vector Addition ===\n");
    println!("Contract & Lean 4 Proof Summary:");
    println!("  • Launch contract: domain = 1, block = (256, 1, 1)");
    println!("  • Host requires:   a.len() >= c.len(), b.len() >= c.len()");
    println!("  • Lean 4 proved:   no_oob_idx(a, b, c)      [CudaOxide.Contracts.NoOobIdx]");
    println!("                     disjoint_writes(c)       [CudaOxide.Contracts.DisjointWrites]");
    println!("                     writes_all_elems(c)      [CudaOxide.Contracts.WritesAllElems]");
    println!("  • Codegen payoff:  a[idx] & b[idx] bounds checks elided before PTX lowering\n");

    let ctx = CudaContext::new(0)?;
    let stream = ctx.default_stream();

    const N: usize = 1000;
    const BLOCK_SIZE: u32 = 256;
    let a_host: Vec<f32> = (0..N).map(|i| i as f32).collect();
    let b_host: Vec<f32> = (0..N).map(|i| (i * 2) as f32).collect();

    let a_dev = DeviceBuffer::from_host(&stream, &a_host)?;
    let b_dev = DeviceBuffer::from_host(&stream, &b_host)?;
    let mut c_dev = DeviceBuffer::<f32>::zeroed(&stream, N)?;

    // SAFETY: this binary embeds the single `verified_vecadd` PTX module.
    let module = unsafe { kernels::load(&ctx)? };
    let blocks = (N as u32).div_ceil(BLOCK_SIZE);
    let launch = module.prepare_vecadd(LaunchConfig1D::new(blocks, BLOCK_SIZE, 0))?;

    // Safe, contract-checked launch: enforces `a.len() >= c.len()` and
    // `b.len() >= c.len()` on the host before launching the Lean-verified PTX.
    module.vecadd(&stream, &launch, &a_dev, &b_dev, &mut c_dev)?;

    let c_host = c_dev.to_host_vec(&stream)?;
    for i in 0..N {
        let expected = a_host[i] + b_host[i];
        assert!(
            (c_host[i] - expected).abs() <= 1e-5,
            "mismatch at index {i}: expected {expected}, got {}",
            c_host[i]
        );
    }

    println!("Verified launch succeeded: all {N} elements match!");
    Ok(())
}
