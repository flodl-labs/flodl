//! System resource sampling: CPU, RAM, GPU memory, GPU utilization.
//!
//! CPU is read from `/proc/stat` (Linux only), RAM from
//! [`crate::sys::mem_info`] (Linux, macOS and Windows).
//! GPU identity (count, names, VRAM totals) comes from
//! [`crate::sys::detect_gpus`]. Live metrics have no single source: NVML
//! for NVIDIA, amdgpu sysfs for AMD (NVIDIA publishes no utilization
//! through sysfs, and asking AMD through a library would mean loading a
//! GPU runtime). Each device's backend is resolved once, at construction,
//! and neither of them initializes the CUDA runtime. The
//! only CUDA-context-dependent
//! read, caching-allocator reserved bytes, is gated on
//! [`crate::tensor::gpu_has_primary_context`] so that constructing or
//! polling a sampler never creates a CUDA context as a side effect.
//! `Monitor::new` runs in every process, including the pre-fan-out
//! launcher, where touching CUDA would break the
//! no-CUDA-before-`Trainer::run` invariant and pin VRAM on every GPU
//! for the life of the process.

use std::collections::VecDeque;
use std::fs;
use std::sync::atomic::{AtomicBool, Ordering};
use std::sync::{Arc, Mutex};
use std::thread;
use std::time::Duration;

/// Background NVML poll interval. Higher rate means denser samples per
/// epoch, so a single barrier-period sample (which can read 0%) gets
/// diluted by surrounding compute samples in the rolling-window mean
/// returned from [`ResourceSampler::sample`]. 250 ms keeps NVML
/// overhead negligible while giving ~13 samples per 3 s epoch.
const GPU_POLL_INTERVAL: Duration = Duration::from_millis(250);

/// Rolling-window size for per-device GPU utilization samples. At
/// [`GPU_POLL_INTERVAL`] = 250 ms, 32 entries covers ~8 s of history
/// — long enough to smooth out brief sync-barrier dips, short enough
/// that the displayed average still tracks real workload shifts
/// (mode changes, batch-size sweeps, schedule transitions) within a
/// few seconds rather than blurring the entire run.
const GPU_UTIL_WINDOW: usize = 32;

/// Per-device GPU snapshot.
#[derive(Debug, Clone, Default)]
pub struct GpuSnapshot {
    /// Physical device index (nvidia-smi / NVML enumeration). Matches
    /// the CUDA runtime index when `CUDA_VISIBLE_DEVICES` is unset; in
    /// scoped-down processes it identifies the actual card rather than
    /// the remapped runtime slot.
    pub device_index: u8,
    /// Device name (e.g., "NVIDIA GeForce RTX 5060 Ti").
    pub name: String,
    /// GPU utilization percentage (0-100), None if NVML unavailable.
    pub util_percent: Option<f32>,
    /// Bytes reserved by the CUDA caching allocator.
    pub vram_allocated_bytes: Option<u64>,
    /// Total physical VRAM in bytes.
    pub vram_total_bytes: Option<u64>,
}

/// A snapshot of system resource usage.
#[derive(Debug, Clone, Default)]
pub struct ResourceSample {
    /// CPU utilization percentage (0-100), None if unavailable.
    pub cpu_percent: Option<f32>,
    /// RAM used by the system in bytes.
    pub ram_used_bytes: Option<u64>,
    /// Total system RAM in bytes.
    pub ram_total_bytes: Option<u64>,
    /// GPU utilization percentage (0-100) for the rank in `aggregate_rank`,
    /// None if NVML unavailable.
    pub gpu_util_percent: Option<f32>,
    /// Total physical VRAM in bytes for the rank in `aggregate_rank`.
    pub vram_total_bytes: Option<u64>,
    /// Bytes reserved by the CUDA caching allocator on the rank in
    /// `aggregate_rank`.
    pub vram_allocated_bytes: Option<u64>,
    /// CUDA device index whose data populates the aggregate fields above.
    /// Picked uniformly at random per `sample()` call so that, over the
    /// run, each rank is observed roughly equally without paying O(N)
    /// per-tick aggregation cost. Per-GPU detail is preserved in `gpus`.
    pub aggregate_rank: Option<u8>,
    /// Per-GPU snapshots (empty on CPU builds).
    pub gpus: Vec<GpuSnapshot>,
}

