//! WebGPU/native GPU solver backend for pow-buster message families.
//!
//! The same Rust implementation targets native `wgpu` backends and browser WebGPU on `wasm32`.

use core::{fmt, num::NonZeroU8};
use std::{borrow::Cow, string::String, vec::Vec};

use bytemuck::{Pod, Zeroable};
use sha2::{Digest, Sha256};

const WG_SIZE: u32 = 64;
const STEPS: u32 = 128;
const HASHES_PER_WG: u64 = WG_SIZE as u64 * STEPS as u64;
const CANCEL_INTERVAL: u32 = 16;
const COUNTER_SPACE: u64 = 1_u64 << 54;

#[inline]
fn gpu_batch_target(expected_work: u64, quantum: u64) -> u64 {
    expected_work.saturating_mul(3).div_ceil(10).max(quantum)
}

/// Error returned by the GPU solver.
#[derive(Debug, Clone)]
pub struct GpuError(String);

impl GpuError {
    fn new(message: impl Into<String>) -> Self {
        Self(message.into())
    }
}

impl fmt::Display for GpuError {
    fn fmt(&self, f: &mut fmt::Formatter<'_>) -> fmt::Result {
        f.write_str(&self.0)
    }
}

impl std::error::Error for GpuError {}

/// Successful GPU proof-of-work solution.
#[derive(Debug, Clone, Copy, PartialEq, Eq)]
pub struct GpuSolution {
    /// Solver nonce.
    pub nonce: u64,
    /// Solver digest/output words.
    pub hash: [u32; 8],
    /// Candidate hashes submitted through the winning batch.
    ///
    /// Workgroups stop cooperatively after a hit, so this is an upper bound on hashes actually executed.
    pub dispatched_hashes: u64,
}

#[repr(C)]
#[derive(Clone, Copy, Pod, Zeroable)]
struct Params {
    words: [u32; 16],
}

/// Reusable GPU device/context shared by all GPU solver instances.
///
/// Native builds use the best backend selected by `wgpu`; wasm builds use browser WebGPU.
pub struct GpuContext {
    device: wgpu::Device,
    queue: wgpu::Queue,
    pipeline: wgpu::ComputePipeline,
    in_buf: wgpu::Buffer,
    generic_pipeline: wgpu::ComputePipeline,
    double_pipeline: wgpu::ComputePipeline,
    goaway_pipeline: wgpu::ComputePipeline,
    binary_pipeline: wgpu::ComputePipeline,
    cerberus_pipeline: wgpu::ComputePipeline,
    altcha_pipeline: wgpu::ComputePipeline,
    generic_in_buf: wgpu::Buffer,
    out_buf: wgpu::Buffer,
    staging: wgpu::Buffer,
    bind_group: wgpu::BindGroup,
    generic_bind_group: wgpu::BindGroup,
    double_bind_group: wgpu::BindGroup,
    goaway_bind_group: wgpu::BindGroup,
    binary_bind_group: wgpu::BindGroup,
    cerberus_bind_group: wgpu::BindGroup,
    altcha_bind_group: wgpu::BindGroup,
    max_wgs: u32,
    adapter: String,
}

impl GpuContext {
    /// Create a GPU solver using the high-performance adapter selected by `wgpu`.
    pub async fn create() -> Result<Self, GpuError> {
        let instance =
            wgpu::Instance::new(wgpu::InstanceDescriptor::new_without_display_handle_from_env());
        let adapter = instance
            .request_adapter(&wgpu::RequestAdapterOptions {
                power_preference: wgpu::PowerPreference::HighPerformance,
                ..Default::default()
            })
            .await
            .map_err(|e| GpuError::new(format!("request GPU adapter: {e}")))?;
        let info = adapter.get_info();
        let adapter_name = format!("{} ({:?}, {})", info.name, info.backend, info.driver);
        let limits = adapter.limits();
        let (device, queue) = adapter
            .request_device(&wgpu::DeviceDescriptor {
                required_limits: wgpu::Limits::downlevel_defaults(),
                ..Default::default()
            })
            .await
            .map_err(|e| GpuError::new(format!("request GPU device: {e}")))?;

        let shader = device.create_shader_module(wgpu::ShaderModuleDescriptor {
            label: Some("pow-buster-anubis"),
            source: wgpu::ShaderSource::Wgsl(Cow::Owned(shader_source())),
        });
        let pipeline = device.create_compute_pipeline(&wgpu::ComputePipelineDescriptor {
            label: Some("pow-buster-anubis"),
            layout: None,
            module: &shader,
            entry_point: Some("solve"),
            compilation_options: Default::default(),
            cache: None,
        });
        let generic_shader = device.create_shader_module(wgpu::ShaderModuleDescriptor {
            label: Some("pow-buster-sha256-single-block"),
            source: wgpu::ShaderSource::Wgsl(Cow::Owned(generic_single_block_shader_source())),
        });
        let generic_pipeline = device.create_compute_pipeline(&wgpu::ComputePipelineDescriptor {
            label: Some("pow-buster-sha256-single-block"),
            layout: None,
            module: &generic_shader,
            entry_point: Some("solve"),
            compilation_options: Default::default(),
            cache: None,
        });
        let multi_shader = device.create_shader_module(wgpu::ShaderModuleDescriptor {
            label: Some("pow-buster-sha256-multi-layout"),
            source: wgpu::ShaderSource::Wgsl(Cow::Owned(multi_layout_shader_source())),
        });
        let create_multi_pipeline = |label, mode| {
            let constants = [("MODE", mode)];
            device.create_compute_pipeline(&wgpu::ComputePipelineDescriptor {
                label: Some(label),
                layout: None,
                module: &multi_shader,
                entry_point: Some("solve"),
                compilation_options: wgpu::PipelineCompilationOptions {
                    constants: &constants,
                    ..Default::default()
                },
                cache: None,
            })
        };
        let double_pipeline = create_multi_pipeline("pow-buster-sha256-double-block", 1.0);
        let goaway_pipeline = create_multi_pipeline("pow-buster-sha256-goaway", 2.0);
        let binary_pipeline = create_multi_pipeline("pow-buster-sha256-binary", 3.0);
        let cerberus_shader = device.create_shader_module(wgpu::ShaderModuleDescriptor {
            label: Some("pow-buster-cerberus"),
            source: wgpu::ShaderSource::Wgsl(Cow::Owned(cerberus_shader_source())),
        });
        let cerberus_pipeline = device.create_compute_pipeline(&wgpu::ComputePipelineDescriptor {
            label: Some("pow-buster-cerberus"),
            layout: None,
            module: &cerberus_shader,
            entry_point: Some("solve"),
            compilation_options: Default::default(),
            cache: None,
        });
        let altcha_shader = device.create_shader_module(wgpu::ShaderModuleDescriptor {
            label: Some("pow-buster-altcha"),
            source: wgpu::ShaderSource::Wgsl(Cow::Owned(altcha_shader_source())),
        });
        let altcha_pipeline = device.create_compute_pipeline(&wgpu::ComputePipelineDescriptor {
            label: Some("pow-buster-altcha"),
            layout: None,
            module: &altcha_shader,
            entry_point: Some("solve"),
            compilation_options: Default::default(),
            cache: None,
        });
        let in_buf = device.create_buffer(&wgpu::BufferDescriptor {
            label: Some("pow-buster-anubis-input"),
            size: 64,
            usage: wgpu::BufferUsages::UNIFORM | wgpu::BufferUsages::COPY_DST,
            mapped_at_creation: false,
        });
        let generic_in_buf = device.create_buffer(&wgpu::BufferDescriptor {
            label: Some("pow-buster-sha256-single-block-input"),
            size: 256,
            usage: wgpu::BufferUsages::STORAGE | wgpu::BufferUsages::COPY_DST,
            mapped_at_creation: false,
        });
        let out_buf = device.create_buffer(&wgpu::BufferDescriptor {
            label: Some("pow-buster-anubis-output"),
            size: 48,
            usage: wgpu::BufferUsages::STORAGE
                | wgpu::BufferUsages::COPY_SRC
                | wgpu::BufferUsages::COPY_DST,
            mapped_at_creation: false,
        });
        let staging = device.create_buffer(&wgpu::BufferDescriptor {
            label: Some("pow-buster-anubis-staging"),
            size: 48,
            usage: wgpu::BufferUsages::MAP_READ | wgpu::BufferUsages::COPY_DST,
            mapped_at_creation: false,
        });
        let bind_group = device.create_bind_group(&wgpu::BindGroupDescriptor {
            label: Some("pow-buster-anubis"),
            layout: &pipeline.get_bind_group_layout(0),
            entries: &[
                wgpu::BindGroupEntry {
                    binding: 0,
                    resource: in_buf.as_entire_binding(),
                },
                wgpu::BindGroupEntry {
                    binding: 1,
                    resource: out_buf.as_entire_binding(),
                },
            ],
        });
        let generic_bind_group = device.create_bind_group(&wgpu::BindGroupDescriptor {
            label: Some("pow-buster-sha256-single-block"),
            layout: &generic_pipeline.get_bind_group_layout(0),
            entries: &[
                wgpu::BindGroupEntry {
                    binding: 0,
                    resource: generic_in_buf.as_entire_binding(),
                },
                wgpu::BindGroupEntry {
                    binding: 1,
                    resource: out_buf.as_entire_binding(),
                },
            ],
        });
        let make_multi_bind_group = |label: &'static str, pipeline: &wgpu::ComputePipeline| {
            device.create_bind_group(&wgpu::BindGroupDescriptor {
                label: Some(label),
                layout: &pipeline.get_bind_group_layout(0),
                entries: &[
                    wgpu::BindGroupEntry {
                        binding: 0,
                        resource: generic_in_buf.as_entire_binding(),
                    },
                    wgpu::BindGroupEntry {
                        binding: 1,
                        resource: out_buf.as_entire_binding(),
                    },
                ],
            })
        };
        let double_bind_group =
            make_multi_bind_group("pow-buster-sha256-double-block", &double_pipeline);
        let goaway_bind_group = make_multi_bind_group("pow-buster-sha256-goaway", &goaway_pipeline);
        let binary_bind_group = make_multi_bind_group("pow-buster-sha256-binary", &binary_pipeline);
        let cerberus_bind_group = device.create_bind_group(&wgpu::BindGroupDescriptor {
            label: Some("pow-buster-cerberus"),
            layout: &cerberus_pipeline.get_bind_group_layout(0),
            entries: &[
                wgpu::BindGroupEntry {
                    binding: 0,
                    resource: generic_in_buf.as_entire_binding(),
                },
                wgpu::BindGroupEntry {
                    binding: 1,
                    resource: out_buf.as_entire_binding(),
                },
            ],
        });

        let altcha_bind_group = device.create_bind_group(&wgpu::BindGroupDescriptor {
            label: Some("pow-buster-altcha"),
            layout: &altcha_pipeline.get_bind_group_layout(0),
            entries: &[
                wgpu::BindGroupEntry {
                    binding: 0,
                    resource: generic_in_buf.as_entire_binding(),
                },
                wgpu::BindGroupEntry {
                    binding: 1,
                    resource: out_buf.as_entire_binding(),
                },
            ],
        });

