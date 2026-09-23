mod cache;
mod check_cuda_version;
mod cluster;
mod endpoint;
pub mod http_server;
pub mod metric;
pub mod proto;
pub mod registry;
#[cfg(feature = "tracing")]
mod trace;
#[cfg(not(feature = "tracing"))]
mod trace {
    pub(crate) fn init() {}
    pub(crate) fn flush() {}
}
mod utils;
mod wire;

pub use registry::{CudaTensorRegistry, RegistryHandle};

use clap::Parser;
use cudarc::driver::result as cuda_driver;
use log::{error, info, warn};
use opentelemetry::global;
use opentelemetry_otlp::WithExportConfig;
use opentelemetry_sdk::metrics::SdkMeterProvider;
use orbitkv_common::grpc::{
    GRPC_SERVER_HTTP2_KEEPALIVE_INTERVAL, GRPC_SERVER_HTTP2_KEEPALIVE_TIMEOUT,
};
use orbitkv_core::{OrbitKVEngine, P2pTransferService};
use prometheus::Registry;
use proto::engine::engine_server::EngineServer;
use pyo3::{PyErr, Python, types::PyAnyMethods};
use std::error::Error;
use std::net::SocketAddr;
use std::sync::Arc;
use std::time::Duration;
use tokio::sync::Notify;
use tonic::transport::Server;
use utils::parse_memory_size;

#[cfg(not(target_env = "msvc"))]
use tikv_jemallocator::Jemalloc;

#[cfg(not(target_env = "msvc"))]
#[global_allocator]
static GLOBAL: Jemalloc = Jemalloc;

#[derive(Parser, Debug)]
#[command(
    name = "orbitkv-cache-manager",
    bin_name = "orbitkv-cache-manager",
    version,
    about = "OrbitKV local cache with optional distributed control"
)]
pub struct Cli {
    /// Peer control address in distributed mode; its port also names the default local socket.
    #[arg(long, default_value = "127.0.0.1:50055")]
    pub addr: SocketAddr,

    /// CUDA devices to initialize (comma-separated, e.g., "0,1,2,3").
    /// If not specified, auto-detects and initializes all available GPUs.
    #[arg(long, value_delimiter = ',')]
    pub devices: Vec<i32>,

    /// Pinned memory pool size (supports units: kb, mb, gb, tb)
    /// Examples: "10gb", "500mb", "1tb"
    #[arg(long, default_value = "30gb", value_parser = parse_memory_size)]
    pub pool_size: usize,

    /// Hint for typical value size (supports units: kb, mb, gb, tb); tunes cache + allocator
    #[arg(long, value_parser = parse_memory_size)]
    pub hint_value_size: Option<usize>,

    /// Bytes owned by queries through preparation, ready leases and GPU loads.
    /// Defaults to 75% of --pool-size.
    #[arg(long, value_parser = parse_memory_size)]
    pub query_budget: Option<usize>,

    /// Query bytes per registered instance; defaults to the global query budget.
    #[arg(long, value_parser = parse_memory_size)]
    pub query_instance_budget: Option<usize>,

    /// Maximum bytes in each ordinary read batch (0 keeps the demand baseline).
    /// Prepared reads always use at most 32 MiB, or one oversized page.
    #[arg(long, default_value = "0", value_parser = parse_memory_size)]
    pub query_read_batch: usize,

    /// Stop submitting new ordinary reads after this relative deadline (0 disables).
    #[arg(long, default_value_t = 0)]
    pub query_read_timeout_ms: u64,

    /// Maximum read batches per ordinary query (0 unlimited, 1 best effort).
    #[arg(long, default_value_t = 0)]
    pub query_read_max_batches: usize,

    /// Use huge pages for pinned memory pool (faster allocation).
    /// Requires pre-configured huge pages via /proc/sys/vm/nr_hugepages
    #[arg(long, default_value_t = false)]
    pub use_hugepages: bool,

    /// Enable TinyLFU admission policy for cache (default: plain LRU)
    #[arg(long, default_value_t = false)]
    pub enable_lfu_admission: bool,

    /// Disable NUMA-aware memory allocation (use single pool instead of per-node pools)
    #[arg(long, default_value_t = false)]
    pub disable_numa_affinity: bool,

    /// HTTP server address for health check and Prometheus metrics.
    /// Always enabled for health check endpoint.
    #[arg(long, default_value = "0.0.0.0:9091")]
    pub http_addr: SocketAddr,