impl ResourceSample {
    /// Format a compact resource summary string.
    ///
    /// Example: `"CPU: 45% | RAM: 3.2/7.8 GB | GPU: 82% | VRAM: 2.1 GB / 0 KB"`
    pub fn summary(&self) -> String {
        let mut parts = Vec::new();

        if let Some(cpu) = self.cpu_percent {
            parts.push(format!("CPU: {:.0}%", cpu));
        }
        if let (Some(used), Some(total)) = (self.ram_used_bytes, self.ram_total_bytes) {
            parts.push(format!(
                "RAM: {}/{}",
                super::format::format_bytes(used),
                super::format::format_bytes(total),
            ));
        }

        if self.gpus.len() > 1 {
            // Multi-GPU: show per-device VRAM
            for gpu in &self.gpus {
                if let Some(alloc) = gpu.vram_allocated_bytes {
                    let spill = match gpu.vram_total_bytes {
                        Some(total) if alloc > total => alloc - total,
                        _ => 0,
                    };
                    let util = gpu
                        .util_percent
                        .map(|u| format!(" ({:.0}%)", u))
                        .unwrap_or_default();
                    parts.push(format!(
                        "GPU{}: {} / {}{}",
                        gpu.device_index,
                        super::format::format_bytes(alloc),
                        super::format::format_bytes(spill),
                        util,
                    ));
                }
            }
        } else {
            // Single GPU or CPU
            if let Some(gpu) = self.gpu_util_percent {
                parts.push(format!("GPU: {:.0}%", gpu));
            }
            if let Some(alloc) = self.vram_allocated_bytes {
                let spill = match self.vram_total_bytes {
                    Some(total) if alloc > total => alloc - total,
                    _ => 0,
                };
                parts.push(format!(
                    "VRAM: {} / {}",
                    super::format::format_bytes(alloc),
                    super::format::format_bytes(spill),
                ));
            }
        }

        parts.join(" | ")
    }
}

/// Accumulated CPU jiffies from `/proc/stat`.
#[derive(Clone)]
pub(super) struct CpuTimes {
    pub(super) total: u64,
    pub(super) idle: u64,
}

/// Per-device GPU utilization rolling-window accumulator. Background
/// poller pushes a sample per device every [`GPU_POLL_INTERVAL`];
/// [`ResourceSampler::sample`] reads the per-device mean over the last
/// [`GPU_UTIL_WINDOW`] entries without draining the buffer. This
/// dilutes single-sample dips when one poll lands during a sync
/// barrier; with ~32 samples in the window, the per-device mean tracks
/// the between-syncs compute load rather than any individual barrier-
/// period zero.
struct GpuUtilAccum {
    samples: Vec<VecDeque<f32>>,
}

/// Handle for the background GPU utilization poller thread.
struct GpuPollerHandle {
    accum: Arc<Mutex<GpuUtilAccum>>,
    stop: Arc<AtomicBool>,
    thread: Option<thread::JoinHandle<()>>,
}

impl Drop for GpuPollerHandle {
    fn drop(&mut self) {
        self.stop.store(true, Ordering::Relaxed);
        if let Some(h) = self.thread.take() {
            let _ = h.join();
        }
    }
}

/// Where one device's live metrics come from, resolved once at sampler
/// construction.
///
/// The two vendors have no common source: NVIDIA publishes nothing
/// through sysfs, and this crate must not load a GPU runtime to ask
/// AMD, so each keeps its own backend. Resolving per device up front
/// means the poller never re-decides and never pays a lookup per tick.
#[derive(Clone)]
enum LiveMetrics {
    /// NVML through the shim, queried by physical index.
    Nvml,
    /// amdgpu sysfs, with every attribute path already resolved.
    AmdSysfs(crate::sys::AmdMetricsProbe),
    /// Nothing this build can read: a CPU-only build, or an AMD device
    /// whose topology was unreadable (see [`crate::sys::amd_metrics_probes`]).
    None,
}

/// One instantaneous utilization read, routed to the device's backend.
fn read_util(physical_index: u8, live: &LiveMetrics) -> Option<f32> {
    match live {
        LiveMetrics::Nvml => {
            crate::tensor::gpu_utilization_idx(physical_index as i32).map(|u| u as f32)
        }
        LiveMetrics::AmdSysfs(probe) => probe.read().util_percent.map(|u| u as f32),
        LiveMetrics::None => None,
    }
}

