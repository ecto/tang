//! One runner for tensor-IR programs on every backend.
//!
//! A [`TensorGraph`] lowers to a [`WgslProgram`] (kernels + buffer specs)
//! for wgpu (`to_wgsl`, or MSL passthrough) or for CUDA (`to_cuda`: mma
//! tensor-core tiles plus transpiled WGSL). [`Runtime`] picks the backend
//! once — CUDA when the `cuda` feature is on and an NVIDIA device with
//! nvrtc is present, wgpu otherwise — and [`Program`] owns the buffers of
//! one lowered program on that backend.
//!
//! # Interop
//!
//! A program lives entirely on its runtime's backend: every buffer it
//! reads or writes is allocated there. Programs on the same runtime hand
//! tensors to each other with device-side copies ([`Program::copy`]);
//! crossing backends (or reaching the CPU) is an explicit host round trip
//! ([`Program::read`] / [`Program::write`]). On wgpu, [`Program::wgpu_buffer`]
//! exposes the buffers to tang-gpu's hand kernels exactly as before; on
//! CUDA the hand kernels (`llm.rs`, `nn.rs`, …) do not run, so a code path
//! that wants CUDA must be expressed as IR programs end to end — the
//! derived training step and Adam are (`tang-bench/examples/train_loop.rs`).
//! There is no zero-copy Vulkan/CUDA sharing.
//!
//! # Memory plans
//!
//! By default every materialized tensor gets its own allocation. A
//! [`BufferPlan`] maps the program's buffers onto fewer slots (tensors
//! with disjoint lifetimes sharing one allocation); [`Program::with_plan`]
//! allocates the slots instead and runs the kernels in the plan's order.
//! `TensorGraph::plan_memory`'s [`MemoryPlan`] converts directly
//! ([`BufferPlan::from_memory_plan`], [`Program::planned`]). On CUDA a
//! plan may update in place (an output sharing its input's slot); wgpu
//! cannot bind one buffer read-only and read-write in the same dispatch,
//! so there such plans are refused.
//!
//! # CUDA graphs
//!
//! On a runtime from [`Runtime::cuda_capturable`] (its own stream,
//! cudarc's event tracking off), [`Program::capture`] records one run as
//! a CUDA graph; later [`Program::run`]s replay it.

use std::cell::{RefCell, RefMut};

use tang_compile::tensor::memplan::MemoryPlan;
#[cfg(feature = "cuda")]
use tang_compile::tensor::precision::{bf16_bits, bf16_from_bits};
use tang_compile::tensor::precision::{f16_bits, f16_from_bits};
use tang_compile::tensor::wgsl::WgslProgram;
use tang_compile::tensor::{Format, TensorGraph, TensorId};

use crate::{GpuBuffer, GpuDevice, GpuError, KernelCache};

#[cfg(feature = "cuda")]
use crate::cuda::CudaDevice;

/// Which backend a [`Runtime`] runs on.
#[derive(Clone, Copy, Debug, PartialEq, Eq)]
pub enum BackendKind {
    Wgpu,
    Cuda,
}

/// A device plus what running programs on it needs.
pub enum Runtime {
    Wgpu {
        device: GpuDevice,
        cache: RefCell<KernelCache>,
    },
    #[cfg(feature = "cuda")]
    Cuda(CudaDevice),
}

impl Runtime {
    /// CUDA when compiled with `cuda` and an NVIDIA device with nvrtc is
    /// present, else wgpu. `TANG_BACKEND=wgpu` or `=cuda` forces one.
    pub fn select() -> Result<Self, GpuError> {
        let want = std::env::var("TANG_BACKEND").ok();
        if want.as_deref() != Some("wgpu") {
            #[cfg(feature = "cuda")]
            if let Some(rt) = Self::cuda() {
                return Ok(rt);
            }
            if want.as_deref() == Some("cuda") {
                return Err(GpuError::NoAdapter);
            }
        }
        Self::wgpu()
    }

    pub fn wgpu() -> Result<Self, GpuError> {
        Ok(Self::from_wgpu(GpuDevice::new_sync()?))
    }

    /// Wrap an existing wgpu device (its own kernel cache).
    pub fn from_wgpu(device: GpuDevice) -> Self {
        Self::Wgpu {
            device,
            cache: RefCell::new(KernelCache::new()),
        }
    }

    /// CUDA device 0, if a driver, a device and nvrtc are all present.
    #[cfg(feature = "cuda")]
    pub fn cuda() -> Option<Self> {
        if !CudaDevice::has_nvrtc() {
            return None;
        }
        CudaDevice::new(0).map(Self::Cuda)
    }

    /// CUDA device 0 set up for [`Program::capture`]
    /// ([`CudaDevice::new_capturable`]).
    #[cfg(feature = "cuda")]
    pub fn cuda_capturable() -> Option<Self> {
        if !CudaDevice::has_nvrtc() {
            return None;
        }
        CudaDevice::new_capturable(0).map(Self::Cuda)
    }

    pub fn kind(&self) -> BackendKind {
        match self {
            Self::Wgpu { .. } => BackendKind::Wgpu,
            #[cfg(feature = "cuda")]
            Self::Cuda(_) => BackendKind::Cuda,
        }
    }

    pub fn name(&self) -> &str {
        match self {
            Self::Wgpu { device, .. } => &device.name,
            #[cfg(feature = "cuda")]
            Self::Cuda(d) => &d.name,
        }
    }

    /// The wgpu device and kernel cache, for hand kernels.
    pub fn wgpu_parts(&self) -> Option<(&GpuDevice, RefMut<'_, KernelCache>)> {
        match self {
            Self::Wgpu { device, cache } => Some((device, cache.borrow_mut())),
            #[cfg(feature = "cuda")]
            Self::Cuda(_) => None,
        }
    }

    #[cfg(feature = "cuda")]
    pub fn cuda_device(&self) -> Option<&CudaDevice> {
        match self {
            Self::Cuda(d) => Some(d),
            _ => None,
        }
    }

    /// `g`'s program for this backend. wgpu: WGSL, or native MSL tiles
    /// with `TANG_NATIVE=1` on Metal. CUDA: `to_cuda` (tensor cores on).
    pub fn lower(&self, g: &TensorGraph, outputs: &[TensorId]) -> WgslProgram {
        match self {
            Self::Wgpu { device, .. } => {
                if device.msl_passthrough && std::env::var("TANG_NATIVE").is_ok() {
                    g.to_msl_mma(outputs)
                } else {
                    g.to_wgsl(outputs)
                }
            }
            #[cfg(feature = "cuda")]
            Self::Cuda(_) => g.to_cuda(outputs),
        }
    }