        Ok(Self {
            device,
            queue,
            pipeline,
            in_buf,
            generic_pipeline,
            double_pipeline,
            goaway_pipeline,
            binary_pipeline,
            cerberus_pipeline,
            altcha_pipeline,
            generic_in_buf,
            out_buf,
            staging,
            bind_group,
            generic_bind_group,
            double_bind_group,
            goaway_bind_group,
            binary_bind_group,
            cerberus_bind_group,
            altcha_bind_group,
            max_wgs: limits.max_compute_workgroups_per_dimension,
            adapter: adapter_name,
        })
    }

    /// Submit a small representative batch to force lazy browser/driver shader setup.
    ///
    /// Browser WebGPU implementations may defer substantial pipeline work until the first submit.
    /// Extensions can call this once during startup so the first real challenge does not pay that cost.
    pub async fn warm_up(&mut self) -> Result<(), GpuError> {
        let mut params = Params { words: [0; 16] };
        params.words[..8].copy_from_slice(&crate::sha256::IV);
        params.words[10] = 19 * 8;
        params.words[11] = u32::MAX;
        params.words[12] = u32::MAX;
        self.queue.write_buffer(&self.out_buf, 0, &[0; 48]);
        self.queue
            .write_buffer(&self.in_buf, 0, bytemuck::bytes_of(&params));
        self.queue.write_buffer(&self.generic_in_buf, 0, &[0; 256]);
        let mut encoder = self
            .device
            .create_command_encoder(&wgpu::CommandEncoderDescriptor {
                label: Some("pow-buster-anubis-warmup"),
            });
        {
            let mut pass = encoder.begin_compute_pass(&wgpu::ComputePassDescriptor {
                label: Some("pow-buster-anubis-warmup"),
                timestamp_writes: None,
            });
            pass.set_pipeline(&self.pipeline);
            pass.set_bind_group(0, &self.bind_group, &[]);
            pass.dispatch_workgroups(64, 1, 1);
        }
        for (label, pipeline, bind_group) in [
            (
                "pow-buster-sha256-single-block-warmup",
                &self.generic_pipeline,
                &self.generic_bind_group,
            ),
            (
                "pow-buster-sha256-double-block-warmup",
                &self.double_pipeline,
                &self.double_bind_group,
            ),
            (
                "pow-buster-sha256-goaway-warmup",
                &self.goaway_pipeline,
                &self.goaway_bind_group,
            ),
            (
                "pow-buster-sha256-binary-warmup",
                &self.binary_pipeline,
                &self.binary_bind_group,
            ),
            (
                "pow-buster-cerberus-warmup",
                &self.cerberus_pipeline,
                &self.cerberus_bind_group,
            ),
            (
                "pow-buster-altcha-warmup",
                &self.altcha_pipeline,
                &self.altcha_bind_group,
            ),
        ] {
            let mut pass = encoder.begin_compute_pass(&wgpu::ComputePassDescriptor {
                label: Some(label),
                timestamp_writes: None,
            });
            pass.set_pipeline(pipeline);
            pass.set_bind_group(0, bind_group, &[]);
            pass.dispatch_workgroups(1, 1, 1);
        }
        encoder.copy_buffer_to_buffer(&self.out_buf, 0, &self.staging, 0, 48);
        self.queue.submit([encoder.finish()]);
        let _ = self.read_result().await?;
        Ok(())
    }

    /// Human-readable adapter/backend description.
    pub fn adapter(&self) -> &str {
        &self.adapter
    }

    /// Solve an Anubis SHA-256 challenge.
    pub async fn solve_anubis(
        &mut self,
        prefix: &[u8],
        difficulty: NonZeroU8,
    ) -> Result<GpuSolution, GpuError> {
        self.solve_anubis_with_limit(prefix, difficulty, COUNTER_SPACE)
            .await?
            .ok_or_else(|| GpuError::new("GPU search space exhausted"))
    }

    /// Solve an Anubis SHA-256 challenge while dispatching at most `max_hashes` candidates.
    pub async fn solve_anubis_with_limit(
        &mut self,
        prefix: &[u8],
        difficulty: NonZeroU8,
        max_hashes: u64,
    ) -> Result<Option<GpuSolution>, GpuError> {
        if prefix.len() % 64 != 0 {
            return Err(GpuError::new(format!(
                "GPU Anubis solver requires a block-aligned prefix, got {} bytes",
                prefix.len()
            )));
        }
        if difficulty.get() > 16 {
            return Err(GpuError::new("Anubis GPU difficulty must be <= 16"));
        }
        let bitlen = prefix
            .len()
            .checked_add(19)
            .and_then(|n| n.checked_mul(8))
            .and_then(|n| u32::try_from(n).ok())
            .ok_or_else(|| GpuError::new("challenge is too large for the GPU kernel"))?;

        let mid = midstate(prefix);
        let mask = crate::compute_mask_anubis(difficulty);
        let mut params = Params { words: [0; 16] };
        params.words[..8].copy_from_slice(&mid);
        params.words[10] = bitlen;
        params.words[11] = (mask >> 32) as u32;
        params.words[12] = mask as u32;
        self.queue.write_buffer(&self.out_buf, 0, &[0; 48]);

        let expected = 16_u64.saturating_pow(u32::from(difficulty.get()));
        let desired = gpu_batch_target(expected, HASHES_PER_WG);
        let limit = max_hashes.min(COUNTER_SPACE);
        let mut base = 0_u64;

        while base < limit {
            let remaining = limit - base;
            let batch = desired
                .min(remaining)
                .min(u64::from(self.max_wgs) * HASHES_PER_WG);
            let wgs = batch.div_ceil(HASHES_PER_WG).max(1) as u32;
            params.words[8] = base as u32;
            params.words[9] = (base >> 32) as u32;
            self.queue
                .write_buffer(&self.in_buf, 0, bytemuck::bytes_of(&params));

            let mut encoder = self
                .device
                .create_command_encoder(&wgpu::CommandEncoderDescriptor {
                    label: Some("pow-buster-anubis-solve"),
                });
            {
                let mut pass = encoder.begin_compute_pass(&wgpu::ComputePassDescriptor {
                    label: Some("pow-buster-anubis-solve"),
                    timestamp_writes: None,
                });
                pass.set_pipeline(&self.pipeline);
                pass.set_bind_group(0, &self.bind_group, &[]);
                pass.dispatch_workgroups(wgs, 1, 1);
            }
            encoder.copy_buffer_to_buffer(&self.out_buf, 0, &self.staging, 0, 48);
            self.queue.submit([encoder.finish()]);

            let values = self.read_result().await?;
            let dispatched = base.saturating_add(u64::from(wgs) * HASHES_PER_WG);
            if values[0] != 0 {
                let counter = (u64::from(values[2]) << 32) | u64::from(values[1]);
                let nonce = counter_to_decimal_nonce(counter);
                let hash: [u32; 8] = values[3..11]
                    .try_into()
                    .map_err(|_| GpuError::new("invalid GPU result layout"))?;
                if !verify(prefix, nonce, hash, mask) {
                    return Err(GpuError::new("GPU returned an invalid Anubis proof"));
                }
                return Ok(Some(GpuSolution {
                    nonce,
                    hash,
                    dispatched_hashes: dispatched,
                }));
            }
            base = dispatched;
        }

        Ok(None)
    }

    /// Solve a parsed Anubis challenge descriptor.
    #[cfg(feature = "adapter")]
    pub async fn solve_anubis_descriptor(
        &mut self,
        descriptor: &crate::adapter::anubis::ChallengeDescriptor,
    ) -> Result<GpuSolution, GpuError> {
        if descriptor.rules().algorithm() == "preact" {
            return Err(GpuError::new(
                "preact challenges do not require GPU proof-of-work",
            ));
        }
        if !descriptor.supported() {
            return Err(GpuError::new("unsupported Anubis algorithm"));
        }
        let difficulty = NonZeroU8::new(descriptor.rules().difficulty())
            .ok_or_else(|| GpuError::new("Anubis difficulty must be non-zero"))?;
        self.solve_anubis(descriptor.challenge().as_ref().as_bytes(), difficulty)
            .await
    }

    async fn solve_single_block_inner<const TYPE: u8>(
        &mut self,
        message: &crate::message::SingleBlockMessage,
        target: u64,
        mask: u64,
        limit: u64,
    ) -> Result<Option<GpuSolution>, GpuError> {
        if !matches!(
            TYPE,
            crate::solver::SOLVE_TYPE_LT
                | crate::solver::SOLVE_TYPE_GT
                | crate::solver::SOLVE_TYPE_MASK
        ) {
            return Err(GpuError::new("unsupported solve type"));
        }

        if TYPE == crate::solver::SOLVE_TYPE_MASK
            && target == 0
            && single_block_fast_compatible(message)
        {
            return self
                .solve_fast_single_block_message(message, mask, limit)
                .await;
        }

        self.solve_generic_single_block::<TYPE>(message, target, mask, limit)
            .await
    }

    async fn solve_fast_single_block_message(
        &mut self,
        message: &crate::message::SingleBlockMessage,
        mask: u64,
        max_hashes: u64,
    ) -> Result<Option<GpuSolution>, GpuError> {
        let mut params = Params { words: [0; 16] };
        params.words[..8].copy_from_slice(&message.prefix_state);
        params.words[10] = message.message[15];
        params.words[11] = (mask >> 32) as u32;
        params.words[12] = if cfg!(feature = "compare-64bit") {
            mask as u32
        } else {
            0
        };
        self.queue.write_buffer(&self.out_buf, 0, &[0; 48]);

        let desired = gpu_batch_target(
            expected_work::<{ crate::solver::SOLVE_TYPE_MASK }>(0, mask),
            HASHES_PER_WG,
        );
        let limit = max_hashes.min(COUNTER_SPACE);
        let mut base = 0_u64;

        while base < limit {
            let remaining = limit - base;
            let batch = desired
                .min(remaining)
                .min(u64::from(self.max_wgs) * HASHES_PER_WG);
            let wgs = batch.div_ceil(HASHES_PER_WG).max(1) as u32;
            params.words[8] = base as u32;
            params.words[9] = (base >> 32) as u32;
            self.queue
                .write_buffer(&self.in_buf, 0, bytemuck::bytes_of(&params));

            let mut encoder = self
                .device
                .create_command_encoder(&wgpu::CommandEncoderDescriptor {
                    label: Some("pow-buster-sha256-fast-single-block"),
                });
            {
                let mut pass = encoder.begin_compute_pass(&wgpu::ComputePassDescriptor {
                    label: Some("pow-buster-sha256-fast-single-block"),
                    timestamp_writes: None,
                });
                pass.set_pipeline(&self.pipeline);
                pass.set_bind_group(0, &self.bind_group, &[]);
                pass.dispatch_workgroups(wgs, 1, 1);
            }
            encoder.copy_buffer_to_buffer(&self.out_buf, 0, &self.staging, 0, 48);
            self.queue.submit([encoder.finish()]);

            let values = self.read_result().await?;
            let dispatched = base.saturating_add(u64::from(wgs) * HASHES_PER_WG);
            if values[0] != 0 {
                let counter = (u64::from(values[2]) << 32) | u64::from(values[1]);
                let nonce = counter_to_decimal_nonce(counter);
                let hash: [u32; 8] = values[3..11]
                    .try_into()
                    .map_err(|_| GpuError::new("invalid GPU result layout"))?;
                if !verify_fast_single_block(message, nonce, hash, mask) {
                    return Err(GpuError::new("GPU returned an invalid fast-path proof"));
                }
                return Ok(Some(GpuSolution {
                    nonce,
                    hash,
                    dispatched_hashes: dispatched,
                }));
            }
            base = dispatched;
        }

        Ok(None)
    }

    async fn solve_generic_single_block<const TYPE: u8>(
        &mut self,
        message: &crate::message::SingleBlockMessage,
        target: u64,
        mask: u64,
        max_hashes: u64,
    ) -> Result<Option<GpuSolution>, GpuError> {
        let search_space = single_block_search_space(message);
        let limit = max_hashes.min(search_space);
        if limit == 0 {
            return Ok(None);
        }

        let start = if message.nonce_addend == 0 {
            100_000_000_u64
        } else {
            0
        };
        let mut params = [0_u32; 40];
        params[..8].copy_from_slice(&message.prefix_state);
        params[8..24].copy_from_slice(&message.message.0);
        params[25] = message.digit_index as u32;
        params[26] = message.nonce_addend as u32;
        params[27] = (message.nonce_addend >> 32) as u32;
        params[28] = (target >> 32) as u32;
        params[29] = target as u32;
        params[30] = (mask >> 32) as u32;
        params[31] = mask as u32;
        params[32] = u32::from(TYPE);
        params[33] = u32::from(message.no_trailing_zeros)
            | (u32::from(cfg!(feature = "compare-64bit")) << 1);
        self.queue.write_buffer(&self.out_buf, 0, &[0; 48]);

        let desired = gpu_batch_target(expected_work::<TYPE>(target, mask), HASHES_PER_WG);
        let mut offset = 0_u64;

        while offset < limit {
            let remaining = limit - offset;
            let batch = desired
                .min(remaining)
                .min(u64::from(self.max_wgs) * HASHES_PER_WG);
            let wgs = batch.div_ceil(HASHES_PER_WG).max(1) as u32;
            let candidate_start = start + offset;
            let candidate_end = start + offset + batch;
            params[24] = candidate_start as u32;
            params[34] = candidate_end as u32;
            self.queue
                .write_buffer(&self.generic_in_buf, 0, bytemuck::cast_slice(&params));

            let mut encoder = self
                .device
                .create_command_encoder(&wgpu::CommandEncoderDescriptor {
                    label: Some("pow-buster-sha256-generic-single-block"),
                });
            {
                let mut pass = encoder.begin_compute_pass(&wgpu::ComputePassDescriptor {
                    label: Some("pow-buster-sha256-generic-single-block"),
                    timestamp_writes: None,
                });
                pass.set_pipeline(&self.generic_pipeline);
                pass.set_bind_group(0, &self.generic_bind_group, &[]);
                pass.dispatch_workgroups(wgs, 1, 1);
            }
            encoder.copy_buffer_to_buffer(&self.out_buf, 0, &self.staging, 0, 48);
            self.queue.submit([encoder.finish()]);

            let values = self.read_result().await?;
            let dispatched = offset.saturating_add(batch);
            if values[0] != 0 {
                let nonce = (u64::from(values[2]) << 32) | u64::from(values[1]);
                let hash: [u32; 8] = values[3..11]
                    .try_into()
                    .map_err(|_| GpuError::new("invalid GPU result layout"))?;
                if !verify_single_block::<TYPE>(message, nonce, hash, target, mask) {
                    return Err(GpuError::new("GPU returned an invalid generic proof"));
                }
                return Ok(Some(GpuSolution {
                    nonce,
                    hash,
                    dispatched_hashes: dispatched,
                }));
            }
            offset = dispatched;
        }

        Ok(None)
    }

    async fn dispatch_multi(
        &mut self,
        params: &[u32; 64],
        workgroups: u32,
    ) -> Result<Option<(u64, [u32; 8])>, GpuError> {
        self.queue.write_buffer(&self.out_buf, 0, &[0; 48]);
        self.queue
            .write_buffer(&self.generic_in_buf, 0, bytemuck::cast_slice(params));
        let (label, pipeline, bind_group) = match params[0] {
            1 => (
                "pow-buster-sha256-double-block",
                &self.double_pipeline,
                &self.double_bind_group,
            ),
            2 => (
                "pow-buster-sha256-goaway",
                &self.goaway_pipeline,
                &self.goaway_bind_group,
            ),
            3 => (
                "pow-buster-sha256-binary",
                &self.binary_pipeline,
                &self.binary_bind_group,
            ),
            mode => {
                return Err(GpuError::new(format!(
                    "invalid SHA-256 GPU layout mode {mode}"
                )));
            }
        };
        let mut encoder = self
            .device
            .create_command_encoder(&wgpu::CommandEncoderDescriptor { label: Some(label) });
        {
            let mut pass = encoder.begin_compute_pass(&wgpu::ComputePassDescriptor {
                label: Some(label),
                timestamp_writes: None,
            });
            pass.set_pipeline(pipeline);
            pass.set_bind_group(0, bind_group, &[]);
            pass.dispatch_workgroups(workgroups, 1, 1);
        }
        encoder.copy_buffer_to_buffer(&self.out_buf, 0, &self.staging, 0, 48);
        self.queue.submit([encoder.finish()]);
        let values = self.read_result().await?;
        if values[0] == 0 {
            return Ok(None);
        }
        let nonce = (u64::from(values[2]) << 32) | u64::from(values[1]);
        let hash = values[3..11]
            .try_into()
            .map_err(|_| GpuError::new("invalid GPU result layout"))?;
        Ok(Some((nonce, hash)))
    }

    async fn dispatch_cerberus(
        &mut self,
        params: &[u32; 64],
        workgroups: u32,
    ) -> Result<Option<(u64, [u32; 8])>, GpuError> {
        self.queue.write_buffer(&self.out_buf, 0, &[0; 48]);
        self.queue
            .write_buffer(&self.generic_in_buf, 0, bytemuck::cast_slice(params));
        let mut encoder = self
            .device
            .create_command_encoder(&wgpu::CommandEncoderDescriptor {
                label: Some("pow-buster-cerberus"),
            });
        {
            let mut pass = encoder.begin_compute_pass(&wgpu::ComputePassDescriptor {
                label: Some("pow-buster-cerberus"),
                timestamp_writes: None,
            });
            pass.set_pipeline(&self.cerberus_pipeline);
            pass.set_bind_group(0, &self.cerberus_bind_group, &[]);
            pass.dispatch_workgroups(workgroups, 1, 1);
        }
        encoder.copy_buffer_to_buffer(&self.out_buf, 0, &self.staging, 0, 48);
        self.queue.submit([encoder.finish()]);
        let values = self.read_result().await?;
        if values[0] == 0 {
            return Ok(None);
        }
        let nonce = (u64::from(values[2]) << 32) | u64::from(values[1]);
        let hash = values[3..11]
            .try_into()
            .map_err(|_| GpuError::new("invalid GPU Cerberus result layout"))?;
        Ok(Some((nonce, hash)))
    }

    async fn dispatch_altcha(
        &mut self,
        params: &[u32; 64],
        workgroups: u32,
    ) -> Result<Option<(u64, [u32; 8])>, GpuError> {
        self.queue.write_buffer(&self.out_buf, 0, &[0; 48]);
        self.queue
            .write_buffer(&self.generic_in_buf, 0, bytemuck::cast_slice(params));
        let mut encoder = self
            .device
            .create_command_encoder(&wgpu::CommandEncoderDescriptor {
                label: Some("pow-buster-altcha"),
            });
        {
            let mut pass = encoder.begin_compute_pass(&wgpu::ComputePassDescriptor {
                label: Some("pow-buster-altcha"),
                timestamp_writes: None,
            });
            pass.set_pipeline(&self.altcha_pipeline);
            pass.set_bind_group(0, &self.altcha_bind_group, &[]);
            pass.dispatch_workgroups(workgroups, 1, 1);
        }
        encoder.copy_buffer_to_buffer(&self.out_buf, 0, &self.staging, 0, 48);
        self.queue.submit([encoder.finish()]);
        let values = self.read_result().await?;
        if values[0] == 0 {
            return Ok(None);
        }
        let nonce = (u64::from(values[2]) << 32) | u64::from(values[1]);
        let hash = values[3..11]
            .try_into()
            .map_err(|_| GpuError::new("invalid GPU Altcha result layout"))?;
        Ok(Some((nonce, hash)))
    }

    async fn read_result(&self) -> Result<Vec<u32>, GpuError> {
        let slice = self.staging.slice(..);
        let (tx, rx) = futures_channel::oneshot::channel();
        slice.map_async(wgpu::MapMode::Read, move |result| {
            let _ = tx.send(result);
        });

        #[cfg(not(target_arch = "wasm32"))]
        self.device
            .poll(wgpu::PollType::wait_indefinitely())
            .map_err(|e| GpuError::new(format!("poll GPU: {e}")))?;

        rx.await
            .map_err(|_| GpuError::new("GPU map callback dropped"))?
            .map_err(|e| GpuError::new(format!("map GPU result: {e}")))?;
        let mapped = slice
            .get_mapped_range()
            .map_err(|e| GpuError::new(format!("read mapped GPU result: {e}")))?;
        let values = bytemuck::cast_slice::<u8, u32>(&mapped).to_vec();
        drop(mapped);
        self.staging.unmap();
        Ok(values)
    }
}