/// Static per-device identity, captured once at sampler construction
/// from [`crate::sys::detect_gpus`]. No CUDA runtime involvement, and
/// no per-sample process spawn.
struct GpuStatic {
    /// Physical index (vendor-tool enumeration). NVML queries must use
    /// this: NVML ignores `CUDA_VISIBLE_DEVICES`.
    physical_index: u8,
    name: String,
    total_bytes: Option<u64>,
    /// Resolved live-metrics backend for this device.
    live: LiveMetrics,
}

/// Enumerate GPUs without touching the CUDA runtime. Position in the
/// returned Vec is used as the CUDA runtime index for context-gated
/// allocator reads (exact when `CUDA_VISIBLE_DEVICES` is unset or an
/// ascending index list; a reordering list like `1,0` would mislabel
/// allocator stats, which nothing in flodl's launch paths produces).
fn detect_gpu_statics() -> Vec<GpuStatic> {
    if !cfg!(feature = "gpu") {
        return Vec::new();
    }
    let devices = crate::sys::detect_gpus();
    // Resolved once, and only where an AMD device is actually present:
    // the walk is cheap but pointless on a box that has none, and
    // `detect_gpus` is already vendor-filtered to this build.
    let amd = devices
        .iter()
        .any(|g| g.vendor == crate::sys::GpuVendor::Amd)
        .then(crate::sys::amd_metrics_probes)
        .unwrap_or_default();
    devices
        .into_iter()
        .map(|g| {
            // Probe position is device index by construction, so an
            // absent entry means the topology was unreadable rather
            // than that this device is the wrong one.
            let live = match g.vendor {
                crate::sys::GpuVendor::Amd => amd
                    .get(g.index as usize)
                    .cloned()
                    .map_or(LiveMetrics::None, LiveMetrics::AmdSysfs),
                _ => LiveMetrics::Nvml,
            };
            GpuStatic {
                physical_index: g.index,
                total_bytes: Some(g.vram_bytes()),
                name: g.name,
                live,
            }
        })
        .collect()
}

/// Stateful resource sampler. Maintains previous CPU reading for delta
/// computation and a background thread for GPU utilization averaging.
///
/// GPU utilization is polled via NVML every ~1 second in a background
/// thread. When `sample()` is called, it returns the average over the
/// interval since the last call. This prevents point-in-time sampling
/// artifacts in heterogeneous DDP (where the fast GPU may be idle at
/// epoch boundaries, giving misleadingly low single-sample readings).
///
/// Construction and sampling never initialize the CUDA runtime (see
/// the module docs); a sampler is safe in any process, launcher
/// included.
pub struct ResourceSampler {
    prev_cpu: Option<CpuTimes>,
    gpus: Vec<GpuStatic>,
    gpu_poller: Option<GpuPollerHandle>,
}

impl Default for ResourceSampler {
    fn default() -> Self {
        Self::new()
    }
}

impl ResourceSampler {
    /// Create a new sampler, capturing an initial CPU reading for the
    /// first delta and starting a background GPU utilization poller.
    pub fn new() -> Self {
        let prev_cpu = read_cpu_times();
        let gpus = detect_gpu_statics();
        let gpu_poller = Self::start_gpu_poller(&gpus);
        Self {
            prev_cpu,
            gpus,
            gpu_poller,
        }
    }

    /// Start a background thread that polls NVML utilization at
    /// [`GPU_POLL_INTERVAL`] and feeds a per-device rolling window
    /// (window position i tracks `gpus[i]`, polled by physical index).
    /// Returns `None` if no GPUs are visible.
    fn start_gpu_poller(gpus: &[GpuStatic]) -> Option<GpuPollerHandle> {
        if gpus.is_empty() {
            return None;
        }
        let physical: Vec<(u8, LiveMetrics)> = gpus
            .iter()
            .map(|g| (g.physical_index, g.live.clone()))
            .collect();
        let accum = Arc::new(Mutex::new(GpuUtilAccum {
            samples: physical
                .iter()
                .map(|_| VecDeque::with_capacity(GPU_UTIL_WINDOW))
                .collect(),
        }));
        let stop = Arc::new(AtomicBool::new(false));
        let accum2 = accum.clone();
        let stop2 = stop.clone();
        let thread = thread::Builder::new()
            .name("gpu-util-poller".into())
            .spawn(move || {
                while !stop2.load(Ordering::Relaxed) {
                    thread::sleep(GPU_POLL_INTERVAL);
                    if stop2.load(Ordering::Relaxed) {
                        break;
                    }
                    if let Ok(mut acc) = accum2.lock() {
                        for (i, (phys, live)) in physical.iter().enumerate() {
                            if let Some(util) = read_util(*phys, live) {
                                let buf = &mut acc.samples[i];
                                if buf.len() == GPU_UTIL_WINDOW {
                                    buf.pop_front();
                                }
                                buf.push_back(util);
                            }
                        }
                    }
                }
            })
            .ok()?;
        Some(GpuPollerHandle {
            accum,
            stop,
            thread: Some(thread),
        })
    }