    /// Submit pending work and wait for it.
    pub fn sync(&self) {
        match self {
            Self::Wgpu { device, cache } => {
                cache.borrow_mut().flush(device);
                device.device.poll(wgpu::PollType::Wait).ok();
            }
            #[cfg(feature = "cuda")]
            Self::Cuda(d) => d.sync(),
        }
    }
}

/// Program buffers → allocations. `slot[i]` is the slot backing
/// `program.buffers[i]`; each slot is allocated once with `slot_len`
/// f32 words. Tensors sharing a slot must have disjoint live ranges and
/// graph inputs should keep slots of their own (the planner's job).
#[derive(Clone, Debug)]
pub struct BufferPlan {
    pub slot: Vec<usize>,
    pub slot_len: Vec<usize>,
    /// Kernel indices in execution order (a topological order the slot
    /// sharing is valid for).
    pub order: Vec<usize>,
}

impl BufferPlan {
    /// One slot per buffer, program order — what [`Program::new`] uses.
    pub fn identity(program: &WgslProgram) -> Self {
        Self {
            slot: (0..program.buffers.len()).collect(),
            slot_len: program.buffers.iter().map(words).collect(),
            order: (0..program.kernels.len()).collect(),
        }
    }

    /// The slots and order of a liveness plan from
    /// `TensorGraph::plan_memory`, in-place donations included.
    pub fn from_memory_plan(plan: &MemoryPlan) -> Self {
        Self {
            slot: plan.slot.clone(),
            slot_len: plan.slot_words.clone(),
            order: plan.order.clone(),
        }
    }
}

impl From<&MemoryPlan> for BufferPlan {
    fn from(plan: &MemoryPlan) -> Self {
        Self::from_memory_plan(plan)
    }
}

/// f32 words a buffer needs (f16 and bf16 pack two per word, element
/// `i` at half `i`: WGSL's packed words and CUDA's `unsigned short`
/// buffers share the layout).
fn words(b: &tang_compile::tensor::wgsl::BufferSpec) -> usize {
    match b.format {
        Format::F16 | Format::BF16 => b.len.div_ceil(2),
        _ => b.len,
    }
    .max(1)
}

fn check_plan(program: &WgslProgram, inputs: &[&[f32]], plan: &BufferPlan, shared: &[usize]) {
    assert_eq!(plan.slot.len(), program.buffers.len(), "plan size");
    let mut order = plan.order.clone();
    order.sort_unstable();
    assert!(
        order.iter().copied().eq(0..program.kernels.len()),
        "plan order is not a permutation of the kernels"
    );
    for (i, b) in program.buffers.iter().enumerate() {
        assert!(words(b) <= plan.slot_len[plan.slot[i]], "slot too small");
        if let Some(k) = b.input.filter(|k| !shared.contains(k)) {
            assert_eq!(inputs[k].len(), b.len, "input {k} has wrong length");
        }
    }
}

/// One input of a program bound to another program's buffer instead of
/// an allocation of its own ([`Program::with_shared`]): weights and
/// caches shared by a prefill and a decode program.
#[derive(Clone, Copy)]
pub struct Shared<'a> {
    /// Graph input of the program being built.
    pub input: usize,
    /// The program that owns the buffer, and its tensor.
    pub from: &'a Program,
    pub tensor: TensorId,
}

/// A wgpu program recorded once ([`Program::capture`]): pipelines, bind
/// groups and uniforms built, so a run is one compute pass.
struct WgpuRecording {
    passes: Vec<(wgpu::ComputePipeline, wgpu::BindGroup, u32, u32)>,
}

enum Storage {
    Wgpu(Vec<GpuBuffer>),
    #[cfg(feature = "cuda")]
    Cuda {
        /// Reference counted: programs over shared buffers hold the same
        /// slots ([`Program::with_shared`]).
        slots: Vec<std::rc::Rc<cudarc::driver::CudaSlice<f32>>>,
        functions: Vec<cudarc::driver::CudaFunction>,
        /// One captured run ([`Program::capture`]).
        graph: Option<cudarc::driver::CudaGraph>,
    },
}

/// A lowered program with its buffers on one backend; reusable across runs.
pub struct Program {
    pub program: WgslProgram,
    storage: Storage,
    /// `slot[i]` backs `program.buffers[i]`.
    slot: Vec<usize>,
    /// Per kernel: slots of its reads then its output.
    args: Vec<Vec<usize>>,
    /// Kernel indices in the order [`run`](Self::run) launches them.
    order: Vec<usize>,
    /// wgpu: the run recorded by [`capture`](Self::capture).
    recording: Option<WgpuRecording>,
}

/// What [`Program::tuned`] did.
#[derive(Clone, Copy, Debug, Default)]
pub struct TuneReport {
    /// Kernels with a tensor-core (native) version that kept it.
    pub native_kept: usize,
    /// Kernels with a native version at all.
    pub native_total: usize,
    /// The choices came from the tuning cache file.
    pub from_cache: bool,
}

impl Program {
    /// Lower `g` for `rt` and allocate it; `inputs` in graph input order.
    pub fn compile(rt: &Runtime, g: &TensorGraph, outputs: &[TensorId], inputs: &[&[f32]]) -> Self {
        Self::new(rt, rt.lower(g, outputs), inputs)
    }

    /// Allocate every buffer (one per tensor) and upload the inputs.
    pub fn new(rt: &Runtime, program: WgslProgram, inputs: &[&[f32]]) -> Self {
        let plan = BufferPlan::identity(&program);
        Self::with_plan(rt, program, inputs, &plan)
    }

    /// Allocate the slots of `plan` and upload the inputs.
    pub fn with_plan(
        rt: &Runtime,
        program: WgslProgram,
        inputs: &[&[f32]],
        plan: &BufferPlan,
    ) -> Self {
        Self::with_shared(rt, program, inputs, plan, &[])
    }