/// Async GPU counterpart of the CPU single-block SHA-256 solver family.
///
/// Anubis, mCaptcha and Cap.js all route through this protocol-agnostic message type.
#[derive(Debug, Clone)]
pub struct SingleBlockSolver {
    message: crate::message::SingleBlockMessage,
    attempted_nonces: u64,
    limit: u64,
}

impl From<crate::message::SingleBlockMessage> for SingleBlockSolver {
    fn from(message: crate::message::SingleBlockMessage) -> Self {
        Self {
            message,
            attempted_nonces: 0,
            limit: u64::MAX,
        }
    }
}

impl SingleBlockSolver {
    /// Set the maximum number of candidates dispatched by this solver.
    pub fn set_limit(&mut self, limit: u64) {
        self.limit = limit;
    }

    /// Number of candidates dispatched so far.
    ///
    /// GPU workgroups cooperatively stop after a hit, so this is an upper bound on candidates
    /// actually executed by the device.
    pub fn get_attempted_nonces(&self) -> u64 {
        self.attempted_nonces
    }

    /// Solve this SHA-256 single-block message on the GPU.
    pub async fn solve<const TYPE: u8>(
        &mut self,
        gpu: &mut GpuContext,
        target: u64,
        mask: u64,
    ) -> Result<Option<GpuSolution>, GpuError> {
        let result = gpu
            .solve_single_block_inner::<TYPE>(&self.message, target, mask, self.limit)
            .await?;
        self.attempted_nonces = result.as_ref().map_or_else(
            || self.limit.min(single_block_search_space(&self.message)),
            |solution| solution.dispatched_hashes.min(self.limit),
        );
        Ok(result)
    }

    /// Solve and return only the nonce.
    pub async fn solve_nonce_only<const TYPE: u8>(
        &mut self,
        gpu: &mut GpuContext,
        target: u64,
        mask: u64,
    ) -> Result<Option<u64>, GpuError> {
        Ok(self
            .solve::<TYPE>(gpu, target, mask)
            .await?
            .map(|x| x.nonce))
    }
}

/// Async GPU counterpart of the CPU double-block decimal SHA-256 solver.
pub struct DoubleBlockSolver {
    message: crate::message::DoubleBlockMessage,
    attempted_nonces: u64,
    limit: u64,
}

impl From<crate::message::DoubleBlockMessage> for DoubleBlockSolver {
    fn from(message: crate::message::DoubleBlockMessage) -> Self {
        Self {
            message,
            attempted_nonces: 0,
            limit: u64::MAX,
        }
    }
}

impl DoubleBlockSolver {
    /// Set the maximum number of candidates dispatched.
    pub fn set_limit(&mut self, limit: u64) {
        self.limit = limit;
    }
    /// Number of candidates dispatched so far.
    pub fn get_attempted_nonces(&self) -> u64 {
        self.attempted_nonces
    }

    /// Solve this double-block decimal message on the GPU.
    pub async fn solve<const TYPE: u8>(
        &mut self,
        gpu: &mut GpuContext,
        target: u64,
        mask: u64,
    ) -> Result<Option<GpuSolution>, GpuError> {
        let search_space = if self.message.nonce_addend == 0 {
            900_000_000_u64
        } else {
            1_000_000_000
        };
        let limit = self.limit.min(search_space);
        let start = if self.message.nonce_addend == 0 {
            100_000_000_u64
        } else {
            0
        };
        let desired = gpu_batch_target(expected_work::<TYPE>(target, mask), HASHES_PER_WG);
        let mut offset = 0_u64;
        while offset < limit {
            let batch = desired
                .min(limit - offset)
                .min(u64::from(gpu.max_wgs) * HASHES_PER_WG);
            let wgs = batch.div_ceil(HASHES_PER_WG).max(1) as u32;
            let mut p = [0_u32; 64];
            p[0] = 1;
            p[1] = u32::from(TYPE);
            p[2] = u32::from(cfg!(feature = "compare-64bit"));
            p[3] = (start + offset) as u32;
            p[5] = batch as u32;
            p[6] = (target >> 32) as u32;
            p[7] = target as u32;
            p[8] = (mask >> 32) as u32;
            p[9] = mask as u32;
            p[16..24].copy_from_slice(&self.message.prefix_state.0);
            p[24..40].copy_from_slice(&self.message.message.0);
            let mut hot_state = self.message.prefix_state.0;
            crate::sha256::ingest_message_prefix::<13>(
                &mut hot_state,
                self.message.message[..13].try_into().unwrap(),
            );
            p[44..52].copy_from_slice(&hot_state);
            p[40] = self.message.nonce_addend as u32;
            p[41] = (self.message.nonce_addend >> 32) as u32;
            let bitlen = self.message.message_length.saturating_mul(8);
            p[42] = (bitlen >> 32) as u32;
            p[43] = bitlen as u32;
            if let Some((nonce, hash)) = gpu.dispatch_multi(&p, wgs).await? {
                self.attempted_nonces = offset + batch;
                if !verify_double_block::<TYPE>(&self.message, nonce, hash, target, mask) {
                    return Err(GpuError::new("GPU returned an invalid double-block proof"));
                }
                return Ok(Some(GpuSolution {
                    nonce,
                    hash,
                    dispatched_hashes: self.attempted_nonces,
                }));
            }
            offset += batch;
        }
        self.attempted_nonces = limit;
        Ok(None)
    }