    /// Take a snapshot of current system resources (CPU, RAM, GPU, VRAM).
    ///
    /// CPU utilization is computed as a delta since the previous call.
    /// GPU utilization is averaged over background samples since the last
    /// call (falls back to an instant NVML sample if no background data).
    /// Fields that cannot be read on this platform are `None`.
    pub fn sample(&mut self) -> ResourceSample {
        let mut s = ResourceSample::default();

        // CPU utilization (delta between two readings)
        if let Some(current) = read_cpu_times() {
            if let Some(ref prev) = self.prev_cpu {
                let d_total = current.total.saturating_sub(prev.total);
                let d_idle = current.idle.saturating_sub(prev.idle);
                if d_total > 0 {
                    s.cpu_percent =
                        Some((d_total.saturating_sub(d_idle) as f32 / d_total as f32) * 100.0);
                }
            }
            self.prev_cpu = Some(current);
        }

        if let Some((used, total)) = read_ram() {
            s.ram_used_bytes = Some(used);
            s.ram_total_bytes = Some(total);
        }

        // Read the per-device rolling-window mean WITHOUT draining
        // the buffer: samples persist across `sample()` calls so a
        // short epoch with one sync-period dip averages out against
        // the rest of the window's compute samples. See [`GPU_UTIL_WINDOW`]
        // / [`GPU_POLL_INTERVAL`] for window-sizing rationale.
        let n = self.gpus.len();
        let util_averages: Vec<Option<f32>> = if let Some(ref poller) = self.gpu_poller {
            if let Ok(acc) = poller.accum.lock() {
                acc.samples
                    .iter()
                    .map(|buf| {
                        if buf.is_empty() {
                            None
                        } else {
                            let sum: f32 = buf.iter().sum();
                            Some(sum / buf.len() as f32)
                        }
                    })
                    .collect()
            } else {
                vec![None; n]
            }
        } else {
            vec![None; n]
        };

        // Per-GPU snapshots. Identity from the construction-time
        // nvidia-smi statics, utilization via NVML, allocator stats
        // only where this process already holds a CUDA context.
        for (i, g) in self.gpus.iter().enumerate() {
            let mut gpu = GpuSnapshot {
                device_index: g.physical_index,
                name: g.name.clone(),
                vram_total_bytes: g.total_bytes,
                ..Default::default()
            };
            // Caching-allocator reserved bytes are per-process and take
            // the CUDA runtime index (= position in the visible list).
            // Querying them from a process without a context would
            // CREATE one (pinning VRAM); gate on context presence.
            if crate::tensor::gpu_has_primary_context(i as i32)
                && let Ok(alloc) = crate::tensor::gpu_allocated_bytes_idx(i as i32)
            {
                gpu.vram_allocated_bytes = Some(alloc);
            }
            // Background average if available, else an instant sample
            gpu.util_percent = util_averages
                .get(i)
                .copied()
                .flatten()
                .or_else(|| read_util(g.physical_index, &g.live));
            s.gpus.push(gpu);
        }

        // Aggregate fields: pick one GPU uniformly at random and copy its
        // VRAM + util into the top-level fields. Over many ticks the
        // displayed values cover every rank ergodically; each tick pays
        // O(1) instead of O(world_size). Per-GPU detail stays in `s.gpus`
        // for the timeline CSV / dashboard so this only affects the
        // compact summary surface (epoch log line, summary string).
        if !s.gpus.is_empty() {
            let pick = crate::rng::Rng::from_entropy().usize(s.gpus.len());
            let g = &s.gpus[pick];
            s.aggregate_rank = Some(g.device_index);
            s.vram_total_bytes = g.vram_total_bytes;
            s.vram_allocated_bytes = g.vram_allocated_bytes;
            s.gpu_util_percent = g.util_percent;
        }

        s
    }
}