    /// [`with_plan`](Self::with_plan) with some inputs bound to other
    /// programs' buffers (same runtime): nothing is allocated or uploaded
    /// for them (their `inputs` entries may be empty), and writes either
    /// program makes — an in-place cache update — are seen by both. The
    /// shared tensor must have the input's length and format.
    pub fn with_shared(
        rt: &Runtime,
        program: WgslProgram,
        inputs: &[&[f32]],
        plan: &BufferPlan,
        shared: &[Shared<'_>],
    ) -> Self {
        let ks: Vec<usize> = shared.iter().map(|s| s.input).collect();
        check_plan(&program, inputs, plan, &ks);
        // slot of this program -> (program, its slot)
        let mut borrowed: Vec<Option<(&Program, usize)>> = vec![None; plan.slot_len.len()];
        for sh in shared {
            let i = program
                .buffers
                .iter()
                .position(|b| b.input == Some(sh.input))
                .expect("shared input not bound");
            let (b, theirs) = (
                &program.buffers[i],
                &sh.from.program.buffers[sh.from.buffer_index(sh.tensor)],
            );
            assert_eq!(
                (words(b), b.format),
                (words(theirs), theirs.format),
                "shared input {} differs from its buffer",
                sh.input
            );
            borrowed[plan.slot[i]] = Some((sh.from, sh.from.slot_of(sh.tensor)));
        }
        let own = |k: usize| !ks.contains(&k);
        match rt {
            Runtime::Wgpu { device, .. } => {
                Self::wgpu_with_plan(device, program, inputs, plan, &borrowed, &own)
            }
            #[cfg(feature = "cuda")]
            Runtime::Cuda(d) => {
                use std::rc::Rc;
                let mut slots: Vec<Rc<_>> = plan
                    .slot_len
                    .iter()
                    .zip(&borrowed)
                    .map(|(&n, b)| match b {
                        Some((p, s)) => match &p.storage {
                            Storage::Cuda { slots, .. } => slots[*s].clone(),
                            _ => panic!("programs on different backends"),
                        },
                        None => Rc::new(d.stream.alloc_zeros::<f32>(n).expect("alloc")),
                    })
                    .collect();
                for (i, b) in program.buffers.iter().enumerate() {
                    if let Some(k) = b.input.filter(|&k| own(k)) {
                        let host = pack_words(b.format, inputs[k]);
                        let slot = Rc::get_mut(&mut slots[plan.slot[i]]).expect("own slot");
                        let mut view = slot.slice_mut(0..host.len());
                        d.stream.memcpy_htod(&host[..], &mut view).expect("upload");
                    }
                }
                // nvrtc the missing kernels on all cores, then load
                crate::cuda::precompile(program.kernels.iter().map(|k| k.source.as_str()), d.arch);
                let functions = program
                    .kernels
                    .iter()
                    .map(|k| d.function(&k.source))
                    .collect();
                let storage = Storage::Cuda {
                    slots,
                    functions,
                    graph: None,
                };
                Self::assemble(program, storage, plan)
            }
        }
    }

    /// Lower nothing: allocate `program` with the slots and order of a
    /// [`MemoryPlan`] (in-place donations need CUDA).
    pub fn planned(
        rt: &Runtime,
        program: WgslProgram,
        inputs: &[&[f32]],
        plan: &MemoryPlan,
    ) -> Self {
        Self::with_plan(rt, program, inputs, &BufferPlan::from_memory_plan(plan))
    }

    /// [`Program::new`] on a bare wgpu device, for callers that keep
    /// their own device and [`KernelCache`] (run it with
    /// [`dispatch`](Self::dispatch)).
    pub fn on_wgpu(device: &GpuDevice, program: WgslProgram, inputs: &[&[f32]]) -> Self {
        let plan = BufferPlan::identity(&program);
        check_plan(&program, inputs, &plan, &[]);
        let borrowed = vec![None; plan.slot_len.len()];
        Self::wgpu_with_plan(device, program, inputs, &plan, &borrowed, &|_| true)
    }

    fn wgpu_with_plan(
        device: &GpuDevice,
        program: WgslProgram,
        inputs: &[&[f32]],
        plan: &BufferPlan,
        borrowed: &[Option<(&Program, usize)>],
        own: &dyn Fn(usize) -> bool,
    ) -> Self {
        let mut slots: Vec<GpuBuffer> = plan
            .slot_len
            .iter()
            .zip(borrowed)
            .map(|(&n, b)| match b {
                Some((p, s)) => match &p.storage {
                    Storage::Wgpu(slots) => GpuBuffer {
                        buffer: slots[*s].buffer.clone(),
                        len: slots[*s].len,
                    },
                    #[cfg(feature = "cuda")]
                    _ => panic!("programs on different backends"),
                },
                None => GpuBuffer::uninit(device, n),
            })
            .collect();
        for (i, b) in program.buffers.iter().enumerate() {
            let Some(k) = b.input.filter(|&k| own(k)) else {
                continue;
            };
            let s = plan.slot[i];
            // a whole-slot input is uploaded as its own buffer, as the old
            // executor did
            let fresh = match b.format {
                Format::F16 => GpuBuffer::from_u32_slice(device, &pack_f16(inputs[k])),
                Format::F32 => GpuBuffer::from_slice(device, inputs[k]),
                Format::BF16 => unreachable!("bf16 is interpreter-only"),
            };
            if fresh.len() == plan.slot_len[s] {
                slots[s] = fresh;
            } else {
                write_wgpu(device, &slots[s], b.format, inputs[k]);
            }
        }
        let p = Self::assemble(program, Storage::Wgpu(slots), plan);
        for (i, a) in p.args.iter().enumerate() {
            let (out, reads) = a.split_last().unwrap();
            assert!(
                !reads.contains(out),
                "kernel {i} updates a slot in place: wgpu cannot bind one buffer \
                 read-only and read-write in one dispatch (plan without donations)"
            );
        }
        p
    }

    fn assemble(program: WgslProgram, storage: Storage, plan: &BufferPlan) -> Self {
        let mut p = Self {
            program,
            storage,
            slot: plan.slot.clone(),
            args: Vec::new(),
            order: plan.order.clone(),
            recording: None,
        };
        p.args = p
            .program
            .kernels
            .iter()
            .map(|k| {
                k.reads
                    .iter()
                    .chain(std::iter::once(&k.node))
                    .map(|&t| p.slot_of(t))
                    .collect()
            })
            .collect();
        p
    }

    fn buffer_index(&self, t: TensorId) -> usize {
        let t = self.program.storage(t);
        self.program
            .buffers
            .iter()
            .position(|b| b.node == t)
            .expect("tensor has no buffer")
    }

    fn slot_of(&self, t: TensorId) -> usize {
        self.slot[self.buffer_index(t)]
    }

    /// The tensor bound to graph input `k`.
    pub fn input(&self, k: usize) -> TensorId {
        self.program
            .buffers
            .iter()
            .find(|b| b.input == Some(k))
            .expect("input not bound")
            .node
    }

    /// Format of the buffer holding `t`.
    pub fn format(&self, t: TensorId) -> Format {
        self.program.buffers[self.buffer_index(t)].format
    }

    /// The wgpu buffer holding `t`, for tang-gpu's hand kernels.
    pub fn wgpu_buffer(&self, t: TensorId) -> Option<&GpuBuffer> {
        match &self.storage {
            Storage::Wgpu(s) => Some(&s[self.slot_of(t)]),
            #[cfg(feature = "cuda")]
            _ => None,
        }
    }

    /// Run every kernel in plan order (one submission on wgpu,
    /// asynchronous launches on the CUDA stream, or one graph launch once
    /// [`capture`](Self::capture)d).
    pub fn run(&self, rt: &Runtime) {
        match rt {
            Runtime::Wgpu { device, cache } => match &self.recording {
                Some(rec) => {
                    let mut cache = cache.borrow_mut();
                    cache.flush(device);
                    let mut enc = device
                        .device
                        .create_command_encoder(&wgpu::CommandEncoderDescriptor { label: None });
                    {
                        let mut pass = enc.begin_compute_pass(&wgpu::ComputePassDescriptor {
                            label: Some("tang-gpu program"),
                            timestamp_writes: None,
                        });
                        for (pipe, bind, x, y) in &rec.passes {
                            pass.set_pipeline(pipe);
                            pass.set_bind_group(0, bind, &[]);
                            pass.dispatch_workgroups(*x, *y, 1);
                        }
                    }
                    device.queue.submit(std::iter::once(enc.finish()));
                }
                None => self.dispatch(device, &mut cache.borrow_mut()),
            },
            #[cfg(feature = "cuda")]
            Runtime::Cuda(d) => {
                if let Storage::Cuda { graph: Some(g), .. } = &self.storage {
                    g.launch().expect("graph launch");
                    return;
                }
                self.launch_all(d);
            }
        }
    }

    #[cfg(feature = "cuda")]
    fn launch_all(&self, d: &CudaDevice) {
        for &i in &self.order {
            self.run_cuda(d, i);
        }
    }

    /// [`run`](Self::run) on a bare wgpu device and kernel cache: every
    /// kernel as one submission.
    pub fn dispatch(&self, device: &GpuDevice, cache: &mut KernelCache) {
        cache.begin_batch();
        for &i in &self.order {
            self.run_wgpu(device, cache, i);
        }
        // leaving the cache in batch mode would make a later
        // `to_vec_sync` (the hand path's readbacks) wait on work that was
        // never submitted
        cache.end_batch(device);
    }

    /// [`run_kernel`](Self::run_kernel) on a bare wgpu device.
    pub fn dispatch_kernel(&self, device: &GpuDevice, cache: &mut KernelCache, i: usize) {
        self.run_wgpu(device, cache, i);
    }

    /// Record one run as a CUDA graph; later [`run`](Self::run)s replay
    /// it (same kernels, same slots — host writes between runs are seen).
    /// Needs a runtime from [`Runtime::cuda_capturable`]. On wgpu: build
    /// every kernel's pipeline, bind group and uniform once, so a run is
    /// one command buffer with one compute pass (the kernels in order).
    pub fn capture(&mut self, rt: &Runtime) {
        #[cfg(feature = "cuda")]
        if let Runtime::Cuda(d) = rt {
            use cudarc::driver::sys::{CUgraphInstantiate_flags, CUstreamCaptureMode};
            assert!(
                d.capturable(),
                "capture needs Runtime::cuda_capturable (own stream, no event tracking)"
            );
            if let Storage::Cuda { graph, .. } = &mut self.storage {
                *graph = None;
            }
            d.sync();
            d.stream
                .begin_capture(CUstreamCaptureMode::CU_STREAM_CAPTURE_MODE_THREAD_LOCAL)
                .expect("begin capture");
            self.launch_all(d);
            let g = d
                .stream
                .end_capture(
                    CUgraphInstantiate_flags::CUDA_GRAPH_INSTANTIATE_FLAG_AUTO_FREE_ON_LAUNCH,
                )
                .expect("end capture");
            if let Storage::Cuda { graph, .. } = &mut self.storage {
                *graph = g;
            }
            return;
        }
        #[allow(irrefutable_let_patterns)]
        if let Runtime::Wgpu { device, cache } = rt {
            self.recording = None;
            let Storage::Wgpu(slots) = &self.storage else {
                panic!("program and runtime are on different backends")
            };
            let mut cache = cache.borrow_mut();
            let passes = self
                .order
                .iter()
                .map(|&i| {
                    let k = &self.program.kernels[i];
                    let bufs: Vec<&GpuBuffer> = self.args[i].iter().map(|&s| &slots[s]).collect();
                    let (pipe, layout) = cache.pipeline(
                        device,
                        &k.source,
                        bufs.len(),
                        &[bufs.len() - 1],
                        k.workgroup_size,
                    );
                    let bind = cache.bind(device, &layout, &bufs, &[k.points, 0, 0, 0]);
                    let groups = k.count.div_ceil(k.workgroup_size);
                    (pipe, bind, groups.min(65535), groups.div_ceil(65535))
                })
                .collect();
            self.recording = Some(WgpuRecording { passes });
        }
    }

    /// Run kernel `i` only (its inputs must already be computed).
    pub fn run_kernel(&self, rt: &Runtime, i: usize) {
        match rt {
            Runtime::Wgpu { device, cache } => self.run_wgpu(device, &mut cache.borrow_mut(), i),
            #[cfg(feature = "cuda")]
            Runtime::Cuda(d) => self.run_cuda(d, i),
        }
    }

    fn run_wgpu(&self, device: &GpuDevice, cache: &mut KernelCache, i: usize) {
        #[allow(irrefutable_let_patterns)]
        let Storage::Wgpu(slots) = &self.storage
        else {
            panic!("program and runtime are on different backends")
        };
        let k = &self.program.kernels[i];
        let bufs: Vec<&GpuBuffer> = self.args[i].iter().map(|&s| &slots[s]).collect();
        cache.dispatch_buffers(
            device,
            &k.source,
            &bufs,
            &[bufs.len() - 1],
            &[k.points, 0, 0, 0],
            k.count,
            k.workgroup_size,
        );
    }

    #[cfg(feature = "cuda")]
    fn run_cuda(&self, d: &CudaDevice, i: usize) {
        use cudarc::driver::{LaunchConfig, PushKernelArg};
        let Storage::Cuda {
            slots, functions, ..
        } = &self.storage
        else {
            panic!("program and runtime are on different backends")
        };
        let k = &self.program.kernels[i];
        let cfg = LaunchConfig {
            grid_dim: (k.count.div_ceil(k.workgroup_size), 1, 1),
            block_dim: (k.workgroup_size, 1, 1),
            shared_mem_bytes: crate::cuda::dynamic_smem(&k.source),
        };
        let mut launch = d.stream.launch_builder(&functions[i]);
        for &s in &self.args[i] {
            launch.arg(&*slots[s]);
        }
        launch.arg(&k.points);
        unsafe { launch.launch(cfg) }.expect("launch");
    }

    /// Read `t` back as f32 (waits for queued work; f16 widened exactly).
    pub fn read(&self, rt: &Runtime, t: TensorId) -> Vec<f32> {
        match (rt, &self.storage) {
            (Runtime::Wgpu { device, cache }, Storage::Wgpu(_)) => {
                cache.borrow_mut().flush(device);
                self.read_wgpu(device, t)
            }
            #[cfg(feature = "cuda")]
            (Runtime::Cuda(d), Storage::Cuda { slots, .. }) => {
                let b = &self.program.buffers[self.buffer_index(t)];
                let n = words(b);
                let mut out = vec![0.0f32; n];
                d.stream
                    .memcpy_dtoh(&slots[self.slot_of(t)].slice(0..n), &mut out)
                    .expect("download");
                d.sync();
                unpack_words(b.format, &out, b.len)
            }
            #[allow(unreachable_patterns)]
            _ => panic!("program and runtime are on different backends"),
        }
    }

    /// [`read`](Self::read) on a bare wgpu device (work queued in a
    /// [`KernelCache`] batch must be flushed first).
    pub fn read_wgpu(&self, device: &GpuDevice, t: TensorId) -> Vec<f32> {
        let b = &self.program.buffers[self.buffer_index(t)];
        let Some(buf) = self.wgpu_buffer(t) else {
            panic!("program is not on wgpu")
        };
        let raw = buf.to_vec_sync(device);
        match b.format {
            Format::F16 => unpack_f16(&raw, b.len),
            _ => raw[..b.len].to_vec(),
        }
    }

    /// Overwrite `t` (usually an input) from the host.
    pub fn write(&self, rt: &Runtime, t: TensorId, data: &[f32]) {
        let b = &self.program.buffers[self.buffer_index(t)];
        assert_eq!(data.len(), b.len, "write length");
        let s = self.slot_of(t);
        match (rt, &self.storage) {
            (Runtime::Wgpu { device, cache }, Storage::Wgpu(slots)) => {
                cache.borrow_mut().flush(device);
                write_wgpu(device, &slots[s], b.format, data);
            }
            #[cfg(feature = "cuda")]
            (Runtime::Cuda(d), Storage::Cuda { slots, .. }) => {
                use cudarc::driver::DevicePtr;
                let host = pack_words(b.format, data);
                let (dst, _sync) = slots[s].device_ptr(&d.stream);
                unsafe {
                    cudarc::driver::result::memcpy_htod_async(dst, &host[..], d.stream.cu_stream())
                }
                .expect("upload");
                // `data` is borrowed only for this call
                d.sync();
            }
            #[allow(unreachable_patterns)]
            _ => panic!("program and runtime are on different backends"),
        }
    }

    /// Device-side copy of `src`'s tensor `src_t` into this program's
    /// tensor `dst` (same runtime; queued in order with the kernels).
    pub fn copy(&self, rt: &Runtime, dst: TensorId, src: &Program, src_t: TensorId) {
        let (db, sb) = (
            &self.program.buffers[self.buffer_index(dst)],
            &src.program.buffers[src.buffer_index(src_t)],
        );
        assert_eq!((db.len, db.format), (sb.len, sb.format), "copy shape");
        let (ds, ss) = (self.slot_of(dst), src.slot_of(src_t));
        match (rt, &self.storage, &src.storage) {
            (Runtime::Wgpu { device, cache }, Storage::Wgpu(d), Storage::Wgpu(s)) => {
                let mut cache = cache.borrow_mut();
                if d[ds].len() == s[ss].len() {
                    d[ds].copy_from(device, &mut cache, &s[ss]);
                } else {
                    copy_wgpu(device, &mut cache, &d[ds], &s[ss], words(db));
                }
            }
            #[cfg(feature = "cuda")]
            (
                Runtime::Cuda(dev),
                Storage::Cuda { slots: d, .. },
                Storage::Cuda { slots: s, .. },
            ) => {
                use cudarc::driver::DevicePtr;
                let (dp, _a) = d[ds].device_ptr(&dev.stream);
                let (sp, _b) = s[ss].device_ptr(&dev.stream);
                unsafe {
                    cudarc::driver::result::memcpy_dtod_async(
                        dp,
                        sp,
                        words(db) * 4,
                        dev.stream.cu_stream(),
                    )
                }
                .expect("dtod");
            }
            #[allow(unreachable_patterns)]
            _ => panic!("programs and runtime are on different backends"),
        }
    }

    /// Milliseconds per run of the whole program: the minimum over five
    /// batches of `iters` (a shared GPU only ever adds time).
    pub fn time(&self, rt: &Runtime, iters: usize) -> f64 {
        time_with(rt, iters, || self.run(rt))
    }

    /// Milliseconds per launch of kernel `i` alone. On CUDA: the minimum
    /// over `5 * iters` single launches, each bracketed by events — on a
    /// time-sliced GPU a batch of launches almost always straddles another
    /// tenant's slice, a single short launch usually does not.
    pub fn time_kernel(&self, rt: &Runtime, i: usize, iters: usize) -> f64 {
        #[cfg(feature = "cuda")]
        if let Runtime::Cuda(dev) = rt {
            use cudarc::driver::sys::CUevent_flags::CU_EVENT_DEFAULT;
            for _ in 0..3 {
                self.run_kernel(rt, i);
            }
            rt.sync();
            return (0..5 * iters)
                .map(|_| {
                    let a = dev
                        .stream
                        .record_event(Some(CU_EVENT_DEFAULT))
                        .expect("event");
                    self.run_kernel(rt, i);
                    let b = dev
                        .stream
                        .record_event(Some(CU_EVENT_DEFAULT))
                        .expect("event");
                    b.synchronize().expect("sync");
                    a.elapsed_ms(&b).expect("elapsed") as f64
                })
                .fold(f64::INFINITY, f64::min);
        }
        time_with(rt, iters, || {
            self.run_kernel(rt, i);
            #[allow(irrefutable_let_patterns)]
            if let Runtime::Wgpu { device, cache } = rt {
                cache.borrow_mut().flush(device);
            }
        })
    }
    /// Lower `g` and tune it for `rt`: per kernel, the backend-native
    /// lowering is timed against the portable one and the faster kept.
    ///
    /// - CUDA: every tensor-core tile (in each `MMA_SHAPES` block shape)
    ///   against its transpiled-WGSL twin.
    /// - wgpu on Metal (MSL passthrough): every simdgroup-matrix MSL tile
    ///   (`to_msl_mma`, what `TANG_NATIVE=1` forces for all kernels)
    ///   against its WGSL kernel.
    /// - other wgpu adapters have one lowering: [`Program::compile`].
    ///
    /// The choices are stored in `cache` (keyed by the device and every
    /// variant's sources) so the measurement is paid once per chip. The
    /// WGSL *schedule* autotuner (`tang_bench::ir_gpu::autotune_kernels`,
    /// `TuningCache`) is a different search — over graph rewrites, before
    /// lowering — and composes with this one: tune the graph, then lower
    /// it here.
    pub fn tuned(
        rt: &Runtime,
        g: &TensorGraph,
        outputs: &[TensorId],
        inputs: &[&[f32]],
        cache: Option<&std::path::Path>,
    ) -> (Self, TuneReport) {
        match rt {
            Runtime::Wgpu { device, .. } => {
                let variants = vec![g.to_wgsl(outputs), g.to_msl_mma(outputs)];
                let same_bindings = variants[0].kernels.len() == variants[1].kernels.len()
                    && variants[0]
                        .kernels
                        .iter()
                        .zip(&variants[1].kernels)
                        .all(|(a, b)| a.node == b.node && a.reads == b.reads);
                if !device.msl_passthrough || !same_bindings {
                    let program = variants.into_iter().next().unwrap();
                    return (Self::new(rt, program, inputs), TuneReport::default());
                }
                Self::tune_variants(rt, variants, "tang-wgpu-tuning", inputs, cache)
            }
            #[cfg(feature = "cuda")]
            Runtime::Cuda(_) => {
                use tang_compile::tensor::cuda::MMA_SHAPES;
                // variant 0: every kernel transpiled; 1 + v: the
                // tensor-core tiles in block shape MMA_SHAPES[v]
                let variants: Vec<WgslProgram> = std::iter::once(None)
                    .chain((0..MMA_SHAPES.len()).map(Some))
                    .map(|v| g.to_cuda_variant(outputs, v))
                    .collect();
                Self::tune_variants(rt, variants, "tang-cuda-tuning", inputs, cache)
            }
        }
    }

    /// Pick a variant per kernel. `variants[0]` is the portable lowering,
    /// the rest native ones with the same kernels and bindings; kernels
    /// whose sources differ are timed, the others take variant 0. Cache
    /// file: a `<tag> <key>` header, then `kernel variant` for every tuned
    /// kernel not on variant 1.
    fn tune_variants(
        rt: &Runtime,
        mut variants: Vec<WgslProgram>,
        tag: &str,
        inputs: &[&[f32]],
        cache: Option<&std::path::Path>,
    ) -> (Self, TuneReport) {
        let n_k = variants[0].kernels.len();
        assert!(variants.iter().all(|p| p.kernels.len() == n_k));
        // per kernel, the variants worth timing: distinct sources only
        let candidates: Vec<Vec<usize>> = (0..n_k)
            .map(|i| {
                let mut c: Vec<usize> = Vec::new();
                for (v, p) in variants.iter().enumerate() {
                    let src = &p.kernels[i].source;
                    if !c.iter().any(|&u| variants[u].kernels[i].source == *src) {
                        c.push(v);
                    }
                }
                c
            })
            .collect();
        let differs: Vec<usize> = (0..n_k).filter(|&i| candidates[i].len() > 1).collect();
        let key = {
            use std::hash::{Hash, Hasher};
            let mut h = std::collections::hash_map::DefaultHasher::new();
            rt.name().hash(&mut h);
            for p in &variants {
                for k in &p.kernels {
                    k.source.hash(&mut h);
                }
            }
            h.finish()
        };
        let header = format!("{tag} {key:016x}");
        // cache lines: `kernel variant` for every tuned kernel not on variant 1
        let cached: Option<Vec<(usize, usize)>> = cache.and_then(|p| {
            let text = std::fs::read_to_string(p).ok()?;
            let mut lines = text.lines();
            (lines.next()? == header).then(|| {
                lines
                    .filter_map(|l| {
                        let (i, v) = l.trim().split_once(' ')?;
                        Some((i.parse().ok()?, v.parse().ok()?))
                    })
                    .collect()
            })
        });
        let from_cache = cached.is_some();
        let mut choice: Vec<usize> = (0..n_k)
            .map(|i| usize::from(candidates[i].len() > 1))
            .collect();
        match cached {
            Some(v) => {
                for (i, c) in v {
                    if i < n_k && c < variants.len() {
                        choice[i] = c;
                    }
                }
            }
            None => {
                let progs: Vec<Self> = variants
                    .drain(..)
                    .map(|p| Self::new(rt, p, inputs))
                    .collect();
                // every kernel's inputs exist once a whole run has gone through
                for p in &progs {
                    p.run(rt);
                }
                for &i in &differs {
                    let mut best = (f64::INFINITY, 0);
                    for &v in &candidates[i] {
                        let t = progs[v].time_kernel(rt, i, 10);
                        if t < best.0 {
                            best = (t, v);
                        }
                    }
                    choice[i] = best.1;
                }
                if let Some(p) = cache {
                    let mut text = header.clone();
                    for &i in &differs {
                        if choice[i] != 1 {
                            text.push_str(&format!("\n{i} {}", choice[i]));
                        }
                    }
                    text.push('\n');
                    if let Some(dir) = p.parent() {
                        let _ = std::fs::create_dir_all(dir);
                    }
                    if let Err(e) = std::fs::write(p, text) {
                        eprintln!("tuning cache: could not write {}: {e}", p.display());
                    }
                }
                variants = progs.into_iter().map(|p| p.program).collect();
            }
        }
        let mut program = variants.remove(0);
        for (i, &c) in choice.iter().enumerate() {
            if c != 0 {
                std::mem::swap(&mut program.kernels[i], &mut variants[c - 1].kernels[i]);
            }
        }
        if std::env::var_os("TANG_TUNE_VERBOSE").is_some() {
            for &i in &differs {
                eprintln!("tune: kernel {i} -> variant {}", choice[i]);
            }
        }
        let report = TuneReport {
            native_kept: differs.iter().filter(|&&i| choice[i] != 0).count(),
            native_total: differs.len(),
            from_cache,
        };
        (Self::new(rt, program, inputs), report)
    }
}

fn time_with(rt: &Runtime, iters: usize, f: impl Fn()) -> f64 {
    for _ in 0..3 {
        f();
    }
    rt.sync();
    (0..5)
        .map(|_| {
            let t = std::time::Instant::now();
            for _ in 0..iters {
                f();
            }
            rt.sync();
            t.elapsed().as_secs_f64() * 1e3 / iters as f64
        })
        .fold(f64::INFINITY, f64::min)
}

/// Write `data` at the start of `buf` (which may be a larger slot).
fn write_wgpu(device: &GpuDevice, buf: &GpuBuffer, format: Format, data: &[f32]) {
    match format {
        Format::F16 => {
            let words = pack_f16(data);
            device
                .queue
                .write_buffer(&buf.buffer, 0, bytemuck::cast_slice(&words));
        }
        _ => device
            .queue
            .write_buffer(&buf.buffer, 0, bytemuck::cast_slice(data)),
    }
}

/// Copy the first `words` of `src` into `dst` (buffers of different sizes).
fn copy_wgpu(
    device: &GpuDevice,
    cache: &mut KernelCache,
    dst: &GpuBuffer,
    src: &GpuBuffer,
    words: usize,
) {
    let mut enc = device
        .device
        .create_command_encoder(&wgpu::CommandEncoderDescriptor { label: None });
    enc.copy_buffer_to_buffer(&src.buffer, 0, &dst.buffer, 0, (words * 4) as u64);
    cache.enqueue(enc.finish());
}

/// Host values in a buffer's device layout, as f32 words (f16/bf16 two
/// per word; f32 as is).
#[cfg(feature = "cuda")]
fn pack_words(format: Format, data: &[f32]) -> std::borrow::Cow<'_, [f32]> {
    let bits = |x: f32| match format {
        Format::BF16 => bf16_bits(x as f64) as u32,
        _ => f16_bits(x as f64) as u32,
    };
    match format {
        Format::F32 => std::borrow::Cow::Borrowed(data),
        _ => data
            .chunks(2)
            .map(|p| f32::from_bits(bits(p[0]) | p.get(1).map_or(0, |&x| bits(x) << 16)))
            .collect(),
    }
}