    /// Solve and return only the nonce.
    pub async fn solve_nonce_only<const TYPE: u8>(
        &mut self,
        gpu: &mut GpuContext,
        target: u64,
        mask: u64,
    ) -> Result<Option<u64>, GpuError> {
        Ok(self
            .solve::<TYPE>(gpu, target, mask)
            .await?
            .map(|x| x.nonce))
    }
}

/// GPU router for decimal SHA-256 messages, mirroring [`crate::message::DecimalMessage`].
pub enum DecimalSolver {
    /// Single-block message.
    SingleBlock(SingleBlockSolver),
    /// Double-block message.
    DoubleBlock(DoubleBlockSolver),
}

impl From<crate::message::DecimalMessage> for DecimalSolver {
    fn from(message: crate::message::DecimalMessage) -> Self {
        match message {
            crate::message::DecimalMessage::SingleBlock(m) => Self::SingleBlock(m.into()),
            crate::message::DecimalMessage::DoubleBlock(m) => Self::DoubleBlock(m.into()),
        }
    }
}

impl DecimalSolver {
    /// Set the maximum number of candidates dispatched.
    pub fn set_limit(&mut self, limit: u64) {
        match self {
            Self::SingleBlock(s) => s.set_limit(limit),
            Self::DoubleBlock(s) => s.set_limit(limit),
        }
    }
    /// Number of candidates dispatched so far.
    pub fn get_attempted_nonces(&self) -> u64 {
        match self {
            Self::SingleBlock(s) => s.get_attempted_nonces(),
            Self::DoubleBlock(s) => s.get_attempted_nonces(),
        }
    }
    /// Solve a decimal SHA-256 message.
    pub async fn solve<const TYPE: u8>(
        &mut self,
        gpu: &mut GpuContext,
        target: u64,
        mask: u64,
    ) -> Result<Option<GpuSolution>, GpuError> {
        match self {
            Self::SingleBlock(s) => s.solve::<TYPE>(gpu, target, mask).await,
            Self::DoubleBlock(s) => s.solve::<TYPE>(gpu, target, mask).await,
        }
    }
}

/// Async GPU GoAway SHA-256 solver.
pub struct GoAwaySolver {
    message: crate::message::GoAwayMessage,
    attempted_nonces: u64,
    limit: u64,
}

impl From<crate::message::GoAwayMessage> for GoAwaySolver {
    fn from(message: crate::message::GoAwayMessage) -> Self {
        Self {
            message,
            attempted_nonces: 0,
            limit: u64::MAX,
        }
    }
}

impl GoAwaySolver {
    /// Set the maximum number of candidates dispatched.
    pub fn set_limit(&mut self, limit: u64) {
        self.limit = limit;
    }
    /// Number of candidates dispatched so far.
    pub fn get_attempted_nonces(&self) -> u64 {
        self.attempted_nonces
    }
    /// Solve a GoAway message on the GPU.
    pub async fn solve<const TYPE: u8>(
        &mut self,
        gpu: &mut GpuContext,
        target: u64,
        mask: u64,
    ) -> Result<Option<GpuSolution>, GpuError> {
        let limit = self.limit.min(u64::from(u32::MAX) + 1);
        let desired = gpu_batch_target(expected_work::<TYPE>(target, mask), HASHES_PER_WG);
        let mut offset = 0_u64;
        while offset < limit {
            let batch = desired
                .min(limit - offset)
                .min(u64::from(gpu.max_wgs) * HASHES_PER_WG);
            let wgs = batch.div_ceil(HASHES_PER_WG).max(1) as u32;
            let mut p = [0_u32; 64];
            p[0] = 2;
            p[1] = u32::from(TYPE);
            p[2] = u32::from(cfg!(feature = "compare-64bit"));
            p[3] = offset as u32;
            p[5] = batch as u32;
            p[6] = (target >> 32) as u32;
            p[7] = target as u32;
            p[8] = (mask >> 32) as u32;
            p[9] = mask as u32;
            p[16..24].copy_from_slice(&self.message.challenge);
            p[24] = self.message.high_word;
            let mut hot_state = crate::sha256::IV;
            let mut invariant = [0_u32; 9];
            invariant[..8].copy_from_slice(&self.message.challenge);
            invariant[8] = self.message.high_word;
            crate::sha256::ingest_message_prefix::<9>(&mut hot_state, invariant);
            p[40..48].copy_from_slice(&hot_state);
            if let Some((nonce, hash)) = gpu.dispatch_multi(&p, wgs).await? {
                self.attempted_nonces = offset + batch;
                if !verify_goaway::<TYPE>(&self.message, nonce, hash, target, mask) {
                    return Err(GpuError::new("GPU returned an invalid GoAway proof"));
                }
                return Ok(Some(GpuSolution {
                    nonce,
                    hash,
                    dispatched_hashes: self.attempted_nonces,
                }));
            }
            offset += batch;
        }
        self.attempted_nonces = limit;
        Ok(None)
    }
    /// Solve and return only the nonce.
    pub async fn solve_nonce_only<const TYPE: u8>(
        &mut self,
        gpu: &mut GpuContext,
        target: u64,
        mask: u64,
    ) -> Result<Option<u64>, GpuError> {
        Ok(self
            .solve::<TYPE>(gpu, target, mask)
            .await?
            .map(|x| x.nonce))
    }
}

/// Async GPU solver for binary SHA-256 nonce messages.
pub struct BinarySolver {
    message: crate::message::BinaryMessage,
    attempted_nonces: u64,
    limit: u64,
}
impl From<crate::message::BinaryMessage> for BinarySolver {
    fn from(message: crate::message::BinaryMessage) -> Self {
        Self {
            message,
            attempted_nonces: 0,
            limit: u64::MAX,
        }
    }
}
impl BinarySolver {
    /// Set the maximum number of candidates dispatched.
    pub fn set_limit(&mut self, limit: u64) {
        self.limit = limit;
    }
    /// Number of candidates dispatched so far.
    pub fn get_attempted_nonces(&self) -> u64 {
        self.attempted_nonces
    }
    /// Solve a binary-nonce SHA-256 message on the GPU.
    pub async fn solve<const TYPE: u8>(
        &mut self,
        gpu: &mut GpuContext,
        target: u64,
        mask: u64,
    ) -> Result<Option<GpuSolution>, GpuError> {
        let bits = u32::from(self.message.nonce_byte_count.get()) * 8;
        let space = if bits == 64 { u64::MAX } else { 1_u64 << bits };
        let limit = self.limit.min(space);
        let (templates, used) = binary_templates(&self.message);
        let desired = gpu_batch_target(expected_work::<TYPE>(target, mask), HASHES_PER_WG);
        let mut base = 0_u64;
        while base < limit {
            let batch = desired
                .min(limit - base)
                .min(u64::from(gpu.max_wgs) * HASHES_PER_WG);
            let wgs = batch.div_ceil(HASHES_PER_WG).max(1) as u32;
            let mut p = [0_u32; 64];
            p[0] = 3;
            p[1] = u32::from(TYPE);
            p[2] = u32::from(cfg!(feature = "compare-64bit"));
            p[3] = base as u32;
            p[4] = (base >> 32) as u32;
            p[5] = batch as u32;
            p[6] = (target >> 32) as u32;
            p[7] = target as u32;
            p[8] = (mask >> 32) as u32;
            p[9] = mask as u32;
            p[10] = used;
            p[11] = u32::from(self.message.nonce_byte_count.get());
            p[12] = self.message.salt_residual_len as u32;
            p[16..24].copy_from_slice(&self.message.prefix_state.0);
            p[24..40].copy_from_slice(&templates[0]);
            p[40..56].copy_from_slice(&templates[1]);
            if let Some((nonce, hash)) = gpu.dispatch_multi(&p, wgs).await? {
                self.attempted_nonces = base + batch;
                if !verify_binary::<TYPE>(&self.message, nonce, hash, target, mask) {
                    return Err(GpuError::new("GPU returned an invalid binary proof"));
                }
                return Ok(Some(GpuSolution {
                    nonce,
                    hash,
                    dispatched_hashes: self.attempted_nonces,
                }));
            }
            base += batch;
        }
        self.attempted_nonces = limit;
        Ok(None)
    }
    /// Solve and return only the nonce.
    pub async fn solve_nonce_only<const TYPE: u8>(
        &mut self,
        gpu: &mut GpuContext,
        target: u64,
        mask: u64,
    ) -> Result<Option<u64>, GpuError> {
        Ok(self
            .solve::<TYPE>(gpu, target, mask)
            .await?
            .map(|x| x.nonce))
    }
}

/// Async GPU counterpart of the CPU Cerberus BLAKE3 solver.
pub struct CerberusSolver {
    message: crate::message::CerberusMessage,
    attempted_nonces: u64,
    limit: u64,
}

impl From<crate::message::CerberusMessage> for CerberusSolver {
    fn from(message: crate::message::CerberusMessage) -> Self {
        Self {
            message,
            attempted_nonces: 0,
            limit: u64::MAX,
        }
    }
}

impl CerberusSolver {
    /// Set the maximum number of candidates dispatched.
    pub fn set_limit(&mut self, limit: u64) {
        self.limit = limit;
    }

    /// Number of candidates dispatched so far.
    pub fn get_attempted_nonces(&self) -> u64 {
        self.attempted_nonces
    }

    /// Solve a Cerberus message on the GPU.
    ///
    /// Cerberus uses a zero target plus bit mask; this mirrors the CPU backend.
    pub async fn solve<const TYPE: u8>(
        &mut self,
        gpu: &mut GpuContext,
        target: u64,
        mask: u64,
    ) -> Result<Option<GpuSolution>, GpuError> {
        if target != 0 {
            return Err(GpuError::new("Cerberus GPU solver requires target == 0"));
        }
        let _ = TYPE;
        let expected = 1_u64.checked_shl(mask.count_ones()).unwrap_or(u64::MAX);
        let desired = gpu_batch_target(expected, HASHES_PER_WG);
        let search_space = match &self.message {
            crate::message::CerberusMessage::Decimal(_) => 1_000_000_000_u64,
            crate::message::CerberusMessage::Binary(_) => u64::from(u32::MAX) + 1,
        };
        let limit = self.limit.min(search_space);
        let mut base = 0_u64;

        while base < limit {
            let batch = desired
                .min(limit - base)
                .min(u64::from(gpu.max_wgs) * HASHES_PER_WG)
                .min(u64::from(u32::MAX));
            let wgs = batch.div_ceil(HASHES_PER_WG).max(1) as u32;
            let mut p = [0_u32; 64];
            p[1] = base as u32;
            p[2] = batch as u32;
            p[3] = (mask >> 32) as u32;
            p[4] = mask as u32;

            match &self.message {
                crate::message::CerberusMessage::Decimal(message) => {
                    p[0] = 0;
                    p[8..16].copy_from_slice(&message.prefix_state.0);
                    for (i, chunk) in message.salt_residual.chunks_exact(4).enumerate() {
                        p[16 + i] = u32::from_le_bytes(chunk.try_into().unwrap());
                    }
                    p[32] = message.salt_residual_len as u32;
                    p[33] = message.salt_residual_len as u32 + 9;
                    p[34] = message.flags;
                    p[35] = message.nonce_addend as u32;
                    p[36] = (message.nonce_addend >> 32) as u32;
                }
                crate::message::CerberusMessage::Binary(message) => {
                    p[0] = 1;
                    p[8..16].copy_from_slice(&message.midstate.0);
                    p[16] = message.first_word;
                }
            }

            if let Some((nonce, hash)) = gpu.dispatch_cerberus(&p, wgs).await? {
                self.attempted_nonces = base + batch;
                if !verify_cerberus(&self.message, nonce, hash, mask) {
                    return Err(GpuError::new("GPU returned an invalid Cerberus proof"));
                }
                return Ok(Some(GpuSolution {
                    nonce,
                    hash,
                    dispatched_hashes: self.attempted_nonces,
                }));
            }
            base += batch;
        }
        self.attempted_nonces = limit;
        Ok(None)
    }

    /// Solve and return only the nonce.
    pub async fn solve_nonce_only<const TYPE: u8>(
        &mut self,
        gpu: &mut GpuContext,
        target: u64,
        mask: u64,
    ) -> Result<Option<u64>, GpuError> {
        Ok(self
            .solve::<TYPE>(gpu, target, mask)
            .await?
            .map(|solution| solution.nonce))
    }
}