    /// Enable Prometheus /metrics endpoint on the HTTP server.
    #[arg(long, default_value_t = true)]
    pub enable_prometheus: bool,

    /// Enable OTLP metrics export over gRPC (e.g. http://127.0.0.1:4317).
    #[arg(long)]
    pub metrics_otel_endpoint: Option<String>,

    /// Period (seconds) for exporting OTLP metrics (only used when endpoint is set).
    #[arg(long, default_value_t = 10)]
    pub metrics_period_secs: u64,

    /// Log level (trace, debug, info, warn, error)
    #[arg(long, default_value = "info")]
    pub log_level: String,

    /// Enable SSD cache for sealed blocks. Provide one or more cache directories.
    /// Repeat the flag to use multiple paths (e.g. one per SSD device).
    #[arg(long, num_args = 1..)]
    pub ssd_cache_path: Vec<String>,

    /// SSD cache capacity (supports units: kb, mb, gb, tb). Default: 512gb
    #[arg(long, default_value = "512gb", value_parser = parse_memory_size)]
    pub ssd_cache_capacity: usize,

    /// SSD cache file shards per path. Use >1 for parallel filesystems such as GPFS.
    /// When multiple --ssd-cache-path values are given each path receives this many
    /// shards so that every device is utilised. Default: 1
    #[arg(long, default_value = "1")]
    pub ssd_cache_shards: std::num::NonZeroUsize,

    /// SSD write queue depth (max pending write batches). Default: 8
    #[arg(long, default_value_t = orbitkv_core::DEFAULT_SSD_WRITE_QUEUE_DEPTH)]
    pub ssd_write_queue_depth: usize,

    /// SSD prefetch queue depth (max pending prefetch batches). Default: 2
    #[arg(long, default_value_t = orbitkv_core::DEFAULT_SSD_PREFETCH_QUEUE_DEPTH)]
    pub ssd_prefetch_queue_depth: usize,

    /// SSD write inflight (max concurrent block writes). Default: 2
    #[arg(long, default_value_t = orbitkv_core::DEFAULT_SSD_WRITE_INFLIGHT)]
    pub ssd_write_inflight: usize,

    /// SSD prefetch inflight (max concurrent block reads). Default: 16
    #[arg(long, default_value_t = orbitkv_core::DEFAULT_SSD_PREFETCH_INFLIGHT)]
    pub ssd_prefetch_inflight: usize,

    /// Trace sampling rate (0.0–1.0). E.g. 0.01 = 1%. Default: 1.0 (100%)
    #[arg(long, default_value_t = 1.0, value_parser = parse_sample_rate)]
    pub trace_sample_rate: f64,

    /// Number of shards for the pinned memory pool (reduces allocator lock contention).
    /// The pool is split into this many independent sub-pools with round-robin allocation.
    #[arg(long, default_value_t = 1)]
    pub pool_shards: usize,

    /// Allocate each block separately in DRAM-only mode (always enabled with SSD).
    /// Lets evicted pages return memory independently of surviving batch pages.
    #[arg(long, default_value_t = false)]
    pub blockwise_alloc: bool,

    /// Optional Mooncake RDMA rail filter (e.g. --nics mlx5_0,mlx5_1).
    /// Without it, Mooncake selects the available transport, including TCP.
    #[arg(long, value_delimiter = ',', value_parser = parse_nic_name, num_args = 1..)]
    pub nics: Option<Vec<String>>,

    /// etcd endpoints for distributed cache membership and immutable catalog placement.
    #[arg(long, value_delimiter = ',', requires_all = ["node_id", "catalog_nodes"])]
    pub etcd_endpoints: Vec<String>,

    /// Stable Manager node IDs that host catalog shards; must match across the cluster.
    #[arg(long, value_delimiter = ',', requires = "etcd_endpoints", value_parser = cluster::parse_label)]
    pub catalog_nodes: Vec<String>,

    /// Accounted catalog metadata bytes across all shards hosted by this Manager.
    #[arg(long, default_value = "256mb", value_parser = parse_memory_size)]
    pub catalog_budget: usize,

    /// Stable, unique identity of this Manager across process restarts.
    #[arg(long, requires = "etcd_endpoints", value_parser = cluster::parse_label)]
    pub node_id: Option<String>,