/// Inverse of [`pack_words`]: the first `n` elements, widened to f32.
#[cfg(feature = "cuda")]
fn unpack_words(format: Format, words: &[f32], n: usize) -> Vec<f32> {
    match format {
        Format::F32 => words[..n].to_vec(),
        Format::F16 => unpack_f16(words, n),
        Format::BF16 => words
            .iter()
            .flat_map(|w| {
                let b = w.to_bits();
                [b as u16, (b >> 16) as u16]
            })
            .take(n)
            .map(|h| bf16_from_bits(h) as f32)
            .collect(),
    }
}

/// f32 values → IEEE f16 (round to nearest even), two per u32 word,
/// little end first — the byte layout of a WGSL `array<f16>`.
pub fn pack_f16(v: &[f32]) -> Vec<u32> {
    v.chunks(2)
        .map(|p| {
            let lo = f16_bits(p[0] as f64) as u32;
            let hi = p.get(1).map_or(0, |&x| f16_bits(x as f64) as u32);
            lo | (hi << 16)
        })
        .collect()
}

/// Inverse of [`pack_f16`]: the first `n` halves of `words` (read back as
/// f32 bit patterns), widened to f32.
pub fn unpack_f16(words: &[f32], n: usize) -> Vec<f32> {
    words
        .iter()
        .flat_map(|w| {
            let b = w.to_bits();
            [b as u16, (b >> 16) as u16]
        })
        .take(n)
        .map(|h| f16_from_bits(h) as f32)
        .collect()
}