/// Async GPU counterpart of the CPU Altcha SHA-256/PBKDF2 solver.
pub struct AltchaSha256Solver {
    message: crate::message::AltchaMessage,
    attempted_nonces: u64,
    limit: u64,
}

impl From<crate::message::AltchaMessage> for AltchaSha256Solver {
    fn from(message: crate::message::AltchaMessage) -> Self {
        Self {
            message,
            attempted_nonces: 0,
            limit: u64::MAX,
        }
    }
}

impl AltchaSha256Solver {
    /// Set the maximum number of candidates dispatched.
    pub fn set_limit(&mut self, limit: u64) {
        self.limit = limit;
    }

    /// Number of candidates dispatched so far.
    pub fn get_attempted_nonces(&self) -> u64 {
        self.attempted_nonces
    }

    /// Solve an Altcha SHA-256 or PBKDF2 challenge on the GPU.
    pub async fn solve<const TYPE: u8>(
        &mut self,
        gpu: &mut GpuContext,
        target: u64,
        mask: u64,
    ) -> Result<Option<GpuSolution>, GpuError> {
        let limit = self.limit.min(u64::from(u32::MAX) + 1);
        let desired = gpu_batch_target(
            expected_work_full64::<TYPE>(target, mask),
            u64::from(WG_SIZE),
        );
        let max_batch = u64::from(gpu.max_wgs) * u64::from(WG_SIZE);
        let mut base = 0_u64;
        while base < limit {
            let batch = desired
                .min(limit - base)
                .min(max_batch)
                .min(u64::from(u32::MAX));
            let wgs = batch.div_ceil(u64::from(WG_SIZE)).max(1) as u32;
            let mut p = [0_u32; 64];
            p[0] = u32::from(self.message.pbkdf2);
            p[1] = base as u32;
            p[2] = batch as u32;
            p[3] = u32::from(TYPE);
            p[4] = (target >> 32) as u32;
            p[5] = target as u32;
            p[6] = (mask >> 32) as u32;
            p[7] = mask as u32;
            p[8] = self.message.cost.get();
            p[9] = self.message.key_length.get().min(32);
            for i in 0..4 {
                p[16 + i] =
                    u32::from_be_bytes(self.message.salt[i * 4..i * 4 + 4].try_into().unwrap());
                p[20 + i] =
                    u32::from_be_bytes(self.message.nonce[i * 4..i * 4 + 4].try_into().unwrap());
            }

            if let Some((nonce, hash)) = gpu.dispatch_altcha(&p, wgs).await? {
                self.attempted_nonces = base + batch;
                if !verify_altcha::<TYPE>(&self.message, nonce, hash, target, mask) {
                    return Err(GpuError::new("GPU returned an invalid Altcha proof"));
                }
                return Ok(Some(GpuSolution {
                    nonce,
                    hash,
                    dispatched_hashes: self.attempted_nonces,
                }));
            }
            base += batch;
        }
        self.attempted_nonces = limit;
        Ok(None)
    }

    /// Solve and return only the nonce.
    pub async fn solve_nonce_only<const TYPE: u8>(
        &mut self,
        gpu: &mut GpuContext,
        target: u64,
        mask: u64,
    ) -> Result<Option<u64>, GpuError> {
        Ok(self
            .solve::<TYPE>(gpu, target, mask)
            .await?
            .map(|solution| solution.nonce))
    }
}

fn single_block_search_space(message: &crate::message::SingleBlockMessage) -> u64 {
    if message.nonce_addend == 0 {
        900_000_000
    } else {
        1_000_000_000
    }
}

fn single_block_fast_compatible(message: &crate::message::SingleBlockMessage) -> bool {
    if message.digit_index != 10
        || message.nonce_addend != 1_000_000_000_000_000_000
        || message.no_trailing_zeros
    {
        return false;
    }
    let words = &message.message.0;
    words[0] == 0x3130_3030
        && words[1] == 0x3030_3030
        && (words[2] & 0xffff_0000) == 0x3030_0000
        && words[4] == 0x0000_0080
}

fn expected_work<const TYPE: u8>(target: u64, mask: u64) -> u64 {
    let compare_mask = if cfg!(feature = "compare-64bit") {
        mask
    } else {
        mask & 0xffff_ffff_0000_0000
    };
    if TYPE == crate::solver::SOLVE_TYPE_MASK {
        return 1_u64
            .checked_shl(compare_mask.count_ones())
            .unwrap_or(u64::MAX);
    }
    let bits = if cfg!(feature = "compare-64bit") {
        64
    } else {
        32
    };
    let t = if bits == 64 {
        target as u128
    } else {
        (target >> 32) as u128
    };
    let space = 1_u128 << bits;
    let success = if TYPE == crate::solver::SOLVE_TYPE_LT {
        t.max(1)
    } else {
        space.saturating_sub(t).saturating_sub(1).max(1)
    };
    (space / success).min(u64::MAX as u128) as u64
}

fn midstate(prefix: &[u8]) -> [u32; 8] {
    let mut state = crate::sha256::IV;
    for block in prefix.chunks_exact(64) {
        let words = core::array::from_fn(|i| {
            u32::from_be_bytes(block[i * 4..i * 4 + 4].try_into().unwrap())
        });
        crate::sha256::digest_block(&mut state, &words);
    }
    state
}

fn counter_to_decimal_nonce(counter: u64) -> u64 {
    let mut nonce = 1_u64;
    for digit in (0..18).rev() {
        nonce = nonce * 10 + ((counter >> (digit * 3)) & 7);
    }
    nonce
}

fn verify(prefix: &[u8], nonce: u64, hash: [u32; 8], mask: u64) -> bool {
    let mut hasher = Sha256::new();
    hasher.update(prefix);
    hasher.update(nonce.to_string().as_bytes());
    let digest = hasher.finalize();
    let expected =
        core::array::from_fn(|i| u32::from_be_bytes(digest[i * 4..i * 4 + 4].try_into().unwrap()));
    expected == hash && ((((hash[0] as u64) << 32) | hash[1] as u64) & mask) == 0
}

fn digest_single_block_message(
    message: &crate::message::SingleBlockMessage,
    nonce: u64,
) -> Option<[u32; 8]> {
    let suffix = nonce.checked_sub(message.nonce_addend)?;
    if suffix >= 1_000_000_000 {
        return None;
    }
    let mut words = message.message.0;
    let mut x = suffix as u32;
    for j in 0..9 {
        let digit = x % 10;
        x /= 10;
        let pos = message.digit_index + 8 - j;
        let word = pos / 4;
        let shift = (3 - (pos % 4)) * 8;
        words[word] = (words[word] & !(0xff_u32 << shift)) | ((u32::from(b'0') + digit) << shift);
    }
    let mut state = message.prefix_state;
    crate::sha256::digest_block(&mut state, &words);
    Some(state)
}

fn result_matches<const TYPE: u8>(hash: [u32; 8], target: u64, mask: u64) -> bool {
    let value = (u64::from(hash[0]) << 32) | u64::from(hash[1]);
    if cfg!(feature = "compare-64bit") {
        if TYPE == crate::solver::SOLVE_TYPE_LT {
            value < target
        } else if TYPE == crate::solver::SOLVE_TYPE_GT {
            value > target
        } else {
            (value & mask) == (target & mask)
        }
    } else {
        let value = hash[0];
        let target = (target >> 32) as u32;
        let mask = (mask >> 32) as u32;
        if TYPE == crate::solver::SOLVE_TYPE_LT {
            value < target
        } else if TYPE == crate::solver::SOLVE_TYPE_GT {
            value > target
        } else {
            (value & mask) == (target & mask)
        }
    }
}

fn verify_single_block<const TYPE: u8>(
    message: &crate::message::SingleBlockMessage,
    nonce: u64,
    hash: [u32; 8],
    target: u64,
    mask: u64,
) -> bool {
    digest_single_block_message(message, nonce)
        .is_some_and(|expected| expected == hash && result_matches::<TYPE>(hash, target, mask))
}

fn verify_fast_single_block(
    message: &crate::message::SingleBlockMessage,
    nonce: u64,
    hash: [u32; 8],
    mask: u64,
) -> bool {
    let nonce = nonce.to_string();
    if nonce.len() != 19 {
        return false;
    }
    let mut block = [0_u8; 64];
    block[..19].copy_from_slice(nonce.as_bytes());
    block[19] = 0x80;
    block[60..64].copy_from_slice(&message.message[15].to_be_bytes());
    let words =
        core::array::from_fn(|i| u32::from_be_bytes(block[i * 4..i * 4 + 4].try_into().unwrap()));
    let mut state = message.prefix_state;
    crate::sha256::digest_block(&mut state, &words);
    state == hash && result_matches::<{ crate::solver::SOLVE_TYPE_MASK }>(hash, 0, mask)
}

fn verify_cerberus(
    message: &crate::message::CerberusMessage,
    nonce: u64,
    hash: [u32; 8],
    mask: u64,
) -> bool {
    let expected = match message {
        crate::message::CerberusMessage::Decimal(message) => {
            let Some(mut suffix) = nonce.checked_sub(message.nonce_addend) else {
                return false;
            };
            if suffix >= 1_000_000_000 {
                return false;
            }
            let mut bytes = message.salt_residual.0;
            for i in (0..9).rev() {
                bytes[message.salt_residual_len + i] = (suffix % 10) as u8 + b'0';
                suffix /= 10;
            }
            let words = core::array::from_fn(|i| {
                u32::from_le_bytes(bytes[i * 4..i * 4 + 4].try_into().unwrap())
            });
            crate::blake3::compress8(
                &message.prefix_state.0,
                &words,
                0,
                message.salt_residual_len as u32 + 9,
                message.flags,
            )
        }
        crate::message::CerberusMessage::Binary(message) => {
            if (nonce >> 32) as u32 != message.first_word {
                return false;
            }
            let mut words = [0_u32; 16];
            words[0] = message.first_word;
            words[1] = nonce as u32;
            crate::blake3::compress8(
                &message.midstate.0,
                &words,
                0,
                8,
                crate::blake3::FLAG_CHUNK_END | crate::blake3::FLAG_ROOT,
            )
        }
    };
    expected == hash && ((((hash[0] as u64) << 32) | u64::from(hash[1])) & mask) == 0
}

fn expected_work_full64<const TYPE: u8>(target: u64, mask: u64) -> u64 {
    if TYPE == crate::solver::SOLVE_TYPE_MASK {
        return 1_u64.checked_shl(mask.count_ones()).unwrap_or(u64::MAX);
    }
    let space = 1_u128 << 64;
    let t = u128::from(target);
    let success = if TYPE == crate::solver::SOLVE_TYPE_LT {
        t.max(1)
    } else {
        space.saturating_sub(t).saturating_sub(1).max(1)
    };
    (space / success).min(u128::from(u64::MAX)) as u64
}

fn result_matches_full64<const TYPE: u8>(hash: [u32; 8], target: u64, mask: u64) -> bool {
    let value = (u64::from(hash[0]) << 32) | u64::from(hash[1]);
    if TYPE == crate::solver::SOLVE_TYPE_LT {
        value < target
    } else if TYPE == crate::solver::SOLVE_TYPE_GT {
        value > target
    } else {
        (value & mask) == (target & mask)
    }
}

fn verify_altcha<const TYPE: u8>(
    message: &crate::message::AltchaMessage,
    nonce: u64,
    hash: [u32; 8],
    target: u64,
    mask: u64,
) -> bool {
    let Ok(counter) = u32::try_from(nonce) else {
        return false;
    };
    let expected = if message.pbkdf2 {
        let mut password = [0_u8; 20];
        password[..16].copy_from_slice(&message.nonce);
        password[16..].copy_from_slice(&counter.to_be_bytes());
        let mut output = [0_u8; 32];
        if pbkdf2::pbkdf2::<pbkdf2::hmac::Hmac<Sha256>>(
            &password,
            &message.salt,
            message.cost.get(),
            &mut output,
        )
        .is_err()
        {
            return false;
        }
        core::array::from_fn(|i| u32::from_be_bytes(output[i * 4..i * 4 + 4].try_into().unwrap()))
    } else {
        let mut first = [0_u8; 36];
        first[..16].copy_from_slice(&message.salt);
        first[16..32].copy_from_slice(&message.nonce);
        first[32..].copy_from_slice(&counter.to_be_bytes());
        let mut digest = Sha256::digest(first).to_vec();
        let key_len = message.key_length.get().min(32) as usize;
        for _ in 1..message.cost.get() {
            digest = Sha256::digest(&digest[..key_len]).to_vec();
        }
        core::array::from_fn(|i| u32::from_be_bytes(digest[i * 4..i * 4 + 4].try_into().unwrap()))
    };
    expected == hash && result_matches_full64::<TYPE>(hash, target, mask)
}