    /// Isolates member registrations and persistent node epochs in etcd.
    #[arg(long, default_value = "orbitkv", value_parser = cluster::parse_label)]
    pub cluster_name: String,

    /// Lease TTL; new remote operations stop after half the acknowledged TTL.
    #[arg(long, default_value_t = 30, value_parser = clap::value_parser!(i64).range(12..=3600))]
    pub membership_ttl_secs: i64,

    /// Retained residency journal bytes; overflow triggers an inventory snapshot.
    #[arg(long, default_value_t = orbitkv_core::DEFAULT_INVENTORY_JOURNAL_BYTES)]
    pub inventory_journal_bytes: usize,

    /// HLL sliding-window list for hit-rate estimation. Comma-separated humantime
    /// durations; each becomes a canonical `window` label in metrics (e.g. `15m,1h,1d`).
    /// Slot duration is derived as `clamp(window/24, 1min, 1h)`.
    #[arg(long, default_value = "15m,1h,1d", value_parser = parse_hll_windows_arg)]
    pub metric_hll_windows: String,

    /// HLL bucket index bits 4–18 (default: 16 → 65536 buckets, ~0.4% error)
    #[arg(long, default_value_t = 16, value_parser = parse_hll_bucket_bits)]
    pub metric_hll_bucket_bits: u8,

    /// Mark source transfers overdue after this many seconds; timeout never releases pins.
    #[arg(long, default_value_t = 120)]
    pub transfer_lock_timeout_secs: u64,

    /// Source transfer allocation budget, including overdue sessions. Defaults to half the pool.
    #[arg(long, value_parser = parse_memory_size)]
    pub transfer_budget: Option<usize>,

    /// iceoryx2 service name prefix for the inference control path.
    /// Each startup appends a unique incarnation, advertised through UDS.
    /// Defaults to a name derived from --addr.
    #[arg(long)]
    pub channel_service: Option<String>,

    /// Explicit Cache Manager session epoch for stale-client fencing. A random epoch
    /// is generated when omitted.
    #[arg(long)]
    pub channel_session_epoch: Option<u64>,

    /// Unix socket used to bootstrap inference clients and pass descriptor arena FDs.
    /// Defaults to /tmp/orbitkv-<addr-port>.sock.
    #[arg(long)]
    pub bootstrap_socket: Option<std::path::PathBuf>,

    /// Shared descriptor arena size for inference clients.
    #[arg(long, default_value = "8mb", value_parser = parse_memory_size)]
    pub descriptor_arena_size: usize,

    /// Per-client descriptor slot capacity.
    #[arg(long, default_value = "64kb", value_parser = parse_memory_size)]
    pub descriptor_slot_size: usize,
}

fn parse_hll_bucket_bits(s: &str) -> Result<u8, String> {
    use crate::metric::hll::{MAX_BUCKET_BITS, MIN_BUCKET_BITS};
    let v: u8 = s.parse().map_err(|e| format!("{e}"))?;
    if !(MIN_BUCKET_BITS..=MAX_BUCKET_BITS).contains(&v) {
        return Err(format!(
            "HLL bucket_bits must be in {MIN_BUCKET_BITS}..={MAX_BUCKET_BITS}, got {v}"
        ));
    }
    Ok(v)
}

fn parse_nic_name(s: &str) -> Result<String, String> {
    let name = s.trim();
    if name.is_empty() {
        return Err("--nics contains an empty NIC name".into());
    }
    Ok(name.to_string())
}

fn parse_hll_windows_arg(s: &str) -> Result<String, String> {
    parse_hll_windows(s)?;
    Ok(s.to_string())
}

/// Parse a comma-separated list of humantime windows (e.g. `15m,1h,1d`).
/// Each entry becomes `(label, duration)` where label is canonicalized from
/// the parsed duration.
fn parse_hll_windows(s: &str) -> Result<Vec<(String, Duration)>, String> {
    let mut out = Vec::new();
    let mut seen = std::collections::HashSet::new();
    for (idx, token) in s.split(',').map(str::trim).enumerate() {
        if token.is_empty() {
            return Err(format!(
                "--metric-hll-windows contains an empty window at position {}",
                idx + 1
            ));
        }
        let dur = parse_humantime(token)?;
        if dur < Duration::from_secs(60) {
            return Err(format!("HLL window {token} must be at least 1 minute"));
        }
        if !seen.insert(dur) {
            return Err(format!(
                "duplicate HLL window duration: {token} ({})",
                format_hll_window_label(dur)
            ));
        }
        out.push((format_hll_window_label(dur), dur));
    }
    if out.is_empty() {
        return Err("--metric-hll-windows must list at least one window".into());
    }
    Ok(out)
}