#[cfg(test)]
mod tests {
    use super::*;

    fn matmul_graph() -> (TensorGraph, TensorId) {
        let mut g = TensorGraph::new();
        let a = g.input(&[8, 4]);
        let b = g.input(&[4, 6]);
        let c = g.matmul(a, b).unwrap();
        let (g, outs) = g.substitute_maps(&[c]);
        (g, outs[0])
    }

    fn inputs() -> (Vec<f32>, Vec<f32>) {
        (
            (0..32).map(|i| i as f32 * 0.1 - 1.0).collect(),
            (0..24).map(|i| (i % 5) as f32 * 0.2).collect(),
        )
    }

    #[test]
    fn program_matches_eval() {
        let Ok(rt) = Runtime::select() else { return };
        let (g, c) = matmul_graph();
        let (a, b) = inputs();
        let p = Program::compile(&rt, &g, &[c], &[&a, &b]);
        p.run(&rt);
        let got = p.read(&rt, c);
        let want = g.eval(
            &[
                a.iter().map(|&x| x as f64).collect(),
                b.iter().map(|&x| x as f64).collect(),
            ],
            &[c],
        );
        for (x, y) in got.iter().zip(&want[0]) {
            assert!((*x as f64 - y).abs() < 1e-3, "{x} vs {y}");
        }
    }