fn altcha_shader_source() -> String {
    let mut rounds = String::new();
    for (t, k) in crate::sha256::K32.iter().enumerate() {
        let i = t & 15;
        if t >= 16 {
            rounds.push_str(&format!("w{i}=(rotr(w{},17u)^rotr(w{},19u)^(w{}>>10u))+w{}+(rotr(w{},7u)^rotr(w{},18u)^(w{}>>3u))+w{i};\n",(t-2)&15,(t-2)&15,(t-2)&15,(t-7)&15,(t-15)&15,(t-15)&15,(t-15)&15));
        }
        rounds.push_str(&format!("{{let t1=h+(rotr(e,6u)^rotr(e,11u)^rotr(e,25u))+(g^(e&(f^g)))+0x{k:08x}u+w{i};let t2=(rotr(a,2u)^rotr(a,13u)^rotr(a,22u))+((a&b)^(a&c)^(b&c));h=g;g=f;f=e;e=d+t1;d=c;c=b;b=a;a=t1+t2;}}\n"));
    }
    format!(
        r#"
const IV:array<u32,8>=array<u32,8>(0x6a09e667u,0xbb67ae85u,0x3c6ef372u,0xa54ff53au,0x510e527fu,0x9b05688cu,0x1f83d9abu,0x5be0cd19u);
struct OutBuf {{ flag:atomic<u32>,nonce_lo:u32,nonce_hi:u32,hash:array<u32,8> }};
@group(0) @binding(0) var<storage,read> P:array<u32>;
@group(0) @binding(1) var<storage,read_write> R:OutBuf;
fn rotr(x:u32,n:u32)->u32{{return (x>>n)|(x<<(32u-n));}}
fn compress(s:array<u32,8>,block:array<u32,16>)->array<u32,8>{{
 var w0=block[0];var w1=block[1];var w2=block[2];var w3=block[3];var w4=block[4];var w5=block[5];var w6=block[6];var w7=block[7];
 var w8=block[8];var w9=block[9];var w10=block[10];var w11=block[11];var w12=block[12];var w13=block[13];var w14=block[14];var w15=block[15];
 var a=s[0];var b=s[1];var c=s[2];var d=s[3];var e=s[4];var f=s[5];var g=s[6];var h=s[7];
 {rounds}
 return array<u32,8>(s[0]+a,s[1]+b,s[2]+c,s[3]+d,s[4]+e,s[5]+f,s[6]+g,s[7]+h);
}}
fn target_ok(h0:u32,h1:u32)->bool{{
 let ty=P[3];if(ty==1u){{return h0<P[4]||(h0==P[4]&&h1<P[5]);}}if(ty==2u){{return h0>P[4]||(h0==P[4]&&h1>P[5]);}}return (h0&P[6])==(P[4]&P[6])&&(h1&P[7])==(P[5]&P[7]);
}}
fn hash_prefix(h:array<u32,8>,len:u32)->array<u32,8>{{
 var b:array<u32,16>;for(var i=0u;i<16u;i=i+1u){{b[i]=0u;}}
 for(var j=0u;j<len;j=j+1u){{let wi=j>>2u;let sh=(3u-(j&3u))*8u;let byte=(h[wi]>>sh)&0xffu;b[wi]=b[wi]|(byte<<sh);}}
 let wi=len>>2u;let sh=(3u-(len&3u))*8u;b[wi]=b[wi]|(0x80u<<sh);b[15]=len*8u;return compress(IV,b);
}}
fn hmac(ipad:array<u32,8>,opad:array<u32,8>,msg:array<u32,8>,words:u32,tail_word:u32,bytes:u32)->array<u32,8>{{
 var b:array<u32,16>;for(var i=0u;i<16u;i=i+1u){{b[i]=0u;}}for(var i=0u;i<words;i=i+1u){{b[i]=msg[i];}}if(words<8u){{b[words]=tail_word;}}let padpos=bytes;let pwi=padpos>>2u;let psh=(3u-(padpos&3u))*8u;b[pwi]=b[pwi]|(0x80u<<psh);b[15]=(64u+bytes)*8u;let inner=compress(ipad,b);
 var o:array<u32,16>;for(var i=0u;i<16u;i=i+1u){{o[i]=0u;}}for(var i=0u;i<8u;i=i+1u){{o[i]=inner[i];}}o[8]=0x80000000u;o[15]=768u;return compress(opad,o);
}}
@compute @workgroup_size({WG_SIZE})
fn solve(@builtin(global_invocation_id) gid:vec3<u32>){{
 let idx=gid.x;if(idx>=P[2]||atomicLoad(&R.flag)!=0u){{return;}}let candidate=P[1]+idx;var out:array<u32,8>;
 if(P[0]==0u){{
  var b=array<u32,16>(P[16],P[17],P[18],P[19],P[20],P[21],P[22],P[23],candidate,0x80000000u,0u,0u,0u,0u,0u,288u);out=compress(IV,b);
  for(var r=1u;r<P[8];r=r+1u){{out=hash_prefix(out,P[9]);}}
 }}else{{
  var ib:array<u32,16>;var ob:array<u32,16>;for(var i=0u;i<16u;i=i+1u){{ib[i]=0x36363636u;ob[i]=0x5c5c5c5cu;}}
  for(var i=0u;i<4u;i=i+1u){{ib[i]=ib[i]^P[20+i];ob[i]=ob[i]^P[20+i];}}ib[4]=ib[4]^candidate;ob[4]=ob[4]^candidate;let ipad=compress(IV,ib);let opad=compress(IV,ob);
  var sm:array<u32,8>;for(var i=0u;i<4u;i=i+1u){{sm[i]=P[16+i];}}for(var i=4u;i<8u;i=i+1u){{sm[i]=0u;}}var u=hmac(ipad,opad,sm,4u,1u,20u);var acc=u;
  for(var r=1u;r<P[8];r=r+1u){{u=hmac(ipad,opad,u,8u,0u,32u);for(var i=0u;i<8u;i=i+1u){{acc[i]=acc[i]^u[i];}}}}out=acc;
 }}
 if(target_ok(out[0],out[1])&&atomicExchange(&R.flag,1u)==0u){{R.nonce_lo=candidate;R.nonce_hi=0u;for(var i=0u;i<8u;i=i+1u){{R.hash[i]=out[i];}}}}
}}
"#
    )
}

fn cerberus_shader_source() -> String {
    const PERM: [usize; 16] = [2, 6, 3, 10, 7, 0, 4, 13, 1, 11, 12, 5, 9, 14, 15, 8];
    let mut schedule = [[0_usize; 16]; 7];
    schedule[0] = core::array::from_fn(|i| i);
    for round in 1..7 {
        schedule[round] = core::array::from_fn(|i| schedule[round - 1][PERM[i]]);
    }
    let mut rounds = String::new();
    let gs = [
        (0, 4, 8, 12, 0, 1),
        (1, 5, 9, 13, 2, 3),
        (2, 6, 10, 14, 4, 5),
        (3, 7, 11, 15, 6, 7),
        (0, 5, 10, 15, 8, 9),
        (1, 6, 11, 12, 10, 11),
        (2, 7, 8, 13, 12, 13),
        (3, 4, 9, 14, 14, 15),
    ];
    for sched in &schedule {
        for &(a, b, c, d, x, y) in &gs {
            let mx = sched[x];
            let my = sched[y];
            rounds.push_str(&format!(
                "v[{a}]=v[{a}]+v[{b}]+m[{mx}];v[{d}]=rotr(v[{d}]^v[{a}],16u);v[{c}]=v[{c}]+v[{d}];v[{b}]=rotr(v[{b}]^v[{c}],12u);v[{a}]=v[{a}]+v[{b}]+m[{my}];v[{d}]=rotr(v[{d}]^v[{a}],8u);v[{c}]=v[{c}]+v[{d}];v[{b}]=rotr(v[{b}]^v[{c}],7u);\n"
            ));
        }
    }
    format!(
        r#"
struct OutBuf {{ flag:atomic<u32>,nonce_lo:u32,nonce_hi:u32,hash:array<u32,8> }};
@group(0) @binding(0) var<storage,read> P:array<u32>;
@group(0) @binding(1) var<storage,read_write> R:OutBuf;
fn rotr(x:u32,n:u32)->u32{{return (x>>n)|(x<<(32u-n));}}
fn compress(cv:array<u32,8>,m:array<u32,16>,blen:u32,flags:u32)->array<u32,8>{{
 var v=array<u32,16>(cv[0],cv[1],cv[2],cv[3],cv[4],cv[5],cv[6],cv[7],0x6a09e667u,0xbb67ae85u,0x3c6ef372u,0xa54ff53au,0u,0u,blen,flags);
 {rounds}
 return array<u32,8>(v[0]^v[8],v[1]^v[9],v[2]^v[10],v[3]^v[11],v[4]^v[12],v[5]^v[13],v[6]^v[14],v[7]^v[15]);
}}
@compute @workgroup_size({WG_SIZE})
fn solve(@builtin(global_invocation_id) gid:vec3<u32>){{
 let first=gid.x*{STEPS}u;
 var decimal_m=array<u32,16>(P[16],P[17],P[18],P[19],P[20],P[21],P[22],P[23],P[24],P[25],P[26],P[27],P[28],P[29],P[30],P[31]);
 if(P[0]==0u&&first<P[2]){{
  var x=P[1]+first;for(var j=0u;j<9u;j=j+1u){{let digit=x%10u;x=x/10u;let pos=P[32]+8u-j;let wi=pos>>2u;let sh=(pos&3u)*8u;decimal_m[wi]=(decimal_m[wi]&~(0xffu<<sh))|((0x30u+digit)<<sh);}}
 }}
 for(var step=0u;step<{STEPS}u;step=step+1u){{
  if((step&{}u)==0u&&atomicLoad(&R.flag)!=0u){{return;}}
  let idx=first+step;if(idx>=P[2]){{return;}}let candidate=P[1]+idx;
  let cv=array<u32,8>(P[8],P[9],P[10],P[11],P[12],P[13],P[14],P[15]);
  var m:array<u32,16>;var nlo=candidate;var nhi=0u;var h:array<u32,8>;
  if(P[0]==0u){{
   m=decimal_m;h=compress(cv,m,P[33],P[34]);nlo=P[35]+candidate;let carry=select(0u,1u,nlo<P[35]);nhi=P[36]+carry;
   if(step+1u<{STEPS}u&&idx+1u<P[2]){{var j=0u;loop{{let pos=P[32]+8u-j;let wi=pos>>2u;let sh=(pos&3u)*8u;let digit=(decimal_m[wi]>>sh)&0xffu;if(digit<0x39u){{decimal_m[wi]=(decimal_m[wi]&~(0xffu<<sh))|((digit+1u)<<sh);break;}}decimal_m[wi]=(decimal_m[wi]&~(0xffu<<sh))|(0x30u<<sh);j=j+1u;if(j==9u){{break;}}}}}}
  }}else{{
   m=array<u32,16>(P[16],candidate,0u,0u,0u,0u,0u,0u,0u,0u,0u,0u,0u,0u,0u,0u);h=compress(cv,m,8u,10u);nhi=P[16];
  }}
  if((h[0]&P[3])==0u&&(h[1]&P[4])==0u){{if(atomicExchange(&R.flag,1u)==0u){{R.nonce_lo=nlo;R.nonce_hi=nhi;for(var i=0u;i<8u;i=i+1u){{R.hash[i]=h[i];}}}}}}
 }}
}}
"#,
        CANCEL_INTERVAL - 1
    )
}