/// Minimal humantime parser: `<number><unit>` where unit ∈ {s, m, h, d}.
fn parse_humantime(s: &str) -> Result<Duration, String> {
    let (num_str, unit) = s.split_at(
        s.find(|c: char| !c.is_ascii_digit())
            .ok_or_else(|| format!("missing time unit in {s}"))?,
    );
    let n: u64 = num_str
        .parse()
        .map_err(|e| format!("invalid number in {s}: {e}"))?;
    let unit_secs = match unit {
        "s" => n,
        "m" => n
            .checked_mul(60)
            .ok_or_else(|| format!("duration overflows seconds in {s}"))?,
        "h" => n
            .checked_mul(3600)
            .ok_or_else(|| format!("duration overflows seconds in {s}"))?,
        "d" => n
            .checked_mul(86400)
            .ok_or_else(|| format!("duration overflows seconds in {s}"))?,
        _ => return Err(format!("unknown time unit {unit:?} in {s}; use s/m/h/d")),
    };
    Ok(Duration::from_secs(unit_secs))
}

fn format_hll_window_label(duration: Duration) -> String {
    let secs = duration.as_secs();
    if secs.is_multiple_of(86400) {
        format!("{}d", secs / 86400)
    } else if secs.is_multiple_of(3600) {
        format!("{}h", secs / 3600)
    } else if secs.is_multiple_of(60) {
        format!("{}m", secs / 60)
    } else {
        format!("{secs}s")
    }
}

fn parse_sample_rate(s: &str) -> Result<f64, String> {
    let v: f64 = s.parse().map_err(|e| format!("{e}"))?;
    if !(0.0..=1.0).contains(&v) {
        return Err(format!("sample rate must be between 0.0 and 1.0, got {v}"));
    }
    Ok(v)
}

fn format_py_err(err: PyErr) -> String {
    Python::attach(|py| err.value(py).to_string())
}

fn init_cuda_driver() -> Result<(), std::io::Error> {
    cuda_driver::init()
        .map_err(|err| std::io::Error::other(format!("failed to initialize CUDA driver: {err}")))
}

fn detect_cuda_devices() -> Result<Vec<i32>, std::io::Error> {
    Python::attach(|py| -> pyo3::PyResult<Vec<i32>> {
        let torch = py.import("torch")?;
        let cuda = torch.getattr("cuda")?;
        let device_count: i32 = cuda.call_method0("device_count")?.extract()?;

        // Probe each device ID from 0 to device_count-1 to see if it's available
        let mut available_devices = Vec::new();
        for device_id in 0..device_count {
            // Try to get device properties to verify it's accessible
            match cuda.call_method1("get_device_properties", (device_id,)) {
                Ok(_) => available_devices.push(device_id),
                Err(_) => continue, // Skip unavailable devices
            }
        }
        Ok(available_devices)
    })
    .map_err(|err| {
        std::io::Error::other(format!(
            "failed to detect CUDA devices: {}",
            format_py_err(err)
        ))
    })
}

fn init_python_cuda(device_ids: &[i32]) -> Result<(), std::io::Error> {
    if device_ids.is_empty() {
        return Err(std::io::Error::other("no CUDA devices to initialize"));
    }

    Python::attach(|py| -> pyo3::PyResult<()> {
        let torch = py.import("torch")?;
        let cuda = torch.getattr("cuda")?;
        cuda.call_method0("init")?;

        // Initialize CUDA context for each device by performing a real CUDA operation
        // PyTorch uses lazy initialization, so we need to actually allocate something
        // to force context creation on each device
        for &device_id in device_ids {
            let start = std::time::Instant::now();
            cuda.call_method1("set_device", (device_id,))?;

            // Allocate a small tensor to force CUDA context creation on this device
            // This ensures the CUDA driver creates a context for the device
            let device_str = format!("cuda:{}", device_id);
            let empty_args = (vec![1i64],);
            let kwargs = pyo3::types::PyDict::new(py);
            kwargs.set_item("device", device_str)?;
            let _ = torch.call_method("empty", empty_args, Some(&kwargs))?;

            // Synchronize to ensure context is fully initialized
            cuda.call_method0("synchronize")?;

            let elapsed = start.elapsed();
            log::info!(
                "Initialized CUDA context for device {} in {:.2}s",
                device_id,
                elapsed.as_secs_f64()
            );
        }

        // Set the first device as the default
        cuda.call_method1("set_device", (device_ids[0],))?;
        Ok(())
    })
    .map_err(|err| {
        std::io::Error::other(format!(
            "failed to initialize python/tensor CUDA runtime: {}",
            format_py_err(err)
        ))
    })
}