    #[test]
    fn write_copy_and_plan() {
        let Ok(rt) = Runtime::select() else { return };
        let (g, c) = matmul_graph();
        let (a, b) = inputs();
        let program = rt.lower(&g, &[c]);
        // all buffers in one oversized slot each: exercises slot != buffer sizes
        let mut plan = BufferPlan::identity(&program);
        for n in &mut plan.slot_len {
            *n += 3;
        }
        let p = Program::with_plan(&rt, program, &[&a, &b], &plan);
        p.run(&rt);
        let first = p.read(&rt, c);
        let q = Program::compile(&rt, &g, &[c], &[&a, &b]);
        q.write(&rt, q.input(0), &vec![0.0; a.len()]);
        q.run(&rt);
        assert!(q.read(&rt, c).iter().all(|&x| x == 0.0));
        q.copy(&rt, q.input(0), &p, p.input(0));
        q.run(&rt);
        assert_eq!(q.read(&rt, c), first);
    }

    /// CUDA: f16 and bf16 storage (inputs, an intermediate and the
    /// output, with a half accumulator) matches the emulator.
    #[cfg(feature = "cuda")]
    #[test]
    fn cuda_half_storage_matches_emulation() {
        use tang::Scalar;
        use tang_compile::tensor::Precision;
        use tang_expr::ExprId;
        let Some(rt) = Runtime::cuda() else { return };
        for f in [Format::F16, Format::BF16] {
            let mut g = TensorGraph::new();
            let a = g.input(&[37, 29]);
            let b = g.input(&[29, 23]);
            let c = g.matmul(a, b).unwrap();
            let d = g
                .map(&[c], |v| {
                    v[0] * ExprId::from_f64(0.5) + ExprId::from_f64(1.0)
                })
                .unwrap();
            let (mut g, outs) = g.substitute_maps(&[d]);
            g.schedule_auto(&outs);
            let d = outs[0];
            let full = Precision {
                storage: f,
                accum: f,
            };
            for t in [a, b] {
                g.set_precision(t, Precision::storage(f));
            }
            g.set_precision(d, full);
            let av: Vec<f32> = (0..37 * 29)
                .map(|i| ((i * 7) % 13) as f32 * 0.1 - 0.6)
                .collect();
            let bv: Vec<f32> = (0..29 * 23)
                .map(|i| ((i * 5) % 11) as f32 * 0.1 - 0.5)
                .collect();
            let p = Program::compile(&rt, &g, &[d], &[&av, &bv]);
            assert!(p.program.buffers.iter().any(|b| b.format == f));
            p.run(&rt);
            let got = p.read(&rt, d);
            let want = g.eval_emulated(
                &[
                    av.iter().map(|&x| x as f64).collect(),
                    bv.iter().map(|&x| x as f64).collect(),
                ],
                &[d],
            );
            let scale = want[0].iter().fold(0.0f64, |m, x| m.max(x.abs()));
            let ulp = if f == Format::F16 { 1e-3 } else { 8e-3 };
            for (x, y) in got.iter().zip(&want[0]) {
                assert!(
                    ((*x as f64) - y).abs() <= 4.0 * ulp * scale,
                    "{f:?}: {x} vs {y}"
                );
            }
        }
    }