fn multi_layout_shader_source() -> String {
    let build_rounds = |start: usize| {
        let mut rounds = String::new();
        for (t, k) in crate::sha256::K32.iter().enumerate().skip(start) {
            let i = t & 15;
            if t >= 16 {
                rounds.push_str(&format!("w{i}=(rotr(w{},17u)^rotr(w{},19u)^(w{}>>10u))+w{}+(rotr(w{},7u)^rotr(w{},18u)^(w{}>>3u))+w{i};\n",(t-2)&15,(t-2)&15,(t-2)&15,(t-7)&15,(t-15)&15,(t-15)&15,(t-15)&15));
            }
            rounds.push_str(&format!("{{let t1=h+(rotr(e,6u)^rotr(e,11u)^rotr(e,25u))+(g^(e&(f^g)))+0x{k:08x}u+w{i};let t2=(rotr(a,2u)^rotr(a,13u)^rotr(a,22u))+((a&b)^(a&c)^(b&c));h=g;g=f;f=e;e=d+t1;d=c;c=b;b=a;a=t1+t2;}}\n"));
        }
        rounds
    };
    let rounds = build_rounds(0);
    let rounds9 = build_rounds(9);
    let rounds13 = build_rounds(13);
    format!(
        r#"
const IV:array<u32,8>=array<u32,8>(0x6a09e667u,0xbb67ae85u,0x3c6ef372u,0xa54ff53au,0x510e527fu,0x9b05688cu,0x1f83d9abu,0x5be0cd19u);
override MODE:u32;
struct OutBuf {{ flag:atomic<u32>,nonce_lo:u32,nonce_hi:u32,hash:array<u32,8> }};
@group(0) @binding(0) var<storage,read> P:array<u32>;
@group(0) @binding(1) var<storage,read_write> R:OutBuf;
fn rotr(x:u32,n:u32)->u32{{return (x>>n)|(x<<(32u-n));}}
fn less64(ah:u32,al:u32,bh:u32,bl:u32)->bool{{return ah<bh||(ah==bh&&al<bl);}}
fn greater64(ah:u32,al:u32,bh:u32,bl:u32)->bool{{return ah>bh||(ah==bh&&al>bl);}}
fn target_ok(h0:u32,h1:u32)->bool{{
 let full=(P[2]&1u)!=0u;let ty=P[1];
 if(ty==1u){{return select(h0<P[6],less64(h0,h1,P[6],P[7]),full);}}
 if(ty==2u){{return select(h0>P[6],greater64(h0,h1,P[6],P[7]),full);}}
 let hi=(h0&P[8])==(P[6]&P[8]);return hi&&select(true,(h1&P[9])==(P[7]&P[9]),full);
}}
fn compress(s:array<u32,8>,block:array<u32,16>)->array<u32,8>{{
 var w0=block[0];var w1=block[1];var w2=block[2];var w3=block[3];var w4=block[4];var w5=block[5];var w6=block[6];var w7=block[7];
 var w8=block[8];var w9=block[9];var w10=block[10];var w11=block[11];var w12=block[12];var w13=block[13];var w14=block[14];var w15=block[15];
 var a=s[0];var b=s[1];var c=s[2];var d=s[3];var e=s[4];var f=s[5];var g=s[6];var h=s[7];
 {rounds}
 return array<u32,8>(s[0]+a,s[1]+b,s[2]+c,s[3]+d,s[4]+e,s[5]+f,s[6]+g,s[7]+h);
}}
fn compress9(feed:array<u32,8>,s:array<u32,8>,block:array<u32,16>)->array<u32,8>{{
 var w0=block[0];var w1=block[1];var w2=block[2];var w3=block[3];var w4=block[4];var w5=block[5];var w6=block[6];var w7=block[7];
 var w8=block[8];var w9=block[9];var w10=block[10];var w11=block[11];var w12=block[12];var w13=block[13];var w14=block[14];var w15=block[15];
 var a=s[0];var b=s[1];var c=s[2];var d=s[3];var e=s[4];var f=s[5];var g=s[6];var h=s[7];
 {rounds9}
 return array<u32,8>(feed[0]+a,feed[1]+b,feed[2]+c,feed[3]+d,feed[4]+e,feed[5]+f,feed[6]+g,feed[7]+h);
}}
fn compress13(feed:array<u32,8>,s:array<u32,8>,block:array<u32,16>)->array<u32,8>{{
 var w0=block[0];var w1=block[1];var w2=block[2];var w3=block[3];var w4=block[4];var w5=block[5];var w6=block[6];var w7=block[7];
 var w8=block[8];var w9=block[9];var w10=block[10];var w11=block[11];var w12=block[12];var w13=block[13];var w14=block[14];var w15=block[15];
 var a=s[0];var b=s[1];var c=s[2];var d=s[3];var e=s[4];var f=s[5];var g=s[6];var h=s[7];
 {rounds13}
 return array<u32,8>(feed[0]+a,feed[1]+b,feed[2]+c,feed[3]+d,feed[4]+e,feed[5]+f,feed[6]+g,feed[7]+h);
}}
fn publish(nlo:u32,nhi:u32,h:array<u32,8>){{if(target_ok(h[0],h[1])&&atomicExchange(&R.flag,1u)==0u){{R.nonce_lo=nlo;R.nonce_hi=nhi;for(var i=0u;i<8u;i=i+1u){{R.hash[i]=h[i];}}}}}}
@compute @workgroup_size({WG_SIZE})
fn solve(@builtin(global_invocation_id) gid:vec3<u32>){{
 let first=gid.x*{STEPS}u;
 var decimal_block=array<u32,16>(P[24],P[25],P[26],P[27],P[28],P[29],P[30],P[31],P[32],P[33],P[34],P[35],P[36],P[37],P[38],P[39]);
 var binary_blocks=array<u32,32>(P[24],P[25],P[26],P[27],P[28],P[29],P[30],P[31],P[32],P[33],P[34],P[35],P[36],P[37],P[38],P[39],P[40],P[41],P[42],P[43],P[44],P[45],P[46],P[47],P[48],P[49],P[50],P[51],P[52],P[53],P[54],P[55]);
 if(MODE==1u&&first<P[5]){{
  var x=P[3]+first;
  for(var j=0u;j<9u;j=j+1u){{let digit=x%10u;x=x/10u;let pos=62u-j;let wi=pos>>2u;let sh=(3u-(pos&3u))*8u;decimal_block[wi]=(decimal_block[wi]&~(0xffu<<sh))|((0x30u+digit)<<sh);}}
 }}
 if(MODE==3u&&first<P[5]){{
  let blo=P[3]+first;let bc=select(0u,1u,blo<P[3]);let bhi=P[4]+bc;
  for(var j=0u;j<P[11];j=j+1u){{let byte=select((blo>>(j*8u))&0xffu,(bhi>>((j-4u)*8u))&0xffu,j>=4u);let pos=P[12]+j;let wi=pos>>2u;let sh=(3u-(pos&3u))*8u;binary_blocks[wi]=(binary_blocks[wi]&~(0xffu<<sh))|(byte<<sh);}}
 }}
 for(var step=0u;step<{STEPS}u;step=step+1u){{
  if((step&{}u)==0u&&atomicLoad(&R.flag)!=0u){{return;}}
  let idx=first+step;if(idx>=P[5]){{return;}}
  let clo=P[3]+idx;let carry=select(0u,1u,clo<P[3]);let chi=P[4]+carry;let mode=MODE;
  if(mode==1u){{
   let st=array<u32,8>(P[16],P[17],P[18],P[19],P[20],P[21],P[22],P[23]);let hs=array<u32,8>(P[44],P[45],P[46],P[47],P[48],P[49],P[50],P[51]);let mid=compress13(st,hs,decimal_block);
   var tail=array<u32,16>(0u,0u,0u,0u,0u,0u,0u,0u,0u,0u,0u,0u,0u,0u,P[42],P[43]);let h=compress(mid,tail);
   let nlo=P[40]+clo;let nc=select(0u,1u,nlo<P[40]);publish(nlo,P[41]+nc,h);
   if(step+1u<{STEPS}u&&idx+1u<P[5]){{
    var j=0u;loop{{let pos=62u-j;let wi=pos>>2u;let sh=(3u-(pos&3u))*8u;let digit=(decimal_block[wi]>>sh)&0xffu;if(digit<0x39u){{decimal_block[wi]=(decimal_block[wi]&~(0xffu<<sh))|((digit+1u)<<sh);break;}}decimal_block[wi]=(decimal_block[wi]&~(0xffu<<sh))|(0x30u<<sh);j=j+1u;if(j==9u){{break;}}}}
   }}
  }} else if(mode==2u){{
   let block=array<u32,16>(P[16],P[17],P[18],P[19],P[20],P[21],P[22],P[23],P[24],clo,0x80000000u,0u,0u,0u,0u,320u);
   let hs=array<u32,8>(P[40],P[41],P[42],P[43],P[44],P[45],P[46],P[47]);publish(clo,P[24],compress9(IV,hs,block));
  }} else if(mode==3u){{
   let b0=array<u32,16>(binary_blocks[0],binary_blocks[1],binary_blocks[2],binary_blocks[3],binary_blocks[4],binary_blocks[5],binary_blocks[6],binary_blocks[7],binary_blocks[8],binary_blocks[9],binary_blocks[10],binary_blocks[11],binary_blocks[12],binary_blocks[13],binary_blocks[14],binary_blocks[15]);
   let st=array<u32,8>(P[16],P[17],P[18],P[19],P[20],P[21],P[22],P[23]);var h=compress(st,b0);
   if(P[10]==2u){{let b1=array<u32,16>(binary_blocks[16],binary_blocks[17],binary_blocks[18],binary_blocks[19],binary_blocks[20],binary_blocks[21],binary_blocks[22],binary_blocks[23],binary_blocks[24],binary_blocks[25],binary_blocks[26],binary_blocks[27],binary_blocks[28],binary_blocks[29],binary_blocks[30],binary_blocks[31]);h=compress(h,b1);}}
   publish(clo,chi,h);
   if(step+1u<{STEPS}u&&idx+1u<P[5]){{var j=0u;loop{{let pos=P[12]+j;let wi=pos>>2u;let sh=(3u-(pos&3u))*8u;let byte=(binary_blocks[wi]>>sh)&0xffu;if(byte<0xffu){{binary_blocks[wi]=(binary_blocks[wi]&~(0xffu<<sh))|((byte+1u)<<sh);break;}}binary_blocks[wi]=binary_blocks[wi]&~(0xffu<<sh);j=j+1u;if(j==P[11]){{break;}}}}}}
  }}
 }}
}}
"#,
        CANCEL_INTERVAL - 1
    )
}

fn verify_double_block<const TYPE: u8>(
    message: &crate::message::DoubleBlockMessage,
    nonce: u64,
    hash: [u32; 8],
    target: u64,
    mask: u64,
) -> bool {
    let Some(mut suffix) = nonce.checked_sub(message.nonce_addend) else {
        return false;
    };
    if suffix >= 1_000_000_000 {
        return false;
    }
    let mut block = message.message.0;
    for j in (0..9).rev() {
        let digit = (suffix % 10) as u32;
        suffix /= 10;
        let pos = crate::message::DoubleBlockMessage::DIGIT_IDX as usize + j;
        let wi = pos / 4;
        let sh = (3 - (pos % 4)) * 8;
        block[wi] = (block[wi] & !(0xffu32 << sh)) | ((u32::from(b'0') + digit) << sh);
    }
    let mut state = message.prefix_state.0;
    crate::sha256::digest_block(&mut state, &block);
    let mut tail = [0u32; 16];
    let bits = message.message_length * 8;
    tail[14] = (bits >> 32) as u32;
    tail[15] = bits as u32;
    crate::sha256::digest_block(&mut state, &tail);
    state == hash && result_matches::<TYPE>(hash, target, mask)
}
fn verify_goaway<const TYPE: u8>(
    message: &crate::message::GoAwayMessage,
    nonce: u64,
    hash: [u32; 8],
    target: u64,
    mask: u64,
) -> bool {
    if (nonce >> 32) as u32 != message.high_word {
        return false;
    }
    let mut block = [0u32; 16];
    block[..8].copy_from_slice(&message.challenge);
    block[8] = message.high_word;
    block[9] = nonce as u32;
    block[10] = 0x8000_0000;
    block[15] = 320;
    let mut state = crate::sha256::IV;
    crate::sha256::digest_block(&mut state, &block);
    state == hash && result_matches::<TYPE>(hash, target, mask)
}
fn binary_templates(message: &crate::message::BinaryMessage) -> ([[u32; 16]; 2], u32) {
    let mut bytes = [[0u8; 64]; 2];
    bytes[0][..message.salt_residual_len]
        .copy_from_slice(&message.salt_residual[..message.salt_residual_len]);
    let mut ptr = message.salt_residual_len;
    let mut cur = 0usize;
    for _ in 0..message.nonce_byte_count.get() {
        ptr += 1;
        if ptr == 64 {
            cur = 1;
            ptr = 0;
        }
    }
    bytes[cur][ptr] = 0x80;
    ptr += 1;
    if ptr + 8 > 64 {
        cur = 1;
    }
    bytes[cur][56..64].copy_from_slice(&((message.message_length as u64) * 8).to_be_bytes());
    (
        core::array::from_fn(|b| {
            core::array::from_fn(|i| {
                u32::from_be_bytes(bytes[b][i * 4..i * 4 + 4].try_into().unwrap())
            })
        }),
        (cur + 1) as u32,
    )
}
fn verify_binary<const TYPE: u8>(
    message: &crate::message::BinaryMessage,
    nonce: u64,
    hash: [u32; 8],
    target: u64,
    mask: u64,
) -> bool {
    let (blocks, used) = binary_templates(message);
    let mut flat = [0u32; 32];
    flat[..16].copy_from_slice(&blocks[0]);
    flat[16..].copy_from_slice(&blocks[1]);
    let bytes = nonce.to_le_bytes();
    for j in 0..usize::from(message.nonce_byte_count.get()) {
        let pos = message.salt_residual_len + j;
        let wi = pos / 4;
        let sh = (3 - (pos % 4)) * 8;
        flat[wi] = (flat[wi] & !(0xffu32 << sh)) | (u32::from(bytes[j]) << sh);
    }
    let mut state = message.prefix_state.0;
    crate::sha256::digest_block(&mut state, flat[..16].try_into().unwrap());
    if used == 2 {
        crate::sha256::digest_block(&mut state, flat[16..32].try_into().unwrap());
    }
    state == hash && result_matches::<TYPE>(hash, target, mask)
}