struct MetricsState {
    meter_provider: Option<SdkMeterProvider>,
    prometheus_registry: Option<Registry>,
}

fn init_metrics(
    prometheus_enabled: bool,
    otlp_endpoint: Option<String>,
    otlp_period_secs: u64,
) -> Result<MetricsState, Box<dyn Error>> {
    let otlp_endpoint = otlp_endpoint.filter(|s| !s.is_empty());

    // If neither Prometheus nor OTLP is enabled, return empty state
    if !prometheus_enabled && otlp_endpoint.is_none() {
        info!("Metrics disabled (no Prometheus addr or OTLP endpoint configured)");
        return Ok(MetricsState {
            meter_provider: None,
            prometheus_registry: None,
        });
    }

    let mut builder = SdkMeterProvider::builder();
    let mut prometheus_registry = None;

    // Add Prometheus exporter if enabled
    if prometheus_enabled {
        let registry = Registry::new();
        let exporter = opentelemetry_prometheus::exporter()
            .with_registry(registry.clone())
            .build()?;
        builder = builder.with_reader(exporter);
        prometheus_registry = Some(registry);
        info!("Prometheus metrics exporter enabled");
    }

    // Add OTLP exporter if endpoint is configured
    if let Some(endpoint) = otlp_endpoint {
        let exporter = opentelemetry_otlp::MetricExporter::builder()
            .with_tonic()
            .with_endpoint(endpoint)
            .build()?;

        let reader = opentelemetry_sdk::metrics::PeriodicReader::builder(exporter)
            .with_interval(Duration::from_secs(otlp_period_secs))
            .build();

        builder = builder.with_reader(reader);
        info!(
            "OTLP metrics exporter enabled (period={}s)",
            otlp_period_secs
        );
    }

    let meter_provider = builder.build();
    global::set_meter_provider(meter_provider.clone());

    Ok(MetricsState {
        meter_provider: Some(meter_provider),
        prometheus_registry,
    })
}