/// Parse `/proc/stat` first line for CPU jiffies.
pub(super) fn read_cpu_times() -> Option<CpuTimes> {
    let content = fs::read_to_string("/proc/stat").ok()?;
    let line = content.lines().next()?;
    if !line.starts_with("cpu ") {
        return None;
    }
    let fields: Vec<u64> = line
        .split_whitespace()
        .skip(1)
        .filter_map(|s| s.parse().ok())
        .collect();
    if fields.len() < 4 {
        return None;
    }
    // Fields: user, nice, system, idle, iowait, irq, softirq, steal, ...
    let total: u64 = fields.iter().sum();
    let idle = fields[3] + fields.get(4).copied().unwrap_or(0); // idle + iowait
    Some(CpuTimes { total, idle })
}

/// Host RAM as `(used, total)` bytes, where used is what is not
/// available to a new workload.
pub(super) fn read_ram() -> Option<(u64, u64)> {
    crate::sys::mem_info().map(|m| {
        (
            m.total_bytes.saturating_sub(m.available_bytes),
            m.total_bytes,
        )
    })
}

#[cfg(test)]
mod tests {
    use super::*;

    /// Constructing and polling a sampler must never initialize the
    /// CUDA runtime: `Monitor::new` runs in the fan-out launcher, where
    /// a CUDA touch breaks the no-CUDA-before-`Trainer::run` invariant
    /// and a primary context pins VRAM on every device for the life of
    /// the process.
    ///
    /// Only verifiable when nothing else can create a context during the
    /// sampling window, which is why this test is `#[ignore]`: it runs in
    /// the SERIAL lane (`fdl gpu-test-serial`, `--test-threads=1`), where
    /// a context appearing after the start guard can only be the
    /// sampler's own. In the parallel lane the attribution is impossible —
    /// the unignored version failed every `fdl gpu-test -- monitor`-style
    /// filtered run when a concurrently scheduled CUDA test landed a
    /// context inside the 550ms window (its start guard, checked before
    /// the window, had rightly passed).
    #[test]
    #[ignore = "serial lane: context attribution needs --test-threads=1"]
    fn test_resource_sampler_never_initializes_cuda() {
        if crate::tensor::gpu_has_primary_context(0) {
            eprintln!("skipped: CUDA context already present in this process");
            return;
        }
        let mut sampler = ResourceSampler::new();
        let s = sampler.sample();
        // Give the NVML poller a couple of ticks too.
        std::thread::sleep(Duration::from_millis(550));
        let _ = sampler.sample();
        assert!(
            !crate::tensor::gpu_has_primary_context(0),
            "ResourceSampler must not create a CUDA context"
        );
        // Identity still works without a context: totals come from
        // nvidia-smi, allocator stats stay None.
        for gpu in &s.gpus {
            assert!(gpu.vram_allocated_bytes.is_none());
        }
    }

    /// Report which live-metrics backend this box resolved, and what it
    /// reads.
    ///
    /// Nothing in the suite asserts that utilization is populated, and
    /// nothing can: a box with no GPU has to pass too, so a backend that
    /// silently resolves to nothing is indistinguishable from a green
    /// run. `#[ignore]` because it asserts nothing and needs hardware.
    /// Run it when bringing up a new box, which is the moment the answer
    /// is in doubt:
    ///
    /// ```text
    /// cargo test -p flodl --features cuda reports_this_hosts_gpu_metrics \
    ///     -- --ignored --nocapture
    /// ```
    #[test]
    #[ignore = "hardware probe: prints what this host resolves, asserts nothing"]
    fn reports_this_hosts_gpu_metrics() {
        let mut sampler = ResourceSampler::new();
        for g in &sampler.gpus {
            println!(
                "device {} ({}): backend {}",
                g.physical_index,
                g.name,
                match g.live {
                    LiveMetrics::Nvml => "NVML",
                    LiveMetrics::AmdSysfs(_) => "amdgpu sysfs",
                    LiveMetrics::None => "NONE -- no live metrics on this device",
                },
            );
        }
        // A couple of poll intervals, so the rolling window has content
        // and this reports through the same path a run takes.
        thread::sleep(GPU_POLL_INTERVAL * 2);
        for gpu in sampler.sample().gpus {
            println!(
                "device {}: util={:?} vram_total={:?}",
                gpu.device_index, gpu.util_percent, gpu.vram_total_bytes,
            );
        }
    }
}