    /// CUDA: a matmul whose operands are f16 (bf16) runs on m16n8k16
    /// fragments in every block shape and matches the emulator (fp32
    /// accumulation, the output stored in the operands' format or f32);
    /// with an f32 B operand too (converted while staging).
    #[cfg(feature = "cuda")]
    #[test]
    fn cuda_half_mma_matches_emulation() {
        use tang_compile::tensor::{cuda::MMA_SHAPES, Precision};
        let Some(rt) = Runtime::cuda() else { return };
        for f in [Format::F16, Format::BF16] {
            for (out_f, b_f) in [(Format::F32, f), (f, f), (Format::F32, Format::F32)] {
                let (m, k, n) = (200, 136, 72);
                let mut g = TensorGraph::new();
                let a = g.input(&[m, k]);
                let b = g.input(&[k, n]);
                let c = g.matmul(a, b).unwrap();
                let (mut g, outs) = g.substitute_maps(&[c]);
                g.schedule_auto(&outs);
                let c = outs[0];
                for (t, tf) in [(a, f), (b, b_f)] {
                    g.set_precision(t, Precision::storage(tf));
                }
                g.set_precision(c, Precision::storage(out_f));
                let av: Vec<f32> = (0..m * k)
                    .map(|i| ((i * 7) % 13) as f32 * 0.1 - 0.6)
                    .collect();
                let bv: Vec<f32> = (0..k * n)
                    .map(|i| ((i * 5) % 11) as f32 * 0.1 - 0.5)
                    .collect();
                let want = g.eval_emulated(
                    &[
                        av.iter().map(|&x| x as f64).collect(),
                        bv.iter().map(|&x| x as f64).collect(),
                    ],
                    &[c],
                );
                let scale = want[0].iter().fold(0.0f64, |m, x| m.max(x.abs()));
                for v in 0..MMA_SHAPES.len() {
                    let program = g.to_cuda_variant(&[c], Some(v));
                    assert!(
                        program.kernels[0].source.contains("m16n8k16"),
                        "{f:?} variant {v} is not on half mma"
                    );
                    let p = Program::new(&rt, program, &[&av, &bv]);
                    p.run(&rt);
                    let got = p.read(&rt, c);
                    // a mixed tile rounds its f32 operand to the format (the
                    // emulator does not)
                    let tol = if out_f == Format::F32 && b_f == f {
                        1e-5
                    } else if f == Format::F16 {
                        1e-3
                    } else {
                        8e-3
                    };
                    let err = got
                        .iter()
                        .zip(&want[0])
                        .map(|(x, y)| ((*x as f64) - y).abs())
                        .fold(0.0, f64::max);
                    assert!(
                        err <= tol * scale,
                        "{f:?}/{b_f:?}/{out_f:?} v{v}: err {err:e}"
                    );
                }
            }
        }
    }