/// Main entry point for the Cache Manager.
pub fn run() -> Result<(), Box<dyn Error>> {
    let cli = Cli::parse();
    orbitkv_common::logging::init_stdout_colored(&cli.log_level);
    info!(
        "Starting orbitkv-cache-manager v{}",
        env!("CARGO_PKG_VERSION")
    );
    trace::init();
    orbitkv_core::set_trace_sample_rate(cli.trace_sample_rate);

    // Initialize CUDA in the main thread before starting Tokio runtime
    init_cuda_driver()?;
    check_cuda_version::preflight()?;

    // Determine which devices to initialize
    let devices = if cli.devices.is_empty() {
        // Auto-detect all available devices
        let detected = detect_cuda_devices()?;
        info!(
            "Auto-detected {} CUDA device(s): {:?}",
            detected.len(),
            detected
        );
        detected
    } else {
        info!("Using specified CUDA device(s): {:?}", cli.devices);
        cli.devices.clone()
    };

    if devices.is_empty() {
        return Err("No CUDA devices available".into());
    }

    init_python_cuda(&devices)?;
    info!(
        "CUDA runtime initialized for {} device(s): {:?}",
        devices.len(),
        devices
    );

    let registry = CudaTensorRegistry::new().map_err(|err| {
        let msg = format_py_err(err);
        std::io::Error::other(format!("failed to initialize torch CUDA context: {msg}"))
    })?;
    // Confine the registry to its own thread: GIL + CUDA work now happens off
    // the async runtime, so a wedged `empty_cache` can't starve tokio workers.
    let registry = RegistryHandle::spawn(registry);

    if let Some(hint_value_size) = cli.hint_value_size {
        if hint_value_size == 0 {
            return Err("--hint-value-size must be greater than zero when set".into());
        }
        info!("Value size hint set to {} bytes", hint_value_size);
    }

    info!(
        "Creating OrbitKVEngine with pinned memory pool: {:.2} GiB ({} bytes), hugepages={}",
        cli.pool_size as f64 / (1024.0 * 1024.0 * 1024.0),
        cli.pool_size,
        cli.use_hugepages
    );

    let ssd_cache_config = if cli.ssd_cache_path.is_empty() {
        None
    } else {
        info!(
            "SSD cache enabled: paths={}, capacity={:.2} GiB, shards={}, write_queue={}, prefetch_queue={}, write_inflight={}, prefetch_inflight={}",
            cli.ssd_cache_path.join(", "),
            cli.ssd_cache_capacity as f64 / (1024.0 * 1024.0 * 1024.0),
            cli.ssd_cache_shards,
            cli.ssd_write_queue_depth,
            cli.ssd_prefetch_queue_depth,
            cli.ssd_write_inflight,
            cli.ssd_prefetch_inflight,
        );
        Some(orbitkv_core::SsdCacheConfig {
            cache_paths: cli.ssd_cache_path.iter().map(|p| p.into()).collect(),
            capacity_bytes: cli.ssd_cache_capacity as u64,
            shards: cli.ssd_cache_shards,
            write_queue_depth: cli.ssd_write_queue_depth,
            prefetch_queue_depth: cli.ssd_prefetch_queue_depth,
            write_inflight: cli.ssd_write_inflight,
            prefetch_inflight: cli.ssd_prefetch_inflight,
        })
    };

    let peer_control_enabled = !cli.etcd_endpoints.is_empty();
    if cli.nics.as_ref().is_some_and(|nics| !nics.is_empty()) && !peer_control_enabled {
        log::warn!("--nics has no effect without distributed cache configuration");
    }
    let membership_view = if peer_control_enabled {
        if cli.addr.ip().is_unspecified() || cli.addr.port() == 0 {
            return Err("distributed --addr must be a concrete, routable peer endpoint".into());
        }
        if cli.catalog_budget
            < orbitkv_state::CATALOG_SHARDS * orbitkv_state::INVENTORY_BATCH_BYTES * 2
        {
            return Err(
                "--catalog-budget must allow two inventory batches per shard (16 MiB)".into(),
            );
        }
        Some(Arc::new(orbitkv_catalog::MembershipView::new(
            orbitkv_state::CacheOwner {
                endpoint: cli.addr.to_string(),
                incarnation: uuid::Uuid::new_v4(),
            },
            orbitkv_catalog::Placement::new(cli.catalog_nodes.clone())?,
        )))
    } else {
        None
    };
    let storage_config = orbitkv_core::StorageConfig {
        query_budget_bytes: cli.query_budget,
        query_instance_budget_bytes: cli.query_instance_budget,
        enable_lfu_admission: cli.enable_lfu_admission,
        hint_value_size_bytes: cli.hint_value_size,
        ssd_cache_config,
        mooncake_nic_names: cli.nics.clone().unwrap_or_default(),
        enable_numa_affinity: !cli.disable_numa_affinity,
        blockwise_alloc: cli.blockwise_alloc,
        transfer_lock_timeout: Duration::from_secs(cli.transfer_lock_timeout_secs),
        transfer_budget_bytes: cli.transfer_budget,
        membership: membership_view.clone(),
        inventory_journal_bytes: cli.inventory_journal_bytes,
        pool_shards: cli.pool_shards,
    };

    if cli.pool_shards > 1 {
        info!(
            "Pinned memory pool sharding enabled: {} shards",
            cli.pool_shards
        );
    }
    if cli.enable_lfu_admission {
        info!("TinyLFU cache admission enabled");
    }
    if cli.disable_numa_affinity {
        info!("NUMA-aware memory allocation disabled");
    }

    // Create Tokio runtime early - needed for OTLP metrics gRPC exporter
    let runtime = tokio::runtime::Builder::new_multi_thread()
        .enable_all()
        .build()?;

    // Initialize OTEL metrics BEFORE creating OrbitKVEngine, so that core metrics
    // (pool, cache, save/load) use the real meter provider instead of noop.
    let metrics_state = runtime.block_on(async {
        init_metrics(
            cli.enable_prometheus,
            cli.metrics_otel_endpoint.clone(),
            cli.metrics_period_secs,
        )
    })?;

    let hll_tracker = Arc::new(std::sync::Mutex::new(
        crate::metric::hll::MultiWindowHllTracker::new(
            parse_hll_windows(&cli.metric_hll_windows)
                .map_err(|err| format!("invalid --metric-hll-windows: {err}"))?,
            cli.metric_hll_bucket_bits,
        ),
    ));
    crate::metric::register_hll_gauges(&hll_tracker);

    let shutdown = Arc::new(Notify::new());
    let channel_config = {
        let service_name = cli
            .channel_service
            .clone()
            .unwrap_or_else(|| format!("orbitkv/channel/{}", cli.addr.port()));
        let session_epoch = cli
            .channel_session_epoch
            .unwrap_or_else(random_nonzero_session_epoch);
        if session_epoch == 0 {
            return Err("--channel-session-epoch must be non-zero".into());
        }
        let bootstrap_socket = cli.bootstrap_socket.clone().unwrap_or_else(|| {
            std::path::PathBuf::from(format!("/tmp/orbitkv-{}.sock", cli.addr.port()))
        });
        (
            service_name,
            session_epoch,
            bootstrap_socket,
            cli.descriptor_arena_size,
            cli.descriptor_slot_size,
        )
    };
    let runtime_handle = runtime.handle().clone();
    runtime.block_on(async move {
        let membership = match membership_view.clone() {
            Some(view) => Some(
                cluster::Membership::join(
                    &cli.etcd_endpoints,
                    &cli.cluster_name,
                    cli.node_id
                        .as_deref()
                        .ok_or("--node-id is required with etcd")?,
                    cli.membership_ttl_secs,
                    view,
                )
                .await?,
            ),
            None => None,
        };
        // Create OrbitKVEngine inside tokio runtime context (needed for SSD cache tokio::spawn)
        let engine = Arc::new(OrbitKVEngine::new_with_config(
            cli.pool_size,
            cli.use_hugepages,
            storage_config,
        )?);
        let lifecycle = cache::lifecycle::LifecycleService::new(Arc::clone(&engine), registry);
        let (service_name, session_epoch, bootstrap_socket, arena_size, slot_size) = channel_config;
        let mut channel_endpoint = endpoint::ProcessEndpoint::start(
            service_name,
            session_epoch,
            bootstrap_socket,
            arena_size,
            slot_size,
            Arc::clone(&engine),
            runtime_handle,
            Arc::clone(&hll_tracker),
            Arc::clone(&shutdown),
            lifecycle.clone(),
            cli.query_read_batch as u64,
            (cli.query_read_timeout_ms != 0).then(|| Duration::from_millis(cli.query_read_timeout_ms)),
            if cli.query_read_max_batches == 0 { usize::MAX } else { cli.query_read_max_batches },
        )?;

        // Spawn background GC task for stale inflight blocks and expired transfer locks
        {
            let engine = Arc::clone(&engine);
            let shutdown = Arc::clone(&shutdown);
            tokio::spawn(async move {
                const GC_INTERVAL: Duration = Duration::from_secs(60);
                const INFLIGHT_MAX_AGE: Duration = Duration::from_secs(300); // 5 min

                let mut interval = tokio::time::interval(GC_INTERVAL);
                interval.set_missed_tick_behavior(tokio::time::MissedTickBehavior::Skip);

                loop {
                    tokio::select! {
                        _ = interval.tick() => {
                            let cleaned = engine
                                .gc_stale_inflight(INFLIGHT_MAX_AGE)
                                .await;
                            if cleaned > 0 {
                                info!("Inflight GC: cleaned {} stale blocks", cleaned);
                            }

                            let expired_locks = engine.expire_transfer_locks();
                            if expired_locks > 0 {
                                warn!("Retaining source pins for {} overdue transfer sessions", expired_locks);
                            }
                        }
                        _ = shutdown.notified() => {
                            info!("Background GC task shutting down");
                            break;
                        }
                    }
                }
            });
            info!("Background GC task started (interval=60s, inflight_max_age=5m)");
        }

        // Start HTTP server for health check (always enabled)
        let http_server_handle = http_server::start_http_server_with_lifecycle(
            cli.http_addr,
            Arc::clone(&engine),
            lifecycle.clone(),
            cli.enable_prometheus,
            metrics_state.prometheus_registry.clone(),
            Arc::clone(&shutdown),
        )
        .await?;

        let mut terminate =
            tokio::signal::unix::signal(tokio::signal::unix::SignalKind::terminate())?;
        let shutdown_signal = {
            let notify = Arc::clone(&shutdown);
            async move {
                tokio::select! {
                    _ = tokio::signal::ctrl_c() => {
                        info!("Ctrl+C received, shutting down");
                    }
                    _ = terminate.recv() => {
                        info!("SIGTERM received, shutting down");
                    }
                    _ = notify.notified() => {
                        info!("Shutdown requested via control endpoint");
                    }
                }
                notify.notify_waiters();
            }
        };

        if let Some(view) = membership_view {
            let service = P2pTransferService::new(Arc::clone(&engine));
            info!("Cache Manager peer control listening on {}", cli.addr);

            const MAX_GRPC_MESSAGE_SIZE: usize = 64 * 1024 * 1024; // 64 MiB

            let assigned_shards = (0..orbitkv_state::CATALOG_SHARDS)
                .filter(|&shard| view.placement().host(shard) == cli.node_id.as_deref()).count();
            let stores = std::array::from_fn(|_| Arc::new(orbitkv_catalog::BlockHashStore::with_config(
                orbitkv_catalog::store::StoreConfig {
                    metadata_bytes: cli.catalog_budget / assigned_shards.max(1),
                    ..Default::default()
                }
            )));
            let _catalog_metrics = orbitkv_catalog::metric::register_store_gauges(&stores);
            let catalog = orbitkv_catalog::CatalogService::new(stores.clone(), view);
            // Derived directory evidence expires independently of payload lifetimes.
            let catalog_shutdown = shutdown.clone();
            tokio::spawn(async move {
                let mut interval = tokio::time::interval(Duration::from_secs(30));
                loop {
                    tokio::select! {
                        _ = catalog_shutdown.notified() => break,
                        _ = interval.tick() => {
                            let sweep = stores.clone();
                            let _ = tokio::task::spawn_blocking(move || {
                                for store in sweep { orbitkv_catalog::metric::record_sweep(store.sweep_expired()); }
                            }).await;
                        }
                    }
                }
            });
            let grpc_service = EngineServer::new(service)
                .max_decoding_message_size(MAX_GRPC_MESSAGE_SIZE)
                .max_encoding_message_size(MAX_GRPC_MESSAGE_SIZE);

            if let Err(err) = Server::builder()
                .http2_keepalive_interval(Some(GRPC_SERVER_HTTP2_KEEPALIVE_INTERVAL))
                .http2_keepalive_timeout(Some(GRPC_SERVER_HTTP2_KEEPALIVE_TIMEOUT))
                .concurrency_limit_per_connection(16)
                .add_service(grpc_service)
                .add_service(proto::engine::catalog_server::CatalogServer::new(catalog)
                    .max_decoding_message_size(4 * 1024 * 1024)
                    .max_encoding_message_size(4 * 1024 * 1024))
                .serve_with_shutdown(cli.addr, shutdown_signal)
                .await
            {
                error!("Server error: {err}");
                return Err(err.into());
            }
        } else {
            info!("Standalone Cache Manager ready; peer control is disabled");
            shutdown_signal.await;
        }

        info!("Cache Manager stopped");
        channel_endpoint.stop();

        // Stop HTTP server
        shutdown.notify_waiters();
        lifecycle.shutdown().await?;
        let _ = http_server_handle.await;

        // Catalogs authenticate owner cleanup against membership. Withdraw the
        // inventory while our registration is still valid, then revoke it.
        engine.shutdown_catalog_client().await;
        if let Some(membership) = membership {
            membership.shutdown().await;
        }

        // Flush metrics before exit
        if let Some(provider) = metrics_state.meter_provider
            && let Err(err) = provider.shutdown()
        {
            error!("Failed to shutdown metrics provider: {err}");
        }

        trace::flush();

        Ok(())
    })
}

fn random_nonzero_session_epoch() -> u64 {
    loop {
        let epoch = uuid::Uuid::new_v4().as_u128() as u64;
        if epoch != 0 {
            return epoch;
        }
    }
}

#[cfg(test)]
#[path = "../tests/unit/lib.rs"]
mod tests;