fn generic_single_block_shader_source() -> String {
    let mut rounds = String::new();
    for (t, k) in crate::sha256::K32.iter().enumerate() {
        let i = t & 15;
        if t >= 16 {
            rounds.push_str(&format!("w{i}=(rotr(w{},17u)^rotr(w{},19u)^(w{}>>10u))+w{}+(rotr(w{},7u)^rotr(w{},18u)^(w{}>>3u))+w{i};\n",(t-2)&15,(t-2)&15,(t-2)&15,(t-7)&15,(t-15)&15,(t-15)&15,(t-15)&15));
        }
        rounds.push_str(&format!("{{let t1=h+(rotr(e,6u)^rotr(e,11u)^rotr(e,25u))+(g^(e&(f^g)))+0x{k:08x}u+w{i};let t2=(rotr(a,2u)^rotr(a,13u)^rotr(a,22u))+((a&b)^(a&c)^(b&c));h=g;g=f;f=e;e=d+t1;d=c;c=b;b=a;a=t1+t2;}}\n"));
    }
    format!(
        r#"
struct OutBuf {{ flag:atomic<u32>,nonce_lo:u32,nonce_hi:u32,hash:array<u32,8> }};
@group(0) @binding(0) var<storage,read> P:array<u32>;
@group(0) @binding(1) var<storage,read_write> R:OutBuf;
fn rotr(x:u32,n:u32)->u32{{return (x>>n)|(x<<(32u-n));}}
fn less64(ah:u32,al:u32,bh:u32,bl:u32)->bool{{return ah<bh||(ah==bh&&al<bl);}}
fn greater64(ah:u32,al:u32,bh:u32,bl:u32)->bool{{return ah>bh||(ah==bh&&al>bl);}}
fn target_ok(h0:u32,h1:u32)->bool{{
 let full=(P[33]&2u)!=0u; let ty=P[32];
 if(ty==1u){{return select(h0<P[28],less64(h0,h1,P[28],P[29]),full);}}
 if(ty==2u){{return select(h0>P[28],greater64(h0,h1,P[28],P[29]),full);}}
 let hi=(h0&P[30])==(P[28]&P[30]);
 return hi&&select(true,(h1&P[31])==(P[29]&P[31]),full);
}}
@compute @workgroup_size({WG_SIZE})
fn solve(@builtin(global_invocation_id) gid:vec3<u32>){{
 let first=P[24]+gid.x*{STEPS}u;if(first>=P[34]){{return;}}
 var words=array<u32,16>(P[8],P[9],P[10],P[11],P[12],P[13],P[14],P[15],P[16],P[17],P[18],P[19],P[20],P[21],P[22],P[23]);
 // Format once per invocation. The remaining candidates are generated by an in-place ASCII decimal odometer.
 var x=first;
 for(var j=0u;j<9u;j=j+1u){{
  let digit=x%10u;x=x/10u;let pos=P[25]+8u-j;let wi=pos>>2u;let sh=(3u-(pos&3u))*8u;
  words[wi]=(words[wi]&~(0xffu<<sh))|((0x30u+digit)<<sh);
 }}
 let last_pos=P[25]+8u;let last_wi=last_pos>>2u;let last_sh=(3u-(last_pos&3u))*8u;
 for(var step=0u;step<{STEPS}u;step=step+1u){{
  if((step&{}u)==0u&&atomicLoad(&R.flag)!=0u){{return;}}
  let candidate=first+step;if(candidate>=P[34]){{return;}}
  let trailing_zero=((words[last_wi]>>last_sh)&0xffu)==0x30u;
  if(!((P[33]&1u)!=0u&&trailing_zero)){{
   var w0=words[0];var w1=words[1];var w2=words[2];var w3=words[3];var w4=words[4];var w5=words[5];var w6=words[6];var w7=words[7];
   var w8=words[8];var w9=words[9];var w10=words[10];var w11=words[11];var w12=words[12];var w13=words[13];var w14=words[14];var w15=words[15];
   var a=P[0];var b=P[1];var c=P[2];var d=P[3];var e=P[4];var f=P[5];var g=P[6];var h=P[7];
   {rounds}
   let r0=P[0]+a;let r1=P[1]+b;
   if(target_ok(r0,r1)){{if(atomicExchange(&R.flag,1u)==0u){{
    let nlo=P[26]+candidate;let carry=select(0u,1u,nlo<P[26]);R.nonce_lo=nlo;R.nonce_hi=P[27]+carry;
    R.hash[0]=r0;R.hash[1]=r1;R.hash[2]=P[2]+c;R.hash[3]=P[3]+d;R.hash[4]=P[4]+e;R.hash[5]=P[5]+f;R.hash[6]=P[6]+g;R.hash[7]=P[7]+h;
   }}}}
  }}
  if(step+1u<{STEPS}u&&candidate+1u<P[34]){{
   var j=0u;
   loop{{
    let pos=P[25]+8u-j;let wi=pos>>2u;let sh=(3u-(pos&3u))*8u;let digit=(words[wi]>>sh)&0xffu;
    if(digit<0x39u){{words[wi]=(words[wi]&~(0xffu<<sh))|((digit+1u)<<sh);break;}}
    words[wi]=(words[wi]&~(0xffu<<sh))|(0x30u<<sh);j=j+1u;if(j==9u){{break;}}
   }}
  }}
 }}
}}
"#,
        CANCEL_INTERVAL - 1
    )
}

fn shader_source() -> String {
    let mut rounds = String::new();
    for (t, k) in crate::sha256::K32.iter().enumerate() {
        let i = t & 15;
        if t >= 16 {
            rounds.push_str(&format!("w{i}=(rotr(w{},17u)^rotr(w{},19u)^(w{}>>10u))+w{}+(rotr(w{},7u)^rotr(w{},18u)^(w{}>>3u))+w{i};\n",(t-2)&15,(t-2)&15,(t-2)&15,(t-7)&15,(t-15)&15,(t-15)&15,(t-15)&15));
        }
        rounds.push_str(&format!("{{let t1=h+(rotr(e,6u)^rotr(e,11u)^rotr(e,25u))+(g^(e&(f^g)))+0x{k:08x}u+w{i};let t2=(rotr(a,2u)^rotr(a,13u)^rotr(a,22u))+((a&b)^(a&c)^(b&c));h=g;g=f;f=e;e=d+t1;d=c;c=b;b=a;a=t1+t2;}}\n"));
    }
    format!(
        r#"
struct InParams {{ s0:u32,s1:u32,s2:u32,s3:u32,s4:u32,s5:u32,s6:u32,s7:u32,base_lo:u32,base_hi:u32,bitlen:u32,mask0:u32,mask1:u32 }};
struct OutBuf {{ flag:atomic<u32>,nonce_lo:u32,nonce_hi:u32,hash:array<u32,8> }};
@group(0) @binding(0) var<uniform> P:InParams;
@group(0) @binding(1) var<storage,read_write> R:OutBuf;
fn rotr(x:u32,n:u32)->u32{{return (x>>n)|(x<<(32u-n));}}
@compute @workgroup_size({WG_SIZE})
fn solve(@builtin(global_invocation_id) gid:vec3<u32>){{
 let gid_lo=gid.x<<7u;let gid_hi=gid.x>>25u;let base_lo=P.base_lo+gid_lo;var base_hi=P.base_hi+gid_hi;if(base_lo<P.base_lo){{base_hi=base_hi+1u;}}
 let d2=(base_lo>>6u)&7u;let d3=(base_lo>>9u)&7u;let d4=(base_lo>>12u)&7u;let d5=(base_lo>>15u)&7u;let d6=(base_lo>>18u)&7u;let d7=(base_lo>>21u)&7u;let d8=(base_lo>>24u)&7u;let d9=(base_lo>>27u)&7u;let d10=((base_lo>>30u)|(base_hi<<2u))&7u;let d11=(base_hi>>1u)&7u;let d12=(base_hi>>4u)&7u;let d13=(base_hi>>7u)&7u;let d14=(base_hi>>10u)&7u;let d15=(base_hi>>13u)&7u;let d16=(base_hi>>16u)&7u;let d17=(base_hi>>19u)&7u;
 let nw0=0x31303030u|(d17<<16u)|(d16<<8u)|d15;let nw1=0x30303030u|(d14<<24u)|(d13<<16u)|(d12<<8u)|d11;let nw2=0x30303030u|(d10<<24u)|(d9<<16u)|(d8<<8u)|d7;let nw3=0x30303030u|(d6<<24u)|(d5<<16u)|(d4<<8u)|d3;var nw4=0x30303080u|(d2<<24u);
 const GM:array<u32,7>=array<u32,7>(0x00000100u,0x00000200u,0x00000400u,0x00010000u,0x00020000u,0x00040000u,0x01000000u);
 for(var step=0u;step<{STEPS}u;step=step+1u){{
  if((step&{}u)==0u && atomicLoad(&R.flag)!=0u){{return;}}
  var w0=nw0;var w1=nw1;var w2=nw2;var w3=nw3;var w4=nw4;
  var w5=0u;var w6=0u;var w7=0u;var w8=0u;var w9=0u;var w10=0u;var w11=0u;var w12=0u;var w13=0u;var w14=0u;var w15=P.bitlen;
  var a=P.s0;var b=P.s1;var c=P.s2;var d=P.s3;var e=P.s4;var f=P.s5;var g=P.s6;var h=P.s7;
  {rounds}
  let r0=P.s0+a;let r1=P.s1+b;
  if((r0&P.mask0)==0u&&(r1&P.mask1)==0u){{if(atomicExchange(&R.flag,1u)==0u){{let gray=step^(step>>1u);let clo=base_lo+gray;let carry=select(0u,1u,clo<base_lo);R.nonce_lo=clo;R.nonce_hi=base_hi+carry;R.hash[0]=r0;R.hash[1]=r1;R.hash[2]=P.s2+c;R.hash[3]=P.s3+d;R.hash[4]=P.s4+e;R.hash[5]=P.s5+f;R.hash[6]=P.s6+g;R.hash[7]=P.s7+h;}}}}
  let ns=step+1u;if(ns<{STEPS}u){{nw4=nw4^GM[countTrailingZeros(ns)];}}
 }}
}}
"#,
        CANCEL_INTERVAL - 1
    )
}

#[cfg(test)]
mod tests {
    use super::*;

    #[test]
    fn counter_conversion_is_decimal_octal_digits() {
        assert_eq!(counter_to_decimal_nonce(0), 1_000_000_000_000_000_000);
        assert_eq!(
            counter_to_decimal_nonce(0o1234567),
            1_000_000_000_001_234_567
        );
        assert!(counter_to_decimal_nonce(COUNTER_SPACE - 1) < u64::MAX);
    }
}