    /// CUDA: half tiles over transposed operands (B stored [n, k] like a
    /// weight, A stored [k, m] like a weight gradient's activation) are
    /// staged in their native m16n8k16 layouts and match the emulator.
    #[cfg(feature = "cuda")]
    #[test]
    fn cuda_half_mma_layouts() {
        use tang_compile::tensor::{cuda::MMA_SHAPES, Precision};
        let Some(rt) = Runtime::cuda() else { return };
        let (m, k, n) = (136, 200, 72);
        for (ta, tb) in [(false, true), (true, false), (true, true)] {
            for (f, b_f) in [
                (Format::F16, Format::F16),
                (Format::BF16, Format::BF16),
                (Format::F16, Format::F32),
            ] {
                let mut g = TensorGraph::new();
                let a_shape = if ta { [k, m] } else { [m, k] };
                let a_in = g.input(&a_shape);
                let b_shape = if tb { [n, k] } else { [k, n] };
                let b_in = g.input(&b_shape);
                let a = if ta {
                    g.transpose(a_in, &[1, 0]).unwrap()
                } else {
                    a_in
                };
                let b = if tb {
                    g.transpose(b_in, &[1, 0]).unwrap()
                } else {
                    b_in
                };
                let c = g.matmul(a, b).unwrap();
                let (mut g, outs) = g.substitute_maps(&[c]);
                g.schedule_auto(&outs);
                let c = outs[0];
                g.set_precision(a_in, Precision::storage(f));
                g.set_precision(b_in, Precision::storage(b_f));
                let av: Vec<f32> = (0..m * k)
                    .map(|i| ((i * 7) % 13) as f32 * 0.1 - 0.6)
                    .collect();
                let bv: Vec<f32> = (0..k * n)
                    .map(|i| ((i * 5) % 11) as f32 * 0.1 - 0.5)
                    .collect();
                let want = g.eval_emulated(
                    &[
                        av.iter().map(|&x| x as f64).collect(),
                        bv.iter().map(|&x| x as f64).collect(),
                    ],
                    &[c],
                );
                let scale = want[0].iter().fold(0.0f64, |m, x| m.max(x.abs()));
                let tol = if b_f == f { 1e-5 } else { 1e-3 };
                for v in 0..MMA_SHAPES.len() {
                    let program = g.to_cuda_variant(&[c], Some(v));
                    assert!(
                        program.kernels[0].source.contains("m16n8k16"),
                        "{ta}/{tb} {f:?} variant {v} is not on half mma"
                    );
                    let p = Program::new(&rt, program, &[&av, &bv]);
                    p.run(&rt);
                    let got = p.read(&rt, c);
                    let err = got
                        .iter()
                        .zip(&want[0])
                        .map(|(x, y)| ((*x as f64) - y).abs())
                        .fold(0.0, f64::max);
                    assert!(
                        err <= tol * scale,
                        "{ta}/{tb} {f:?}/{b_f:?} v{v}: err {err:e}"
                    );
                }
            }
        }
    }
}
