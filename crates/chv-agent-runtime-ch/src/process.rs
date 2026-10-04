use async_trait::async_trait;
use chv_errors::ChvError;
use std::collections::HashMap;
use std::io::{Read as _, Seek, SeekFrom};
use std::os::fd::{AsRawFd, OwnedFd};
use std::os::unix::fs::OpenOptionsExt;
use std::path::Path;
use std::process::Stdio;
use std::sync::atomic::{AtomicBool, AtomicU64, Ordering};
use std::sync::Arc;
use tokio::io::{AsyncReadExt, AsyncSeekExt, AsyncWriteExt};
use tokio::process::Child;
use tracing::{debug, error, info, warn};

use crate::core_runtime::is_safe_resource_id;
use chv_hypervisor_api::resources::{
    rotate_console_log, vm_config_file, vm_console_log, vm_pid_file,
};

/// RAII guard that records VM lifecycle RED metrics when it drops.
///
/// - `chv_vm_ops_total{op, result}` counter — `result` is `"ok"` or `"err"`
/// - `chv_vm_op_duration_seconds{op}` histogram (recorded on BOTH paths so
///   dashboards can visualise error latency)
///
/// Mark `succeeded = true` only when the operation returns `Ok`. Any early
/// return via `?` will trigger Drop with the default `succeeded = false`.
struct VmOpGuard {
    op: &'static str,
    start: std::time::Instant,
    succeeded: bool,
}

impl VmOpGuard {
    fn new(op: &'static str) -> Self {
        Self {
            op,
            start: std::time::Instant::now(),
            succeeded: false,
        }
    }
}

impl Drop for VmOpGuard {
    fn drop(&mut self) {
        let label = if self.succeeded { "ok" } else { "err" };
        metrics::counter!(
            chv_observability::CHV_VM_OPS_TOTAL,
            "op" => self.op,
            "result" => label
        )
        .increment(1);
        metrics::histogram!(
            chv_observability::CHV_VM_OP_DURATION_SECONDS,
            "op" => self.op
        )
        .record(self.start.elapsed().as_secs_f64());
    }
}

use crate::adapter::{
    AddDiskParams, AddNetParams, CloudHypervisorAdapter, VmConfig, VmCounters, VmInfo,
};
use crate::ch_api::{parse_http_status, CloudHypervisorApiClient};

const CONSOLE_SCROLLBACK_BYTES: usize = 256 * 1024;
const CONSOLE_LOG_MAX_BYTES: u64 = 10 * 1024 * 1024;

struct AliveGuard(Arc<AtomicBool>);

impl Drop for AliveGuard {
    fn drop(&mut self) {
        self.0.store(false, Ordering::SeqCst);
    }
}

/// RAII guard closing the orphan window between spawning a CH child and
/// registering it in the vm process map. Several awaits separate those two
/// points; if an async cancellation (e.g. the core executor's bounded-drain
/// abort) drops the future in between, an *armed* guard SIGKILLs the child so
/// no unaccounted VMM survives. The guard is disarmed exactly when the child is
/// handed to the vm process map, which owns lifecycle from then on (stop/delete
/// call `start_kill` explicitly, and teardown deliberately leaves running VMs
/// untouched).
struct ChildGuard {
    child: Option<Child>,
    armed: bool,
}

impl ChildGuard {
    fn new(child: Child) -> Self {
        Self {
            child: Some(child),
            armed: true,
        }
    }

    /// Hand the child to its long-lived owner. From here an ordinary drop must
    /// NOT kill the VMM, so disarm before moving the child out of the guard.
    fn disarm(mut self) -> Child {
        debug_assert!(self.armed);
        self.armed = false;
        self.child.take().expect("child is present while armed")
    }
}

impl Drop for ChildGuard {
    fn drop(&mut self) {
        if self.armed {
            if let Some(mut child) = self.child.take() {
                let _ = child.start_kill();
            }
        }
    }
}

impl std::ops::Deref for ChildGuard {
    type Target = Child;
    fn deref(&self) -> &Child {
        self.child.as_ref().expect("child is present until disarm")
    }
}

impl std::ops::DerefMut for ChildGuard {
    fn deref_mut(&mut self) -> &mut Child {
        self.child.as_mut().expect("child is present until disarm")
    }
}

/// How the guest serial console is attached. Kept alongside the connected
/// fd so lifecycle paths can distinguish "reconnect to the listener" from
/// "re-dup the pty slave" when the console broadcaster needs reviving.
#[derive(Clone, Debug)]
enum SerialTransport {
    /// Unix-stream client of cloud-hypervisor's serial listener at this
    /// path. cloud-hypervisor keeps the listener for the VMM process
    /// lifetime, so a lost connection can be re-established by
    /// reconnecting (and the stored fd swapped for the live one).
    Socket(std::path::PathBuf),
    /// Pty slave allocated by cloud-hypervisor (explicit tuning). The
    /// kernel keeps the pty pair alive across guest reboots; consumers
    /// re-dup the stored slave fd.
    Pty,
}

/// The cloud-hypervisor process backing a tracked VM.
///
/// Normally the agent owns the process end-to-end (`Owned`). After an
/// agent restart, a still-running VMM is a re-parented orphan with no
/// `Child` handle: it is tracked by pid (`Adopted`) and every signal is
/// guarded by a `/proc/<pid>/cmdline` re-validation against the VM's
/// api-socket path so a recycled pid can never be killed by mistake.
/// A dead VMM is not an error state: cloud-hypervisor v43 exits with
/// the guest (the VMM control loop's Exit dispatch runs `vmm_shutdown`),
/// so a stopped VM's entry legitimately points at an exited process —
/// `start_vm` re-spawns it from the persisted creation payload. `Dead`
/// marks a re-derived entry whose VMM is provably gone and whose pid was
/// never known (no pidfile — e.g. a force-stop residual): there is
/// nothing to signal, wait for, or prove.
enum VmmChild {
    Owned(Child),
    Adopted(u32),
    Dead,
}

impl VmmChild {
    /// The VMM's pid when one is associated with this entry (`None` for
    /// `Dead`, and for an `Owned` child that has been reaped — tokio
    /// yields `None` after the wait completes). The boot watchdog uses
    /// this as a cheap identity check that its decision still refers to
    /// the same VMM generation (a re-spawn replaces the entry with a
    /// different pid).
    fn vmm_pid(&self) -> Option<u32> {
        match self {
            VmmChild::Owned(child) => child.id(),
            VmmChild::Adopted(pid) => Some(*pid),
            VmmChild::Dead => None,
        }
    }
}

/// Deterministic liveness for the re-spawn decision: `prove_exited`
/// distinguishes a proven-exited process from a proven-live one instead of
/// `has_exited`'s safe-but-lossy "errors mean gone" default — a re-spawn
/// may never run while any doubt remains that the old VMM is dead, or two
/// VMMs would own one VM (and one disk).
#[derive(Debug)]
enum Liveness {
    Alive,
    Exited,
    Unknown(String),
}

impl VmmChild {
    /// Best-effort SIGKILL. For an adopted pid this re-validates the
    /// process identity first and refuses to signal a mismatching (e.g.
    /// recycled) pid rather than risk killing an unrelated process. An
    /// `Owned` child is our own spawn — no identity doubt, `expected_exe`
    /// is unused for it. Returns whether a signal was issued: `false`
    /// means the kill was refused (an adopted pid whose identity cannot
    /// be proven — e.g. its executable was replaced on disk while the
    /// process ran) or there was nothing to signal (`Dead`). Callers
    /// that must not report success over a live process use this to
    /// fail loudly instead of assuming death.
    fn kill(&mut self, api_socket: &Path, expected_exe: Option<&std::ffi::OsStr>) -> bool {
        match self {
            VmmChild::Owned(child) => {
                let _ = child.start_kill();
                true
            }
            VmmChild::Adopted(pid) => {
                if !pid_is_cloud_hypervisor(*pid, api_socket, expected_exe) {
                    warn!(
                        pid = pid,
                        socket = %api_socket.display(),
                        "refusing to signal adopted pid: identity mismatch or process gone"
                    );
                    return false;
                }
                let _ = nix::sys::signal::kill(
                    nix::unistd::Pid::from_raw(*pid as i32),
                    nix::sys::signal::Signal::SIGKILL,
                );
                true
            }
            VmmChild::Dead => false,
        }
    }

    /// Waits for the process to be gone. `Owned` reaps the child; an
    /// adopted orphan is parented to init and reaped there, so this only
    /// polls `/proc` (bounded — a SIGKILLed VMM disappears promptly, and
    /// a hung wait must not pin the caller forever).
    async fn wait(&mut self) {
        match self {
            VmmChild::Owned(child) => {
                let _ = child.wait().await;
            }
            VmmChild::Adopted(pid) => {
                let deadline = std::time::Instant::now() + std::time::Duration::from_secs(5);
                while std::time::Instant::now() < deadline {
                    if !pid_exists(*pid) {
                        return;
                    }
                    tokio::time::sleep(std::time::Duration::from_millis(50)).await;
                }
            }
            VmmChild::Dead => {}
        }
    }

    /// Strict liveness for the re-spawn decision. Unlike a lossy
    /// "errors mean gone" default, probe errors surface as `Unknown`:
    /// `start_vm` refuses to re-spawn on `Unknown` rather than risk a
    /// second VMM on the same disk. An `Adopted` pid that is alive but no
    /// longer proves our identity (recycled) counts as exited — it is not
    /// ours to boot against, and re-spawn takes over the runtime dir.
    fn prove_exited(&mut self, api_socket: &Path) -> Liveness {
        match self {
            VmmChild::Owned(child) => match child.try_wait() {
                Ok(Some(_)) => Liveness::Exited,
                Ok(None) => Liveness::Alive,
                Err(e) => Liveness::Unknown(e.to_string()),
            },
            VmmChild::Adopted(pid) => {
                if !pid_exists(*pid) {
                    Liveness::Exited
                } else if pid_is_cloud_hypervisor(*pid, api_socket, None) {
                    Liveness::Alive
                } else {
                    Liveness::Exited
                }
            }
            VmmChild::Dead => Liveness::Exited,
        }
    }
}

/// Reads `/proc/<pid>/cmdline` (NUL-separated) as a space-joined string.
fn proc_cmdline(pid: u32) -> Option<String> {
    std::fs::read(format!("/proc/{pid}/cmdline"))
        .ok()
        .map(|raw| String::from_utf8_lossy(&raw).replace('\0', " "))
}

/// Whether `/proc/<pid>` shows a live process — liveness for adopted
/// orphans. A zombie or dead process has already exited; it only lingers
/// in /proc until its parent reaps it, so it counts as gone. Malformed
/// stat data also counts as gone (the safe default for lifecycle paths).
fn pid_exists(pid: u32) -> bool {
    let stat = match std::fs::read_to_string(format!("/proc/{pid}/stat")) {
        Ok(stat) => stat,
        Err(_) => return false,
    };
    // The state field follows the comm field in parentheses, and comm can
    // itself contain spaces and parentheses — parse after the LAST ')'.
    let Some((_, tail)) = stat.rsplit_once(')') else {
        return false;
    };
    match tail.split_whitespace().next() {
        Some(state) => state != "Z" && state != "X",
        None => false,
    }
}

/// Identity check for an adopted VMM pid: the process must exist, its
/// command line must reference both the api-socket flag and this VM's
/// socket path (unique per VM), and — when an expected executable name is
/// given — `/proc/<pid>/exe` must resolve to it. The exe cross-check
/// closes the argv-spoofing hole on the SIGKILL authorization path: a
/// crafted argv alone must never be enough to be signalled. Failure to
/// read either `/proc` file counts as unproven identity (false).
fn pid_is_cloud_hypervisor(
    pid: u32,
    api_socket: &Path,
    expected_exe: Option<&std::ffi::OsStr>,
) -> bool {
    let Some(cmdline) = proc_cmdline(pid) else {
        return false;
    };
    let socket_path = api_socket.to_string_lossy();
    if !(cmdline.contains("--api-socket") && cmdline.contains(socket_path.as_ref())) {
        return false;
    }
    if let Some(expected) = expected_exe {
        match std::fs::read_link(format!("/proc/{pid}/exe")) {
            Ok(exe) => {
                if exe.file_name() != Some(expected) {
                    return false;
                }
            }
            Err(_) => return false,
        }
    }
    true
}

/// Whether `/proc/<pid>/task/*/comm` still shows cloud-hypervisor's
/// serial-manager thread (`serial-manager`). A live Socket-transport VMM
/// always runs one — cloud-hypervisor spawns it with the VM and it never
/// exits while the VMM lives — so on a PROVEN-live VMM its absence is the
/// issue-#409 wedge signature: the thread dies silently when the
/// agent-side serial connection is reset with unread data in flight (an
/// agent SIGKILL during the guest's boot window), leaving the serial
/// listener bound but never accepted again while every guest UART write
/// fails EPIPE — the guest keeps "Running" in `vm.info` with a dead
/// console and a half-booted kernel.
///
/// - `Some(true)`: a thread named `serial-manager` was seen.
/// - `Some(false)`: the task list was read and every thread's `comm` was
///   read, with no such thread — a provable absence.
/// - `None`: absence could NOT be proven (unreadable `/proc` — e.g.
///   hidepid or a restricted container — or a task list that vanished
///   mid-scan). Callers must treat this as "act on nothing": a false
///   "dead" verdict would reboot a healthy VM, so only a provable
///   absence may trigger remediation.
fn vmm_serial_manager_thread_alive(pid: u32) -> Option<bool> {
    let tasks = std::fs::read_dir(format!("/proc/{pid}/task")).ok()?;
    let mut scanned_any = false;
    for entry in tasks.flatten() {
        match std::fs::read_to_string(entry.path().join("comm")) {
            Ok(comm) => {
                scanned_any = true;
                if comm.trim() == "serial-manager" {
                    return Some(true);
                }
            }
            // The thread exited between the readdir and the read; its
            // surviving siblings still classify the process.
            Err(e) if e.kind() == std::io::ErrorKind::NotFound => continue,
            Err(_) => return None,
        }
    }
    if scanned_any {
        Some(false)
    } else {
        // An empty task list means the process died between the caller's
        // liveness proof and this scan (or a zombie): absence of a
        // serial-manager thread proves nothing about a live VMM.
        None
    }
}

/// Outcome of a `/proc` scan for a live VMM owning an api socket.
enum UntrackedVmmScan {
    /// The scan completed: no live VMM owns the socket.
    None,
    /// The scan found a live owner (pid).
    Found(u32),
    /// The scan could not be completed — e.g. a `/proc` mount hidden by
    /// `hidepid` or a restricted container. Liveness is UNKNOWN and
    /// callers MUST fail closed: assuming "no VMM" here is exactly the
    /// stranded-guest (delete) or second-VMM-on-one-disk (start) hazard
    /// the scan exists to prevent.
    Unreadable(String),
}

/// Scans `/proc` for a live cloud-hypervisor process bound to exactly
/// this api-socket path (its cmdline carries `--api-socket <path>`).
/// Used where a runtime directory may be owned by a VMM this agent has
/// no map entry for — an agent crash in the create window before the
/// pidfile write, or adoption that was skipped or failed — so that
/// lifecycle paths can prove ownership instead of assuming "no entry
/// means no VMM".
///
/// Classification is deliberately LOOSE (cmdline only, no exe
/// cross-check): the decision this feeds — adopt vs. re-spawn, delete
/// vs. refuse — must never fork a second VMM onto a disk a live process
/// owns, whatever that process's executable is named. The exe-strict
/// check belongs only on the SIGKILL authorization path
/// (`VmmChild::kill`), mirroring how `VmmChild::Adopted`'s liveness
/// probe (`prove_exited`) is already loose while its kill is strict.
fn scan_live_vmm_on_socket(api_socket: &Path) -> UntrackedVmmScan {
    let entries = match std::fs::read_dir("/proc") {
        Ok(entries) => entries,
        Err(e) => return UntrackedVmmScan::Unreadable(format!("cannot read /proc: {e}")),
    };
    for entry in entries.flatten() {
        let Ok(pid) = entry.file_name().to_string_lossy().parse::<u32>() else {
            continue;
        };
        // Skip our own pid (its cmdline never matches, but the read is
        // wasted work).
        if pid == std::process::id() {
            continue;
        }
        // Fail closed the moment one process's cmdline is hidden from
        // us: under hidepid every pid would read as "not the VMM" and
        // the scan would falsely report None. Other read errors (the
        // process exited mid-scan) and empty cmdlines (kernel threads,
        // zombies) are normal skips.
        match std::fs::read(format!("/proc/{pid}/cmdline")) {
            Err(e) if e.kind() == std::io::ErrorKind::PermissionDenied => {
                return UntrackedVmmScan::Unreadable(format!(
                    "cannot read /proc/{pid}/cmdline: {e}"
                ));
            }
            Err(_) => continue,
            Ok(raw) if raw.is_empty() => continue,
            Ok(_) => {}
        }
        if pid_is_cloud_hypervisor(pid, api_socket, None) {
            return UntrackedVmmScan::Found(pid);
        }
    }
    UntrackedVmmScan::None
}

/// The retryable refusal a lifecycle op returns when the agent's
/// graceful shutdown is already in progress: the on-disk state is
/// untouched, and the operation is expected to be re-issued after the
/// supervisor restarts the agent.
fn shutting_down(vm_id: &str) -> ChvError {
    ChvError::Internal {
        reason: format!(
            "agent shutdown in progress; cannot start vm {vm_id} — retry after the agent has restarted"
        ),
    }
}

struct VmProcess {
    api_socket: std::path::PathBuf,
    child: VmmChild,
    /// Guest serial-console I/O fd — a unix-stream socket connected to
    /// cloud-hypervisor's serial listener (default Socket transport) or the
    /// pty slave under explicit Pty tuning. Guest output is read (via the
    /// broadcaster) and user keystrokes written through it.
    console_io: OwnedFd,
    /// Which transport `console_io` speaks; drives respawn semantics.
    serial_transport: SerialTransport,
    pty_tx: tokio::sync::broadcast::Sender<Vec<u8>>,
    pty_scrollback: Arc<std::sync::RwLock<Vec<u8>>>,
    broadcaster_alive: Arc<AtomicBool>,
    /// Console-capture byte offset at which the CURRENT VMM generation's
    /// boot begins. Bytes before it belong to earlier VMM generations
    /// (re-spawn appends to the same console.log) and must not lend
    /// boot-complete evidence to the current boot — the boot watchdog
    /// (see `boot_watchdog_tick`) only accepts a kernel banner at or
    /// after this offset. Set to the file size at re-spawn and at
    /// `reboot_vm` (a CH-level reboot starts a new boot); zero at
    /// create (fresh log), adoption and readopt (a live VMM's whole
    /// capture is its own history).
    boot_watermark: AtomicU64,
    last_cpu_seconds: f64,
    last_cpu_at: Option<std::time::Instant>,
}

pub struct ProcessCloudHypervisorAdapter {
    chv_binary: std::path::PathBuf,
    vms: Arc<tokio::sync::RwLock<HashMap<String, VmProcess>>>,
    /// Per-VM lifecycle serialization. Core-managed mode already
    /// single-flights operations per VM in the executor, but legacy-mode
    /// callers (gRPC handlers, the reconciler) do not, and even core mode
    /// must survive a rare liveness-probe error without forking a VM:
    /// two concurrent lifecycle ops on one VM (notably two `start`s over
    /// an exited VMM) must never both re-spawn a process for it. Entries
    /// are never removed — dropping a key while an operation still holds
    /// its mutex would let a fresh key bypass that holder's serialization.
    lifecycle_locks: std::sync::Mutex<HashMap<String, Arc<tokio::sync::Mutex<()>>>>,
    /// Remediation budget for the issue-#409 serial heal (see
    /// `heal_dead_serial_manager`): vm_id → pid of the adopted VMM whose
    /// provably-dead serial-manager thread a `start_vm` call already
    /// rebooted away. Bounds the remedy to ONE guest reboot per VMM
    /// generation per agent process: if the reboot fails to revive the
    /// console path (or the thread-name detection ever goes stale against
    /// a future cloud-hypervisor), the reconciler's repeated `start_vm`
    /// calls must not turn that into a reboot storm. Entries are never
    /// removed (the same discipline as `lifecycle_locks`); a re-spawned
    /// or re-adopted VM runs under a different pid and is budgeted
    /// afresh.
    serial_heal_reboots: std::sync::Mutex<HashMap<String, u32>>,
    /// One-way latch set by [`Self::drain_and_close_consoles`] during
    /// graceful agent shutdown. Console healing (the broadcaster's
    /// reconnect loop and `respawn_broadcaster_if_dead`) consults it and
    /// stands down: a connection minted during shutdown would be
    /// abortively closed by process exit — unread receive-queue data
    /// makes the kernel reset the connection, which kills cloud-
    /// hypervisor v43's serial-manager thread and can freeze the guest
    /// (see `drain_and_close_consoles` for the full defect chain). Never
    /// cleared: shutdown is one-way.
    console_draining: Arc<AtomicBool>,
    /// Root of this agent's runtime tree (`<runtime_dir>/vms` lives under
    /// it), recorded by `adopt_running_vms` at startup. Lets lifecycle
    /// paths re-derive a runtime entry from the shared on-disk layout
    /// (`<root>/vms/<vm_id>`) for a VM whose in-memory entry is gone —
    /// the force-stop residual — instead of failing with NotFound
    /// against a VM this node demonstrably runs (see
    /// `readopt_stopped_vm`). `None` until adoption has run (tests and
    /// any non-standard construction): those callers keep today's
    /// NotFound semantics.
    vms_root: std::sync::RwLock<Option<std::path::PathBuf>>,
    /// Guest-liveness (boot) watchdog runtime: `None` until
    /// [`Self::configure_boot_watchdog`] opts the node in (the feature
    /// is disabled by default — see `BootWatchdogConfig`). Holds the
    /// per-VM observation state; mutated only from
    /// [`Self::boot_watchdog_tick`], which the agent's main loop drives
    /// on a short interval. Sync lock discipline: never held across an
    /// await (the tick copies out / writes back records around its
    /// async work).
    boot_watchdog: std::sync::RwLock<Option<BootWatchdog>>,
}

/// Node configuration for the guest-liveness (boot) watchdog. Mirrors
/// the agent config's `[watchdog]` section (converted at wiring time);
/// constructed only when the feature is enabled — the `enabled` switch
/// itself lives in the agent config, not here.
#[derive(Debug, Clone)]
pub struct BootWatchdogConfig {
    /// The boot-complete marker: a boot is healthy when this string
    /// appears in the console capture after the most recent kernel
    /// banner (`Linux version …`). Default `systemd-logind`.
    pub boot_marker: String,
    /// Seconds without new console bytes (marker absent, VMM alive)
    /// before the watchdog fires `vm.reboot`.
    pub stall_secs: u64,
    /// Watchdog reboots allowed per unhealthy episode before standing
    /// down.
    pub max_reboots: u32,
    /// Seconds of continuous marker-healthy state after which the
    /// reboot budget resets.
    pub healthy_reset_secs: u64,
}

/// The watchdog's per-VM observation record.
///
/// Evidence model (incremental): the watchdog consumes the console
/// capture in deltas, keeping only a scan offset and an overlap tail,
/// and maintains one bit of evidence — `boot_complete`, "the current
/// boot's completion marker was seen after its kernel banner". The bit
/// flips to `false` only on positive evidence of a NEW boot (a kernel
/// banner in a delta, or a fresh state whose watermark says the current
/// VMM generation has not printed one yet); it flips to `true` when the
/// marker follows the last banner in a delta. A console that shrinks
/// (the writer's 10 MiB wraparound, the graceful stop's in-place
/// truncate, a rotation) is NOT a new boot: the evidence is preserved
/// and the scan restarts from zero — a wrapped, healthy, quiet VM must
/// never look frozen.
#[derive(Debug, Clone)]
struct VmWatchState {
    /// Generation anchor: the VMM pid this state was derived against.
    /// A re-spawn replaces the map entry with a new pid; the state must
    /// not survive it with stale evidence.
    vmm_pid: Option<u32>,
    /// Generation anchor: the entry's boot watermark this state was
    /// derived against. `reboot_vm` bumps the watermark (a CH-level
    /// reboot starts a new boot in the same VMM); the state must be
    /// re-derived when that happens. See `VmProcess::boot_watermark`.
    watermark: u64,
    /// Console bytes consumed by the watchdog so far (scan position).
    scan_offset: u64,
    /// The trailing bytes of the consumed region (at most
    /// `max(banner_len, marker_len) - 1` bytes), kept so a marker or
    /// banner split across scan boundaries is still found. Cleared on
    /// wrap/truncate.
    prev_tail: Vec<u8>,
    /// Evidence: the current boot's completion marker has been seen
    /// after its kernel banner.
    boot_complete: bool,
    /// When the console last grew (or when tracking started): the
    /// stall clock. `now - last_change >= stall_secs` with
    /// `boot_complete == false` is the frozen-guest signature.
    last_change: std::time::Instant,
    /// Watchdog reboots fired in the current unhealthy episode.
    reboots_fired: u32,
    /// When the current stretch of `boot_complete` evidence began;
    /// `None` while a boot is incomplete. Sustained health past
    /// `healthy_reset_secs` resets `reboots_fired`.
    healthy_since: Option<std::time::Instant>,
    /// Set once the episode budget is exhausted (log-once semantics).
    stood_down: bool,
}

impl VmWatchState {
    fn fresh(
        capture: &[u8],
        vmm_pid: Option<u32>,
        watermark: u64,
        config: &BootWatchdogConfig,
    ) -> Self {
        let boot_complete = Self::boot_complete_at_init(capture, watermark, &config.boot_marker);
        let tail_len = Self::scan_overlap(&config.boot_marker);
        let prev_tail = if capture.len() > tail_len {
            capture[capture.len() - tail_len..].to_vec()
        } else {
            capture.to_vec()
        };
        Self {
            vmm_pid,
            watermark,
            scan_offset: capture.len() as u64,
            prev_tail,
            boot_complete,
            last_change: std::time::Instant::now(),
            reboots_fired: 0,
            healthy_since: if boot_complete {
                Some(std::time::Instant::now())
            } else {
                None
            },
            stood_down: false,
        }
    }

    /// How many trailing bytes a scan must overlap with the previous
    /// scan so a banner or marker split across the boundary is found.
    fn scan_overlap(marker: &str) -> usize {
        b"Linux version".len().max(marker.len()).saturating_sub(1)
    }

    /// Initial evidence derivation over the whole capture. The last
    /// kernel banner at or after `watermark` is the current boot's; the
    /// boot is complete when the marker follows it. A banner before the
    /// watermark belongs to an earlier VMM generation (a re-spawn
    /// appends to the same console.log) and must not lend its marker to
    /// the current boot. No banner at or after the watermark means the
    /// current boot has not reached its kernel yet — incomplete (the
    /// frozen-at-firmware signature).
    ///
    /// Honest caveat: for an adopted VM (watermark 0) whose console has
    /// wrapped past its banner, "no banner anywhere" is ambiguous
    /// between "froze before its kernel" and "booted long ago, evidence
    /// wrapped away". This errs toward incomplete (the condition the
    /// watchdog exists to catch) at the cost of a possible single
    /// reboot for such a VM — bounded by the episode budget.
    fn boot_complete_at_init(capture: &[u8], watermark: u64, marker: &str) -> bool {
        let marker_bytes = marker.as_bytes();
        if marker_bytes.is_empty() {
            // Degenerate configuration: never treat a boot as frozen on
            // an unsatisfiable marker.
            return true;
        }
        let banner = b"Linux version";
        let last_banner = capture
            .windows(banner.len())
            .enumerate()
            .filter(|(i, _)| (*i as u64) >= watermark)
            .filter_map(|(i, w)| (w == banner).then_some(i))
            .next_back();
        match last_banner {
            None => false,
            Some(b) => capture[b + banner.len()..]
                .windows(marker_bytes.len())
                .any(|w| w == marker_bytes),
        }
    }

    /// What a scan delta says about the boot. `prev_tail` ++ `delta`
    /// forms the scanned region (the overlap makes split markers
    /// findable); positions are region-relative.
    fn scan_delta_evidence(prev_tail: &[u8], delta: &[u8], marker: &str) -> ConsoleDeltaEvidence {
        let marker_bytes = marker.as_bytes();
        let banner = b"Linux version";
        if marker_bytes.is_empty() || delta.is_empty() {
            return ConsoleDeltaEvidence::NoEvent;
        }
        let mut region = Vec::with_capacity(prev_tail.len() + delta.len());
        region.extend_from_slice(prev_tail);
        region.extend_from_slice(delta);
        let last_banner = region.windows(banner.len()).rposition(|w| w == banner);
        match last_banner {
            // A banner in this region: the boot that banner started is
            // complete only if the marker follows it.
            Some(b) => {
                if region[b + banner.len()..]
                    .windows(marker_bytes.len())
                    .any(|w| w == marker_bytes)
                {
                    ConsoleDeltaEvidence::BootComplete
                } else {
                    ConsoleDeltaEvidence::NewBoot
                }
            }
            // No banner here: a marker completes the boot whose banner
            // preceded this region (a mid-boot continuation).
            None => {
                if region
                    .windows(marker_bytes.len())
                    .any(|w| w == marker_bytes)
                {
                    ConsoleDeltaEvidence::BootComplete
                } else {
                    ConsoleDeltaEvidence::NoEvent
                }
            }
        }
    }
}

/// What one console scan delta reports about the current boot.
enum ConsoleDeltaEvidence {
    /// Nothing conclusive in this delta; the evidence stands.
    NoEvent,
    /// The boot's completion marker followed the last banner (or the
    /// delta has no banner and the marker completes a pending boot).
    BootComplete,
    /// A kernel banner appeared whose completion marker has not
    /// followed: a new boot is under way.
    NewBoot,
}

/// The configured watchdog: its settings plus the per-VM state map.
struct BootWatchdog {
    config: BootWatchdogConfig,
    vms: HashMap<String, VmWatchState>,
}

impl BootWatchdog {
    fn new(config: BootWatchdogConfig) -> Self {
        Self {
            config,
            vms: HashMap::new(),
        }
    }
}

/// What one observation of a VM asks the tick to do. Computed under the
/// state lock; the reboot decision is committed by the executor after
/// the pre-fire re-checks (vm.info state, target identity, drain
/// latch) pass — a declined candidate consumes no episode budget.
enum BootWatchdogAction {
    Noop,
    /// The frozen-guest signature is met; candidate for a recovery
    /// reboot, pending the executor's pre-fire checks.
    Candidate {
        /// How long the console had been stalled when the condition was
        /// met (for the log).
        stalled_secs: u64,
    },
    /// The episode budget is exhausted; log once and stand down.
    StandDown,
}

/// Console.log write mode. `Fresh` (create) truncates — a new VM
/// instance starts a clean log. `Append` (VMM re-spawn, adoption)
/// preserves prior history: the stop path already truncates by design,
/// so appending after a stop starts clean, while a crash leaves boot
/// history worth keeping.
#[derive(Clone, Copy, PartialEq, Eq)]
enum ConsoleLogMode {
    Fresh,
    Append,
}

impl ProcessCloudHypervisorAdapter {
    pub fn new(chv_binary: impl Into<std::path::PathBuf>) -> Self {
        Self {
            chv_binary: chv_binary.into(),
            vms: Arc::new(tokio::sync::RwLock::new(HashMap::new())),
            lifecycle_locks: std::sync::Mutex::new(HashMap::new()),
            serial_heal_reboots: std::sync::Mutex::new(HashMap::new()),
            console_draining: Arc::new(AtomicBool::new(false)),
            vms_root: std::sync::RwLock::new(None),
            boot_watchdog: std::sync::RwLock::new(None),
        }
    }

    /// Opt the node into the guest-liveness (boot) watchdog. Call once,
    /// after `adopt_running_vms` (adoption populates the map the tick
    /// observes). Re-configuring resets the observation state. The
    /// feature is disabled until this is called — the `enabled` switch
    /// lives in the agent config (`[watchdog]`), which gates the wiring.
    pub fn configure_boot_watchdog(&self, config: BootWatchdogConfig) {
        let mut guard = self
            .boot_watchdog
            .write()
            .expect("boot watchdog lock poisoned");
        *guard = Some(BootWatchdog::new(config));
    }

    /// Pre-fire gate: does the map entry still refer to the VMM
    /// generation the decision was made against? A re-spawn replaces
    /// the entry with a new pid; rebooting a decision made about a dead
    /// generation into a fresh healthy boot is exactly the
    /// accidental-reboot class this feature must not have. There
    /// remains a sub-millisecond window between this check and
    /// `reboot_vm` taking the lifecycle op lock — a lifecycle op cannot
    /// interleave there without holding that same lock, so the worst
    /// case is bounded by the episode budget.
    async fn boot_watchdog_target_valid(&self, vm_id: &str, observed_pid: Option<u32>) -> bool {
        let vms = self.vms.read().await;
        match vms.get(vm_id) {
            Some(proc) => proc.child.vmm_pid() == observed_pid,
            None => false,
        }
    }

    /// Pre-fire gate: the CH-reported VM state must be Running. The
    /// frozen guest reports Running (the qualification evidence); a VM
    /// in any other state (Created — stopped before its first boot,
    /// Shutdown, paused) is not mid-boot and is the lifecycle
    /// machinery's territory, not the watchdog's.
    async fn boot_watchdog_vm_running(&self, api_socket: &std::path::Path) -> bool {
        match Self::ch_api_request_with_body(api_socket, "GET", "/api/v1/vm.info", None).await {
            Ok((200, body)) => {
                let state = serde_json::from_str::<serde_json::Value>(&body)
                    .ok()
                    .and_then(|v| v.get("state").and_then(|s| s.as_str()).map(str::to_string));
                state.as_deref() == Some("Running")
            }
            _ => false,
        }
    }

    /// Decline a candidate: reset its stall clock WITHOUT consuming the
    /// episode budget, so the next evaluation comes after a full stall
    /// window rather than on the next pass.
    fn boot_watchdog_decline(&self, vm_id: &str) {
        let mut guard = self
            .boot_watchdog
            .write()
            .expect("boot watchdog lock poisoned");
        if let Some(wd) = guard.as_mut() {
            if let Some(state) = wd.vms.get_mut(vm_id) {
                state.last_change = std::time::Instant::now();
            }
        }
    }

    /// Commit a candidate as a fired reboot: consumes one unit of the
    /// episode budget and starts the post-fire cooldown (a full stall
    /// window for the new boot to show output). Returns the 1-based
    /// attempt number, or `None` when the episode is already exhausted.
    fn boot_watchdog_commit_fire(&self, vm_id: &str) -> Option<u32> {
        let mut guard = self
            .boot_watchdog
            .write()
            .expect("boot watchdog lock poisoned");
        let wd = guard.as_mut()?;
        let state = wd.vms.get_mut(vm_id)?;
        if state.stood_down || state.reboots_fired >= wd.config.max_reboots {
            state.stood_down = true;
            return None;
        }
        state.reboots_fired += 1;
        state.last_change = std::time::Instant::now();
        Some(state.reboots_fired)
    }

    /// Read a byte range from a file (`end` exclusive). A file that
    /// shrank or ended mid-range yields a short read; the caller's scan
    /// offset follows what was actually read.
    async fn read_file_range(
        path: &std::path::Path,
        start: u64,
        end: u64,
    ) -> std::io::Result<Vec<u8>> {
        use tokio::io::{AsyncReadExt, AsyncSeekExt};
        let mut file = tokio::fs::File::open(path).await?;
        if start > 0 {
            file.seek(std::io::SeekFrom::Start(start)).await?;
        }
        let mut buf = vec![0u8; (end - start) as usize];
        let mut read = 0;
        while read < buf.len() {
            let n = file.read(&mut buf[read..]).await?;
            if n == 0 {
                break;
            }
            read += n;
        }
        buf.truncate(read);
        Ok(buf)
    }

    /// One guest-liveness (boot) watchdog pass. The agent's main loop
    /// drives this on a short interval (5 s is the design point).
    ///
    /// What it detects: the frozen-guest condition CH v43's
    /// serial-manager defect produces — a mid-burst serial-client death
    /// (typically the agent's own SIGKILL) silently kills the manager,
    /// the guest freezes mid-boot, and `vm.info` keeps reporting
    /// Running. The working discriminator (the qualification harness's
    /// logind gate, generalized): the boot-complete marker must appear
    /// in the persisted console capture after the current boot's kernel
    /// banner. A console that has stalled — no new bytes for
    /// `stall_secs` — with the marker absent, a live VMM, a live
    /// broadcaster and a Running vm.info is the frozen signature.
    ///
    /// What it does: `vm.reboot`, which is a CH-level guest reset that
    /// needs no cooperating guest, re-creates the serial manager (the
    /// silently-dead component) and — through `reboot_vm`'s connection
    /// rotation — restores console capture of the new boot.
    ///
    /// Safety rails: stands down while `console_draining` is latched
    /// (graceful agent shutdown — re-checked immediately before firing,
    /// not just at pass entry), considers Socket-transport consoles
    /// only (`reboot_vm`'s rotation is Socket-only; Pty is a recorded
    /// follow-up), never fires on a dead broadcaster (a capture gap is
    /// the heal path's territory, and a broadcaster-dead VM's tracking
    /// state survives heal cycles so the episode budget cannot be reset
    /// by flapping), skips non-alive VMMs, bounds reboots per unhealthy
    /// episode, counts FAILED reboot attempts toward the budget so a
    /// wedged API socket cannot loop forever, and re-verifies the
    /// target (same VMM generation) and the Running state immediately
    /// before firing. A declined candidate consumes no budget.
    pub async fn boot_watchdog_tick(&self) {
        if self.console_draining.load(Ordering::SeqCst) {
            return;
        }
        let Some(config) = self
            .boot_watchdog
            .read()
            .expect("boot watchdog lock poisoned")
            .as_ref()
            .map(|wd| wd.config.clone())
        else {
            // Not configured: the feature is opt-in.
            return;
        };
        // Observe every tracked VM: clone the bits the pass needs
        // without holding the map lock across file IO or the reboot.
        // vm_dir derives from the entry's api_socket parent (the same
        // derivation the stop paths use), so no vms_root dependency.
        struct Observation {
            vm_id: String,
            vm_dir: std::path::PathBuf,
            api_socket: std::path::PathBuf,
            watermark: u64,
            vmm_pid: Option<u32>,
            alive: bool,
            broadcaster_alive: bool,
        }
        let observations: Vec<Observation> = {
            let vms = self.vms.read().await;
            vms.iter()
                .filter_map(|(vm_id, proc)| {
                    // Socket transport only: `reboot_vm`'s connection
                    // rotation (which restores capture) is Socket-only;
                    // Pty is a recorded follow-up.
                    if !matches!(proc.serial_transport, SerialTransport::Socket(_)) {
                        return None;
                    }
                    // Loose liveness (mirrors the readopt classification
                    // discipline — cmdline-strict identity is reserved
                    // for kill authorization): a recycled adopted pid
                    // reads as alive, bounded by the episode budget and
                    // caught by the pre-fire vm.info check.
                    let alive = match &proc.child {
                        VmmChild::Dead => false,
                        VmmChild::Owned(child) => child.id().is_some_and(pid_exists),
                        VmmChild::Adopted(pid) => pid_exists(*pid),
                    };
                    let vm_dir = proc.api_socket.parent()?.to_path_buf();
                    Some(Observation {
                        vm_id: vm_id.clone(),
                        vm_dir,
                        api_socket: proc.api_socket.clone(),
                        watermark: proc.boot_watermark.load(Ordering::SeqCst),
                        vmm_pid: proc.child.vmm_pid(),
                        alive,
                        broadcaster_alive: proc.broadcaster_alive.load(Ordering::SeqCst),
                    })
                })
                .collect()
        };
        let mut actions: Vec<(String, std::path::PathBuf, Option<u32>, BootWatchdogAction)> =
            Vec::new();
        for obs in &observations {
            if !obs.alive {
                // A stopped/crashed VMM is the lifecycle machinery's
                // territory, not the watchdog's. Drop the tracking so a
                // later boot of the same id starts a fresh episode.
                let mut guard = self
                    .boot_watchdog
                    .write()
                    .expect("boot watchdog lock poisoned");
                if let Some(wd) = guard.as_mut() {
                    wd.vms.remove(&obs.vm_id);
                }
                continue;
            }
            let log_path = vm_console_log(&obs.vm_dir);
            let size = match tokio::fs::metadata(&log_path).await {
                Ok(m) => m.len(),
                Err(e) if e.kind() == std::io::ErrorKind::NotFound => 0,
                Err(e) => {
                    warn!(
                        vm_id = %obs.vm_id,
                        error = %e,
                        "boot watchdog: console capture unreadable; skipping this pass"
                    );
                    continue;
                }
            };
            // Phase 1 (state lock, no awaits): decide what to read.
            enum Read {
                None,
                Range {
                    start: u64,
                    end: u64,
                },
                /// Read the whole capture. `rederive` is set when a state
                /// exists but is anchored to an older generation: its
                /// evidence must be re-derived, its episode counters
                /// preserved.
                Init {
                    rederive: bool,
                },
            }
            let read = {
                let mut guard = self
                    .boot_watchdog
                    .write()
                    .expect("boot watchdog lock poisoned");
                let Some(wd) = guard.as_mut() else {
                    return;
                };
                // Generation anchor: a state derived against a different
                // VMM pid (a re-spawn replaced the entry — possibly with
                // watermark 0, when the re-spawn appended to a truncated
                // log) or a different boot watermark (`reboot_vm` bumped
                // it: a CH-level reboot starts a new boot in the same
                // VMM) is stale. Its `boot_complete` evidence belongs to
                // a dead generation and must not satisfy the current
                // boot — without this, a re-spawned or rebooted boot
                // frozen BEFORE its kernel banner (the exact signature
                // this watchdog exists for) is masked forever by the
                // previous boot's completed evidence. The episode
                // counters' fate is decided in phase 3 by WHICH anchor
                // moved: a same-VMM reboot (the watchdog's own) preserves
                // them, a new VM life (pid change) starts a fresh
                // episode.
                // (Accepted residual: an Adopted entry whose pid the OS
                // recycles to a new VMM defeats the pid anchor — a
                // stood-down state could survive into the new life.
                // Requires a pid collision on the same vm id with a
                // prior stand-down; recorded in the M2.5 evidence
                // register's watchdog limits.)
                let stale = match wd.vms.get(&obs.vm_id) {
                    Some(state) => state.vmm_pid != obs.vmm_pid || state.watermark != obs.watermark,
                    None => false,
                };
                if stale {
                    Read::Init { rederive: true }
                } else if let Some(state) = wd.vms.get_mut(&obs.vm_id) {
                    if size < state.scan_offset {
                        // Shrink = the writer's 10 MiB wraparound, the
                        // graceful stop's in-place truncate, or a
                        // rotation — none of them is a new boot. Preserve
                        // the evidence and rescan from zero: a new boot
                        // after the wrap still announces itself with a
                        // fresh banner, and a wrapped healthy VM never
                        // looks frozen.
                        state.scan_offset = 0;
                        state.prev_tail.clear();
                        state.last_change = std::time::Instant::now(); // a write happened
                        Read::Range {
                            start: 0,
                            end: size,
                        }
                    } else if size > state.scan_offset {
                        Read::Range {
                            start: state.scan_offset,
                            end: size,
                        }
                    } else {
                        Read::None
                    }
                } else {
                    Read::Init { rederive: false }
                }
            };
            // Phase 2 (async IO): read only what the state asked for —
            // an idle console costs one metadata() call per pass.
            let (is_init, rederive, read_start, bytes) = match read {
                Read::None => (false, false, 0, Vec::new()),
                Read::Range { start, end } => {
                    if start >= end {
                        (false, false, start, Vec::new())
                    } else {
                        match Self::read_file_range(&log_path, start, end).await {
                            Ok(bytes) => (false, false, start, bytes),
                            Err(e) if e.kind() == std::io::ErrorKind::NotFound => {
                                (false, false, start, Vec::new())
                            }
                            Err(e) => {
                                warn!(
                                    vm_id = %obs.vm_id,
                                    error = %e,
                                    "boot watchdog: console capture unreadable; skipping this pass"
                                );
                                continue;
                            }
                        }
                    }
                }
                Read::Init { rederive } => match tokio::fs::read(&log_path).await {
                    Ok(bytes) => (true, rederive, 0, bytes),
                    Err(e) if e.kind() == std::io::ErrorKind::NotFound => {
                        (true, rederive, 0, Vec::new())
                    }
                    Err(e) => {
                        warn!(
                            vm_id = %obs.vm_id,
                            error = %e,
                            "boot watchdog: console capture unreadable; skipping this pass"
                        );
                        continue;
                    }
                },
            };
            // Phase 3 (state lock, no awaits): apply the evidence and
            // decide.
            let action = {
                let mut guard = self
                    .boot_watchdog
                    .write()
                    .expect("boot watchdog lock poisoned");
                let Some(wd) = guard.as_mut() else {
                    return;
                };
                let now = std::time::Instant::now();
                let state = wd.vms.entry(obs.vm_id.clone()).or_insert_with(|| {
                    VmWatchState::fresh(&bytes, obs.vmm_pid, obs.watermark, &wd.config)
                });
                if rederive {
                    // The generation changed under this state. Re-derive
                    // the EVIDENCE from the capture; the episode counters
                    // depend on WHICH change happened:
                    // - a pid change is a NEW VM LIFE (a re-spawn replaced
                    //   the entry): fresh episode, fresh budget — matching
                    //   the documented semantics of the !alive state drop
                    //   ("a later boot of the same id starts a fresh
                    //   episode"), which a fast stop→start that never
                    //   shows a dead window would otherwise miss;
                    // - a watermark-only change is the SAME VMM mid-episode
                    //   (the watchdog's own `reboot_vm` bumped it): the
                    //   counters must survive, or the episode budget —
                    //   the feature's core safety bound — would reset on
                    //   every watchdog reboot.
                    let pid_changed = state.vmm_pid != obs.vmm_pid;
                    let (reboots_fired, stood_down) = if pid_changed {
                        (0, false)
                    } else {
                        (state.reboots_fired, state.stood_down)
                    };
                    *state = VmWatchState::fresh(&bytes, obs.vmm_pid, obs.watermark, &wd.config);
                    state.reboots_fired = reboots_fired;
                    state.stood_down = stood_down;
                }
                if is_init {
                    // `fresh` already consumed these bytes.
                } else if !bytes.is_empty() {
                    // Growth: the console is alive (progress). Apply the
                    // delta evidence; `read_start` may be 0 after a wrap
                    // reset.
                    state.last_change = now;
                    match VmWatchState::scan_delta_evidence(
                        &state.prev_tail,
                        &bytes,
                        &wd.config.boot_marker,
                    ) {
                        ConsoleDeltaEvidence::BootComplete => {
                            if !state.boot_complete {
                                state.healthy_since = Some(now);
                            }
                            state.boot_complete = true;
                        }
                        ConsoleDeltaEvidence::NewBoot => {
                            state.boot_complete = false;
                            state.healthy_since = None;
                        }
                        ConsoleDeltaEvidence::NoEvent => {}
                    }
                    state.scan_offset = read_start + bytes.len() as u64;
                    let mut region = Vec::with_capacity(state.prev_tail.len() + bytes.len());
                    region.extend_from_slice(&state.prev_tail);
                    region.extend_from_slice(&bytes);
                    let tail_len = VmWatchState::scan_overlap(&wd.config.boot_marker);
                    state.prev_tail = if region.len() > tail_len {
                        region[region.len() - tail_len..].to_vec()
                    } else {
                        region
                    };
                }
                if state.boot_complete {
                    // Boot complete — healthy, however quiet the console
                    // is. Sustained health resets the episode's budget.
                    if let Some(healthy_since) = state.healthy_since {
                        if now.duration_since(healthy_since).as_secs()
                            >= wd.config.healthy_reset_secs
                        {
                            state.reboots_fired = 0;
                            state.stood_down = false;
                        }
                    }
                    BootWatchdogAction::Noop
                } else if !obs.broadcaster_alive {
                    // A dead broadcaster is a capture gap, not guest
                    // evidence: never fire on missing evidence (the heal
                    // path owns capture recovery). Tracking continues so
                    // the episode budget survives heal cycles.
                    BootWatchdogAction::Noop
                } else {
                    let stalled_secs = now.duration_since(state.last_change).as_secs();
                    if stalled_secs < wd.config.stall_secs {
                        // Within the stall window — the boot may just be
                        // slow.
                        BootWatchdogAction::Noop
                    } else if state.stood_down {
                        BootWatchdogAction::Noop
                    } else if state.reboots_fired >= wd.config.max_reboots {
                        state.stood_down = true;
                        BootWatchdogAction::StandDown
                    } else {
                        BootWatchdogAction::Candidate { stalled_secs }
                    }
                }
            };
            actions.push((
                obs.vm_id.clone(),
                obs.api_socket.clone(),
                obs.vmm_pid,
                action,
            ));
        }
        // Drop tracking for VMs that left the map this pass (stop,
        // delete, respawn gap) so their next boot starts a fresh
        // episode. Broadcaster-dead VMs were still observed — their
        // state survives heal cycles by design.
        {
            let mut guard = self
                .boot_watchdog
                .write()
                .expect("boot watchdog lock poisoned");
            if let Some(wd) = guard.as_mut() {
                wd.vms
                    .retain(|id, _| observations.iter().any(|obs| &obs.vm_id == id));
            }
        }
        // Execute: the pre-fire re-checks, then the reboot. A declined
        // candidate consumes no episode budget. The vm.info gate runs
        // first: it is the pass's only await on the outside world, so
        // the cheap identity and drain re-checks that FOLLOW it are the
        // last things evaluated before the fire — the windows a
        // concurrent re-spawn or shutdown can still slip into are
        // bounded by the episode budget and the lifecycle op lock.
        for (vm_id, api_socket, vmm_pid, action) in actions {
            match action {
                BootWatchdogAction::Noop => {}
                BootWatchdogAction::Candidate { stalled_secs } => {
                    if !self.boot_watchdog_vm_running(&api_socket).await {
                        info!(
                            vm_id = %vm_id,
                            "boot watchdog: vm.info does not report Running; declining (not mid-boot)"
                        );
                        self.boot_watchdog_decline(&vm_id);
                        continue;
                    }
                    if !self.boot_watchdog_target_valid(&vm_id, vmm_pid).await {
                        debug!(
                            vm_id = %vm_id,
                            "boot watchdog: target changed since observation (re-spawn?); declining"
                        );
                        // Same decline contract as the state gate: the
                        // next evaluation comes after a full stall window
                        // (and the next pass re-anchors the state to the
                        // new generation anyway).
                        self.boot_watchdog_decline(&vm_id);
                        continue;
                    }
                    if self.console_draining.load(Ordering::SeqCst) {
                        // Graceful shutdown latched mid-pass: stand down
                        // without touching the state (shutdown is
                        // one-way; there will be no further passes).
                        continue;
                    }
                    let Some(attempt) = self.boot_watchdog_commit_fire(&vm_id) else {
                        error!(
                            vm_id = %vm_id,
                            marker = %config.boot_marker,
                            reboots = config.max_reboots,
                            "boot watchdog: standing down after exhausting the episode reboot budget; \
                             the VM requires operator attention"
                        );
                        continue;
                    };
                    let op_id = format!("boot-watchdog-reboot-{vm_id}-{attempt}");
                    warn!(
                        vm_id = %vm_id,
                        op = %op_id,
                        marker = %config.boot_marker,
                        stalled_secs = stalled_secs,
                        attempt = attempt,
                        max_reboots = config.max_reboots,
                        "boot watchdog: console stalled mid-boot without the boot-complete marker; \
                         rebooting to recover (this also re-creates the serial manager and \
                         restores console capture)"
                    );
                    match self.reboot_vm(&vm_id, Some(&op_id)).await {
                        Ok(()) => info!(
                            vm_id = %vm_id,
                            op = %op_id,
                            "boot watchdog: recovery reboot dispatched (reboot_vm reports Ok for \
                             non-2xx responses too — the recorded reboot_vm semantics follow-up)"
                        ),
                        Err(e) => warn!(
                            vm_id = %vm_id,
                            op = %op_id,
                            error = %e,
                            "boot watchdog: recovery reboot failed (counted toward the episode budget)"
                        ),
                    }
                }
                BootWatchdogAction::StandDown => {
                    error!(
                        vm_id = %vm_id,
                        marker = %config.boot_marker,
                        reboots = config.max_reboots,
                        "boot watchdog: standing down after exhausting the episode reboot budget; \
                         the VM requires operator attention"
                    );
                }
            }
        }
    }
    /// The per-VM lifecycle mutex (see `lifecycle_locks`). Lifecycle ops
    /// hold it for their whole duration; see the field doc for why keys
    /// are never removed.
    fn vm_op_lock(&self, vm_id: &str) -> Arc<tokio::sync::Mutex<()>> {
        let mut locks = self
            .lifecycle_locks
            .lock()
            .expect("lifecycle lock map poisoned");
        locks
            .entry(vm_id.to_string())
            .or_insert_with(|| Arc::new(tokio::sync::Mutex::new(())))
            .clone()
    }

    /// The executable name this adapter's VMMs must prove when an adopted
    /// pid is identity-checked (see `pid_is_cloud_hypervisor`).
    fn expected_vmm_exe(&self) -> Option<&std::ffi::OsStr> {
        self.chv_binary.file_name()
    }

    /// Refuses a create that would run a second VMM for a VM id whose
    /// runtime dir already hosts a live one — unlinking its sockets and
    /// spawning another process would fork the VM (two VMMs, one disk).
    /// Liveness is proven two ways, covering both a pidfile-identifiable
    /// VMM (the normal post-restart case: legacy-mode reconcilers
    /// re-create desired VMs after an agent restart while the adopted
    /// orphan still runs) and a pidfile-less VMM whose api socket still
    /// answers.
    async fn ensure_no_live_vmm(&self, config: &VmConfig) -> Result<(), ChvError> {
        if let Some(vm_dir) = config.api_socket_path.parent() {
            if let Ok(raw) = std::fs::read_to_string(vm_pid_file(vm_dir)) {
                if let Ok(pid) = raw.trim().parse::<u32>() {
                    if pid_is_cloud_hypervisor(
                        pid,
                        &config.api_socket_path,
                        self.expected_vmm_exe(),
                    ) {
                        return Err(ChvError::Internal {
                            reason: format!(
                                "cannot create vm {}: a cloud-hypervisor for this vm is already running (pid {pid}); stop and delete it first (an agent restart re-adopts it)",
                                config.vm_id
                            ),
                        });
                    }
                }
            }
        }
        if config.api_socket_path.exists() {
            // The socket file exists. A stale file (SIGKILLed VMM) must be
            // removable or the new bind fails — but a LIVE socket answers
            // vm.info, meaning a VMM without a pidfile is running: refuse
            // rather than fork it.
            if Self::ch_api_request(&config.api_socket_path, "GET", "/api/v1/vm.info", None)
                .await
                .is_ok()
            {
                return Err(ChvError::Internal {
                    reason: format!(
                        "cannot create vm {}: its api socket {} is answered by a running cloud-hypervisor (no pidfile); stop and delete it first",
                        config.vm_id,
                        config.api_socket_path.display()
                    ),
                });
            }
        }
        Ok(())
    }

    async fn wait_for_socket(socket: &Path, timeout: std::time::Duration) -> Result<(), ChvError> {
        let start = std::time::Instant::now();
        loop {
            if socket.exists() {
                return Ok(());
            }
            if start.elapsed() >= timeout {
                return Err(ChvError::Internal {
                    reason: format!("CH api socket did not appear: {}", socket.display()),
                });
            }
            tokio::time::sleep(std::time::Duration::from_millis(50)).await;
        }
    }

    async fn get_vm_socket(&self, vm_id: &str) -> Result<std::path::PathBuf, ChvError> {
        let vms = self.vms.read().await;
        let proc = vms.get(vm_id).ok_or_else(|| ChvError::NotFound {
            resource: "vm".to_string(),
            id: vm_id.to_string(),
        })?;
        Ok(proc.api_socket.clone())
    }

    fn expect_status(status: u16, endpoint: &str) -> Result<(), ChvError> {
        if status != 200 && status != 204 {
            return Err(ChvError::Internal {
                reason: format!("{} returned unexpected status {}", endpoint, status),
            });
        }
        Ok(())
    }

    async fn ch_api_request(
        socket: &Path,
        method: &str,
        path: &str,
        body: Option<&str>,
    ) -> Result<u16, ChvError> {
        CloudHypervisorApiClient::default()
            .request(socket, method, path, body)
            .await
    }

    async fn ch_api_request_with_body(
        socket: &Path,
        method: &str,
        path: &str,
        body: Option<&str>,
    ) -> Result<(u16, String), ChvError> {
        CloudHypervisorApiClient::default()
            .request_with_body(socket, method, path, body)
            .await
    }

    fn validate_vm_config(&self, config: &VmConfig) -> Result<(), ChvError> {
        if !self.chv_binary.exists() {
            return Err(ChvError::InvalidArgument {
                field: "chv_binary_path".to_string(),
                reason: format!("binary not found: {}", self.chv_binary.display()),
            });
        }
        if config.api_socket_path.as_os_str().is_empty() {
            return Err(ChvError::InvalidArgument {
                field: "api_socket_path".to_string(),
                reason: "api_socket_path is empty".to_string(),
            });
        }
        if config.api_socket_path.parent().is_none() {
            return Err(ChvError::InvalidArgument {
                field: "api_socket_path".to_string(),
                reason: format!(
                    "api_socket_path has no parent directory: {}",
                    config.api_socket_path.display()
                ),
            });
        }
        if let Some(ref fw) = config.firmware_path {
            if !fw.exists() {
                return Err(ChvError::InvalidArgument {
                    field: "firmware_path".to_string(),
                    reason: format!("firmware not found: {}", fw.display()),
                });
            }
        } else if !config.kernel_path.exists() {
            return Err(ChvError::InvalidArgument {
                field: "kernel_path".to_string(),
                reason: format!("kernel not found: {}", config.kernel_path.display()),
            });
        }
        for disk in &config.disks {
            if !disk.path.exists() {
                return Err(ChvError::InvalidArgument {
                    field: "disk_path".to_string(),
                    reason: format!("disk not found: {}", disk.path.display()),
                });
            }
        }
        Ok(())
    }
}

fn read_stderr_tail(path: &std::path::Path) -> String {
    let mut file = match std::fs::File::open(path) {
        Ok(f) => f,
        Err(_) => return String::new(),
    };
    let len = file.metadata().map(|m| m.len()).unwrap_or(0);
    let read_from = len.saturating_sub(4096);
    if read_from > 0 {
        let _ = file.seek(SeekFrom::Start(read_from));
    }
    let mut buf = Vec::new();
    let _ = file.read_to_end(&mut buf);
    let text = String::from_utf8_lossy(&buf);
    // Return all non-empty lines from the tail, joined, so we see the full
    // error context instead of just the last line (which is often "try --help").
    let lines: Vec<&str> = text.lines().filter(|l| !l.trim().is_empty()).collect();
    if lines.is_empty() {
        return "<empty>".to_string();
    }
    lines.join(" | ")
}

fn build_cpus_config(config: &VmConfig) -> serde_json::Value {
    let hv = config.hypervisor_overrides.as_ref();
    let mut cpus = serde_json::json!({
        "boot_vcpus": config.cpus,
        "max_vcpus": config.cpus,
    });
    if let Some(true) = hv.and_then(|h| h.cpu_amx) {
        cpus["features"] = serde_json::json!({ "amx": true });
    }
    if let Some(true) = hv.and_then(|h| h.cpu_nested) {
        cpus["topology"] = serde_json::json!({
            "threads_per_core": 1,
            "cores_per_die": config.cpus,
            "dies_per_package": 1,
            "packages": 1,
        });
    }
    cpus
}

/// The cloud-init NoCloud `meta-data` document. Both values are quoted so
/// they are always YAML STRINGS: `gen_short_id` emits 8 hex chars, so ~2.3%
/// of ids are all digits — an unquoted all-digit YAML scalar types as an
/// int, which crashes cloud-init 26.1's metadata standardization
/// (`'int' object has no attribute 'replace'`) and discards the ENTIRE
/// NoCloud datasource: userdata and network-config are then silently
/// never applied (#374).
///
/// NOTE: the quoting is not escape-aware — it is only correct for inputs
/// made of `gen_short_id`'s alphabet ([0-9a-f]). If this is ever reused
/// with values that may contain `"` or `\`, escape or reject them first.
fn cloud_init_meta_data(vm_id: &str) -> String {
    format!(
        "instance-id: \"{}\"\nlocal-hostname: \"{}\"\n",
        vm_id, vm_id
    )
}

async fn build_cloud_init_seed(
    vm_dir: &Path,
    vm_id: &str,
    userdata: Option<&str>,
    nics: &[crate::adapter::VmNicConfig],
) -> Result<std::path::PathBuf, ChvError> {
    let seed_dir = vm_dir.join("seed");
    tokio::fs::create_dir_all(&seed_dir)
        .await
        .map_err(|e| ChvError::Io {
            path: seed_dir.to_string_lossy().to_string(),
            source: e,
        })?;

    // The values MUST be quoted: gen_short_id emits 8 hex chars, so ~2.3%
    // of ids are all digits — and an unquoted all-digit YAML scalar types
    // as an int, which crashes cloud-init's metadata standardization
    // ('int' object has no attribute 'replace') and discards the ENTIRE
    // NoCloud datasource: userdata and network-config are then silently
    // never applied (#374).
    let meta_data = cloud_init_meta_data(vm_id);
    tokio::fs::write(seed_dir.join("meta-data"), meta_data.as_bytes())
        .await
        .map_err(|e| ChvError::Io {
            path: seed_dir.join("meta-data").to_string_lossy().to_string(),
            source: e,
        })?;

    let default_userdata = "#cloud-config\nusers:\n  - name: ubuntu\n    sudo: ALL=(ALL) NOPASSWD:ALL\n    lock_passwd: true\n    ssh_authorized_keys: []\nssh_pwauth: false\n";
    let user_data = userdata.unwrap_or(default_userdata);
    tokio::fs::write(seed_dir.join("user-data"), user_data.as_bytes())
        .await
        .map_err(|e| ChvError::Io {
            path: seed_dir.join("user-data").to_string_lossy().to_string(),
            source: e,
        })?;

    // Generate network-config v2 with MAC-matched static IPs from the control plane IPAM.
    let mut network_config = String::from("version: 2\nethernets:\n");
    for (idx, nic) in nics.iter().enumerate() {
        if nic.mac_address.is_empty() || nic.ip_address.is_empty() {
            continue;
        }
        let prefix = nic.cidr.split_once('/').map(|(_, p)| p).unwrap_or("24");
        let gateway = if nic.gateway.is_empty() {
            let parts: Vec<&str> = nic.ip_address.split('.').collect();
            if parts.len() == 4 {
                format!("{}.{}.{}.1", parts[0], parts[1], parts[2])
            } else {
                String::new()
            }
        } else {
            nic.gateway.clone()
        };

        let iface_name = format!("id{}", idx);
        network_config.push_str(&format!(
            "  {}:\n    match:\n      macaddress: \"{}\"\n    dhcp4: false\n    addresses:\n      - {}/{}\n",
            iface_name, nic.mac_address, nic.ip_address, prefix
        ));
        if !gateway.is_empty() {
            network_config.push_str(&format!(
                "    routes:\n      - to: default\n        via: {}\n",
                gateway
            ));
        }
    }

    if network_config.lines().count() <= 2 {
        // No valid NICs with IPAM data — fallback to DHCP with virtio matching.
        network_config.push_str("  id0:\n    match:\n      driver: virtio*\n    dhcp4: true\n");
    }

    tokio::fs::write(seed_dir.join("network-config"), network_config.as_bytes())
        .await
        .map_err(|e| ChvError::Io {
            path: seed_dir
                .join("network-config")
                .to_string_lossy()
                .to_string(),
            source: e,
        })?;

    let seed_iso = vm_dir.join("seed.iso");
    let output = run_genisoimage(&seed_iso, &seed_dir).await?;

    if !output.status.success() {
        return Err(ChvError::Internal {
            reason: format!(
                "genisoimage failed: {}",
                String::from_utf8_lossy(&output.stderr)
            ),
        });
    }

    Ok(seed_iso)
}

/// Runs `genisoimage` to build the cloud-init seed ISO. Resolved through
/// PATH first; if PATH lookup reports NotFound, falls back to the canonical
/// install location (`install.sh` and the systemd unit guarantee /usr/bin,
/// so this covers a stripped environment such as a minimal container).
async fn run_genisoimage(
    seed_iso: &std::path::Path,
    seed_dir: &std::path::Path,
) -> Result<std::process::Output, ChvError> {
    let command = |binary: &str| {
        let mut command = tokio::process::Command::new(binary);
        command
            .arg("-output")
            .arg(seed_iso)
            .arg("-volid")
            .arg("cidata")
            .arg("-joliet")
            .arg("-rock")
            .arg(seed_dir.join("user-data"))
            .arg(seed_dir.join("meta-data"))
            .arg(seed_dir.join("network-config"));
        command
    };
    match command("genisoimage").output().await {
        Ok(output) => Ok(output),
        Err(error) if error.kind() == std::io::ErrorKind::NotFound => {
            command("/usr/bin/genisoimage")
                .output()
                .await
                .map_err(|e| ChvError::Internal {
                    reason: format!("failed to run genisoimage: {}", e),
                })
        }
        Err(error) => Err(ChvError::Internal {
            reason: format!("failed to run genisoimage: {}", error),
        }),
    }
}

/// Borrowed console fan-out pair (broadcast channel + scrollback) used
/// by the serial abandonment paths to preserve drained guest output.
type ConsoleFanout<'a> = (
    &'a tokio::sync::broadcast::Sender<Vec<u8>>,
    &'a Arc<std::sync::RwLock<Vec<u8>>>,
);

impl ProcessCloudHypervisorAdapter {
    /// How long a graceful stop waits, after pressing the ACPI power
    /// button (`vm.power-button`), for the guest OS to power itself off
    /// before falling back to a force kill.
    ///
    /// Measured on the pinned noble guest image (M2.5 qualification,
    /// isolation experiment 2026-09-28): a healthy, fully-booted guest
    /// needs ~32 s from button press to poweroff — `snapd.service` alone
    /// stops for 28-31 s — and a button pressed before `systemd-logind`
    /// has subscribed to the input device is silently dropped by the
    /// guest (no shutdown begins at all). The previous 10 s window
    /// therefore force-killed routine guest shutdowns mid-flight, which
    /// removed the runtime map entry (and, at the time, outright
    /// deleted the console evidence) and left a later start with no
    /// entry to boot — today the force residual is handled
    /// (`readopt_stopped_vm` re-derives the entry and the console log
    /// is rotated, not deleted), but a force kill is still a worse
    /// outcome than a clean guest shutdown. 60 s
    /// gives ~2x headroom over the measured shutdown while still
    /// bounding the worst case for a wedged guest.
    const GRACEFUL_STOP_WINDOW: std::time::Duration = std::time::Duration::from_secs(60);

    /// How long the post-stop SIGKILL remediation may take to confirm
    /// the VMM process is gone. A signalled process dies in
    /// milliseconds; the window only bounds the pathological tail
    /// (a D-state process survives even SIGKILL) so a stop op never
    /// hangs forever — it fails loudly instead.
    const KILL_CONFIRM_WINDOW: std::time::Duration = std::time::Duration::from_secs(30);

    /// Confirms a force-killed VMM actually died — #345's contract
    /// (a live VMM must not outlive a successful stop or delete)
    /// extends to the kill itself: verify death, never assume it
    /// (#348; applied to every force-kill site by #351). The kill can
    /// be REFUSED (an adopted pid whose identity can no longer be
    /// proven — e.g. the VMM binary was replaced on disk while the
    /// process ran — must never be signalled) or INEFFECTIVE (a
    /// D-state process survives even SIGKILL).
    ///
    /// Returns `true` once the process is confirmed gone: an `Owned`
    /// child is confirmed AND reaped by the polling itself
    /// (`try_wait`), an adopted orphan is gone once it leaves
    /// `/proc`, and a `Dead` handle (or an already-exited process)
    /// confirms immediately — stop and delete stay idempotent for the
    /// already-dead VMM. Returns `false` when the process is still
    /// alive: immediately for a refused kill (no signal was issued,
    /// waiting cannot help), or once `KILL_CONFIRM_WINDOW` elapses
    /// over an ineffective one. Callers must then fail loudly with
    /// the documented operator escape instead of reporting success
    /// over the live process.
    async fn confirm_vmm_death(child: &mut VmmChild, signaled: bool) -> bool {
        let deadline = std::time::Instant::now() + Self::KILL_CONFIRM_WINDOW;
        loop {
            let gone = match child {
                // try_wait confirms AND reaps an Owned child in one
                // step.
                VmmChild::Owned(owned) => owned
                    .try_wait()
                    .map(|status| status.is_some())
                    .unwrap_or(true),
                // An adopted orphan is parented to init; gone once it
                // leaves /proc.
                VmmChild::Adopted(pid) => !pid_exists(*pid),
                VmmChild::Dead => true,
            };
            if gone {
                return true;
            }
            if !signaled || std::time::Instant::now() >= deadline {
                return false;
            }
            tokio::time::sleep(std::time::Duration::from_millis(100)).await;
        }
    }

    /// Force-kills the VMM of an entry that was just REMOVED from the
    /// runtime map — `delete_vm`, and `stop_vm`'s force and
    /// graceful-timeout branches — and confirms its death (#351,
    /// mirroring #348's stop-path handling). The pre-#351 shape
    /// (`kill` + `wait`, return value ignored) reported success over
    /// a live VMM whenever the kill was refused or ineffective: the
    /// process survived while holding the VM's runtime dir, sockets,
    /// and disk, and the removed entry meant the VM's state no longer
    /// referenced it — the #345 bug class. Delete's cleanup semantics
    /// do NOT legitimize continuing past a surviving VMM: the
    /// artifact removal below would unlink sockets a live VMM still
    /// holds and drop the runtime evidence, and a later re-create
    /// would target the disk it still owns.
    ///
    /// On a refused or ineffective kill the removed entry is RESTORED
    /// to the map (the truthful state: the VMM is provably alive) so
    /// a retry re-validates liveness instead of the op having
    /// silently orphaned a live VMM, and the error names the
    /// documented operator escape. The caller must hold the VM's
    /// lifecycle op lock (every removal site does, and every insert
    /// path under lifecycle-op control — create, re-spawn, re-adopt —
    /// holds it too), so the restore cannot race a concurrent create
    /// or re-spawn. The ONE lock-free insert, `adopt_running_vms`,
    /// runs only at startup, before the agent serves lifecycle ops;
    /// if a mid-service adoption/reconcile pass is ever added it MUST
    /// take the per-VM op lock or this restore claim is void.
    ///
    /// On success the process is dead and reaped (an `Owned` child is
    /// reaped by the confirmation loop) and `proc` is consumed AFTER
    /// that reap — preserving the kill-before-drop invariant on the
    /// serial descriptor (see `stop_vm`'s force branch): the caller's
    /// cleanup (artifact deletion, log rotation) then runs against a
    /// dead VMM only.
    async fn kill_removed_vmm_or_restore(
        &self,
        vm_id: &str,
        mut proc: VmProcess,
    ) -> Result<(), ChvError> {
        let signaled = proc.child.kill(&proc.api_socket, self.expected_vmm_exe());
        if Self::confirm_vmm_death(&mut proc.child, signaled).await {
            return Ok(());
        }
        let outcome = if signaled {
            "kill ineffective"
        } else {
            "kill refused: process identity unproven"
        };
        let pid = proc
            .child
            .vmm_pid()
            .map(|p| p.to_string())
            .unwrap_or_else(|| "<unknown>".to_string());
        warn!(
            vm_id = %vm_id,
            pid = ?pid,
            outcome,
            "VMM still alive after the force kill: restoring the runtime-map \
             entry and failing the op (the process holds the vm's runtime \
             dir, sockets, and disk)"
        );
        {
            let mut map = self.vms.write().await;
            // The slot is vacant — this entry was removed under the
            // lifecycle op lock, which every insert path under
            // lifecycle-op control for this vm_id also holds (the one
            // lock-free insert, `adopt_running_vms`, is pre-service
            // only; see the doc comment above). The vacancy check is
            // defense in depth and MUST stay unreachable in
            // production: were a newer entry somehow present, keeping
            // it means DROPPING `proc` — a live handle whose
            // console_io covers a provably-alive VMM (the exact
            // close-over-live-VMM hazard this fn exists to prevent) —
            // so it is logged loudly, never silent.
            if !map.contains_key(vm_id) {
                map.insert(vm_id.to_string(), proc);
            } else {
                warn!(
                    vm_id = %vm_id,
                    "runtime-map entry was re-created while a failed force \
                     kill held the lifecycle op lock; keeping the newer \
                     entry (the failed kill's live VMM handle is dropped — \
                     operator attention required)"
                );
            }
        }
        Err(ChvError::Internal {
            reason: format!(
                "VMM for vm '{vm_id}' (pid {pid}) is still alive after the \
                 force SIGKILL ({outcome}): it still holds the vm's runtime \
                 dir, sockets, and disk; manual operator intervention \
                 required (SIGKILL pid {pid} directly — the documented \
                 escape), then retry the operation"
            ),
        })
    }

    /// Builds the cloud-hypervisor serial-console config object for the
    /// VM creation payload. `Socket` (the default transport) points the
    /// serial console at a unix-stream listener inside the VM runtime
    /// directory, which cloud-hypervisor binds while creating the VM and
    /// the agent connects to right after; every other mode is passed
    /// through as the bare mode string, matching the cloud-hypervisor
    /// REST schema (`ConsoleConfig`).
    fn serial_console_config(serial_mode: &str, socket_path: &Path) -> serde_json::Value {
        if serial_mode == chv_common::hypervisor::DEFAULT_SERIAL_MODE {
            serde_json::json!({
                "mode": "Socket",
                "socket": socket_path.to_string_lossy(),
            })
        } else {
            serde_json::json!({ "mode": serial_mode })
        }
    }

    /// Connects once to cloud-hypervisor's serial listener and returns a
    /// blocking, FD_CLOEXEC fd. Fails if the listener is unreachable or
    /// the peer-identity check fails.
    async fn connect_serial_socket_once(socket_path: &Path) -> std::io::Result<OwnedFd> {
        let stream = tokio::net::UnixStream::connect(socket_path).await?;
        let std_stream = stream.into_std()?;
        // tokio connects in non-blocking mode; restore blocking
        // mode so the broadcaster's and console server's plain
        // reads/writes block instead of failing with EAGAIN.
        if let Ok(flags) = nix::fcntl::fcntl(&std_stream, nix::fcntl::F_GETFL) {
            let blocking =
                nix::fcntl::OFlag::from_bits_retain(flags) & !nix::fcntl::OFlag::O_NONBLOCK;
            if let Err(e) = nix::fcntl::fcntl(&std_stream, nix::fcntl::F_SETFL(blocking)) {
                // A fd left non-blocking makes every "blocking" console
                // read spin on EAGAIN; not fatal (connect still
                // succeeded), but it must be visible in the logs.
                warn!(
                    error = %e,
                    "failed to restore blocking mode on the serial socket"
                );
            }
        }
        if let Err(e) = nix::fcntl::fcntl(
            &std_stream,
            nix::fcntl::F_SETFD(nix::fcntl::FdFlag::FD_CLOEXEC),
        ) {
            // Without FD_CLOEXEC this descriptor leaks into every
            // subsequently spawned cloud-hypervisor child.
            warn!(
                error = %e,
                "failed to set FD_CLOEXEC on the serial socket"
            );
        }
        // Defense-in-depth peer-identity check, mirroring this crate's
        // trust-walk discipline: the listener at this path was bound by
        // the cloud-hypervisor child this agent spawned — the same
        // effective uid — and the kernel reports the listener owner's
        // credentials to a connecting client via SO_PEERCRED. Anything
        // else answering on this path means the socket is not ours; fail
        // closed rather than pipe a stranger's bytes into the guest
        // console.
        match nix::sys::socket::getsockopt(&std_stream, nix::sys::socket::sockopt::PeerCredentials)
        {
            Ok(creds) if creds.uid() == nix::unistd::geteuid().as_raw() => {}
            other => {
                return Err(std::io::Error::other(format!(
                    "serial socket peer identity mismatch (peer={other:?}, expected euid {})",
                    nix::unistd::geteuid()
                )));
            }
        }
        Ok(std_stream.into())
    }

    /// Connects to the guest serial-console unix socket (Socket
    /// transport). cloud-hypervisor binds the listener while handling
    /// `vm.create`, so the socket exists by the time this runs; the
    /// bounded retry only guards a slow bind racing the connect. The fd is
    /// returned in blocking mode with FD_CLOEXEC set — the console
    /// broadcaster and console server use blocking reads and writes on it.
    /// On failure the spawned child is killed: a console-less VM is never
    /// left running.
    async fn connect_serial_socket(
        socket_path: &Path,
        child: &mut Child,
        vm_id: &str,
        operation_id: Option<&str>,
    ) -> Result<OwnedFd, ChvError> {
        let path_display = socket_path.to_string_lossy().to_string();
        let mut last_err = None;
        for attempt in 0..10u32 {
            match Self::connect_serial_socket_once(socket_path).await {
                Ok(fd) => {
                    info!(
                        vm_id = vm_id,
                        socket = %path_display,
                        op = operation_id.unwrap_or("-"),
                        "chv serial socket connected"
                    );
                    return Ok(fd);
                }
                Err(e) => {
                    last_err = Some(e);
                    if attempt < 9 {
                        tokio::time::sleep(std::time::Duration::from_millis(100)).await;
                    }
                }
            }
        }
        let _ = child.start_kill();
        let _ = child.wait().await;
        Err(ChvError::Io {
            path: path_display,
            source: last_err.unwrap_or_else(|| std::io::Error::other("connect failed")),
        })
    }

    /// Reconnects to the guest serial-console listener for an already
    /// running VM (broadcaster respawn): the stored connection may have
    /// been closed by the VMM side, so a fresh one is established. No
    /// child to fail closed on — the caller degrades gracefully (console
    /// capture stays down, retried on the next start_vm). Checks the
    /// `draining` latch on every attempt and gives up immediately once
    /// graceful agent shutdown has begun: a connection minted during
    /// shutdown would be abortively closed by process exit (see
    /// [`Self::drain_and_close_consoles`]).
    async fn reconnect_serial_socket(socket_path: &Path, draining: &AtomicBool) -> Option<OwnedFd> {
        for attempt in 0..10u32 {
            if draining.load(Ordering::SeqCst) {
                return None;
            }
            if let Ok(fd) = Self::connect_serial_socket_once(socket_path).await {
                return Some(fd);
            }
            if attempt < 9 {
                tokio::time::sleep(std::time::Duration::from_millis(100)).await;
            }
        }
        None
    }

    /// Reads a serial-socket descriptor's kernel receive queue until it
    /// would block and returns everything drained, restoring the
    /// descriptor's prior status flags. The fd is forced non-blocking for
    /// the drain so it cannot block on a stream that is still receiving
    /// data. Bytes read here are removed from the queue — which is what
    /// makes the descriptor's eventual close a clean FIN instead of an
    /// RST (the kernel resets a unix-stream connection on close when its
    /// receive queue still holds unread data).
    fn drain_serial_receive_queue(fd: &OwnedFd) -> Vec<u8> {
        let saved = nix::fcntl::fcntl(fd, nix::fcntl::F_GETFL)
            .ok()
            .and_then(nix::fcntl::OFlag::from_bits);
        if let Some(saved) = saved {
            let _ = nix::fcntl::fcntl(
                fd,
                nix::fcntl::F_SETFL(saved | nix::fcntl::OFlag::O_NONBLOCK),
            );
        }
        let mut drained = Vec::new();
        let mut buf = [0u8; 4096];
        loop {
            match nix::unistd::read(fd, &mut buf) {
                Ok(0) => break, // peer closed its write side
                Ok(n) => drained.extend_from_slice(&buf[..n]),
                Err(_) => break, // EAGAIN (queue empty) or peer gone
            }
        }
        if let Some(saved) = saved {
            let _ = nix::fcntl::fcntl(fd, nix::fcntl::F_SETFL(saved));
        }
        drained
    }

    /// Appends drained console bytes to the shared scrollback buffer,
    /// enforcing the [`CONSOLE_SCROLLBACK_BYTES`] cap. The single place
    /// the cap policy lives: the broadcaster's drain loop, the
    /// abandoned-connection drain and the shutdown drain all push through
    /// here, so the WS scrollback contract (last 256 KiB, exact,
    /// in-order) is identical on every path.
    fn push_console_scrollback(scrollback: &std::sync::RwLock<Vec<u8>>, data: &[u8]) {
        let mut sb = scrollback.write().expect("scrollback lock poisoned");
        sb.extend_from_slice(data);
        if sb.len() > CONSOLE_SCROLLBACK_BYTES {
            let excess = sb.len() - CONSOLE_SCROLLBACK_BYTES;
            sb.drain(0..excess);
        }
    }

    /// The per-connection console drain loop (issue #469): a tight
    /// BLOCKING read loop with no awaits between reads.
    ///
    /// Why it must drain continuously — cloud-hypervisor v53.0's
    /// pre-connect serial buffering (#8322 upstream) is defective (pin
    /// re-qualification leg 02, §4.3): the backlog flush writes ONE byte
    /// per `write()` syscall to the non-blocking client socket, breaks
    /// silently on the first EAGAIN (~one socket-fill, ~278–330 one-byte
    /// skbs of AF_UNIX truesize accounting), and has NO retry path — the
    /// serial-manager epoll never watches EPOLLOUT. Backlog delivery
    /// resumes only when the guest's own output re-triggers the
    /// device-path flush, and each retried session only gets as far as
    /// the socket's free space allows. A reader with inter-read gaps
    /// therefore truncates every flush session: a quiet guest stalls at
    /// ~278 B and a trickling guest crawls at ~0.6–1.3 KB/s, while a
    /// reader that keeps the socket empty lets the first vCPU-triggered
    /// session push the whole backlog in one pass (E3f: ~72.7 KB in
    /// 0.4 s). This loop provides that property by construction: plain
    /// blocking `read()` (returns as soon as any data is readable), the
    /// fan-out between reads is a bounded memcpy under a sync lock plus
    /// a non-blocking broadcast send, and nothing else — no sleeps, no
    /// poll intervals, no awaits that could park the connection with
    /// unread data pending.
    ///
    /// Endpoint-loss contract (unchanged from the async read loop this
    /// replaces): `Ok(0)` (EOF — the #284 reboot rotation's `SHUT_RD`
    /// lands here, as does a VMM-side close) or any read error ends the
    /// cycle; the caller's self-heal reconnect then takes over. The
    /// descriptor is consumed and closed on return, ending the cycle's
    /// dup exactly as before.
    fn drain_console_endpoint(
        cycle_fd: OwnedFd,
        pty_tx: &tokio::sync::broadcast::Sender<Vec<u8>>,
        pty_scrollback: &std::sync::RwLock<Vec<u8>>,
    ) {
        let mut buf = [0u8; 4096];
        loop {
            match nix::unistd::read(&cycle_fd, &mut buf) {
                Ok(0) | Err(_) => return, // endpoint lost
                Ok(n) => {
                    let data = &buf[..n];
                    Self::push_console_scrollback(pty_scrollback, data);
                    let _ = pty_tx.send(data.to_vec());
                }
            }
        }
    }

    /// Cleanly abandons a live serial-console connection the agent has
    /// decided not to keep (heal superseded by a map replacement, failed
    /// dup, VM leaving the map). Consumes and closes the descriptor.
    ///
    /// Why this exists: cloud-hypervisor v43's socket-serial path
    /// mishandles an *abortively* closed client. If the client's receive
    /// queue still holds unread guest output when its descriptor closes,
    /// the kernel resets the connection; the serial-manager thread then
    /// dies silently on the ECONNRESET, `out` keeps pointing at the dead
    /// socket, every guest UART byte's write fails EPIPE and skips the
    /// THRE interrupt, and the guest's interrupt-driven tty tx stalls —
    /// a frozen guest while `vm.info` keeps reporting Running (root
    /// cause proven in the M2.5 qualification, isolation experiments
    /// e9-kernel/e9-quiet). A *clean* close is handled correctly: the
    /// manager logs "Remote end closed serial socket", detaches the
    /// client, the guest is unaffected, and the listener keeps
    /// accepting. This function therefore takes exactly the clean path:
    ///
    /// 1. half-close the write side (`shutdown(SHUT_WR)`) — the manager
    ///    observes the same clean EOF a well-behaved client produces and
    ///    detaches, which also stops it writing guest output into the
    ///    connection;
    /// 2. after a settle delay, drain the receive queue (forwarding any
    ///    already-buffered guest output into the console fan-out when
    ///    one is given, so console.log keeps the evidence);
    /// 3. drop the descriptor — with an empty receive queue the close
    ///    is a FIN, not an RST.
    ///
    /// `shutdown(SHUT_RD)` is deliberately NOT used anywhere on a live
    /// connection: it makes the peer's writes fail EPIPE while the
    /// connection is still open, which is itself a freeze trigger on
    /// v43 (the skipped-THRE path above).
    async fn abandon_serial_connection(
        vm_id: &str,
        fd: OwnedFd,
        fanout: Option<ConsoleFanout<'_>>,
    ) {
        if let Err(e) =
            nix::sys::socket::shutdown(fd.as_raw_fd(), nix::sys::socket::Shutdown::Write)
        {
            debug!(vm_id = %vm_id, error = %e, "serial half-close failed (peer already gone?)");
        }
        // Settle: give the serial manager a moment to observe the EOF
        // and stop writing guest output into the connection, so the
        // drain below converges to an empty queue.
        tokio::time::sleep(std::time::Duration::from_millis(20)).await;
        let drained = Self::drain_serial_receive_queue(&fd);
        if drained.is_empty() {
            return;
        }
        if let Some((tx, scrollback)) = fanout {
            Self::push_console_scrollback(scrollback, &drained);
            let _ = tx.send(drained.clone());
        }
        info!(
            vm_id = %vm_id,
            bytes = drained.len(),
            "drained buffered console output from an abandoned serial connection"
        );
    }

    /// Graceful-shutdown hook: converts the agent's process exit from an
    /// abortive close of every live serial-console connection into the
    /// clean close cloud-hypervisor v43 handles correctly (see
    /// [`Self::abandon_serial_connection`] for the defect chain — a
    /// client closing with unread receive-queue data resets the
    /// connection, silently kills the serial-manager thread, and can
    /// freeze a still-running guest; VMs outlive the agent).
    ///
    /// Call this as the LAST act of a graceful shutdown — after the
    /// core owner and supervisor shutdown, so the executor's bounded
    /// drain (up to 60 s of still-running lifecycle ops and console
    /// traffic) has finished first. Idempotent: the multiple signal and
    /// error exit paths can each call it.
    ///
    /// 1. latch `console_draining` — console healing stands down instead
    ///    of minting connections that process exit would abortively
    ///    close;
    /// 2. half-close every live Socket-transport connection — each
    ///    serial manager observes the clean EOF it handles correctly and
    ///    detaches, which also stops it writing guest output into the
    ///    connection;
    /// 3. after a settle delay, drain each receive queue, forwarding the
    ///    buffered guest output into the console fan-out (scrollback +
    ///    console.log) so the descriptors' close at process exit is a
    ///    FIN, not an RST;
    /// 4. yield once more so any healer that was mid-reconnect when the
    ///    latch was set can acquire the (now released) vm-map lock, see
    ///    the latch, and cleanly abandon its fresh connection before
    ///    the process goes away.
    ///
    /// Residual risk, documented: guest output landing in a receive
    /// queue between the drain and the process-exit close (a
    /// microsecond-scale window on a loaded host), or a healer starved
    /// past the final yield. A hit degrades to the pre-fix behavior —
    /// recoverable by `vm.reboot`, which re-creates the serial manager.
    pub async fn drain_and_close_consoles(&self) {
        if self.console_draining.swap(true, Ordering::SeqCst) {
            return; // a prior exit path already drained
        }
        let mut socket_vm_ids: Vec<String> = Vec::new();
        {
            // Hold the vm-map write lock across both passes: lifecycle
            // endpoint swaps and the broadcaster heal's swap are blocked
            // behind it, and the heal re-checks the draining latch after
            // acquiring it. (Lock order vms -> pty_scrollback matches
            // every other holder.)
            let mut vms = self.vms.write().await;
            for (vm_id, proc) in vms.iter() {
                if !matches!(proc.serial_transport, SerialTransport::Socket(_)) {
                    continue;
                }
                socket_vm_ids.push(vm_id.clone());
                if let Err(e) = nix::sys::socket::shutdown(
                    proc.console_io.as_raw_fd(),
                    nix::sys::socket::Shutdown::Write,
                ) {
                    debug!(vm_id = %vm_id, error = %e, "console half-close failed (VMM gone?)");
                }
            }
            if !socket_vm_ids.is_empty() {
                info!(
                    vms = socket_vm_ids.len(),
                    "draining serial-console connections for agent shutdown"
                );
            }
            // Settle: let every serial manager observe the EOF, detach
            // its client, and stop writing guest output into the
            // connection — the drain below then converges to an empty
            // queue that stays empty.
            tokio::time::sleep(std::time::Duration::from_millis(200)).await;
            for vm_id in &socket_vm_ids {
                let Some(proc) = vms.get_mut(vm_id) else {
                    continue;
                };
                let drained = Self::drain_serial_receive_queue(&proc.console_io);
                if drained.is_empty() {
                    continue;
                }
                Self::push_console_scrollback(&proc.pty_scrollback, &drained);
                let _ = proc.pty_tx.send(drained.clone());
                info!(
                    vm_id = %vm_id,
                    bytes = drained.len(),
                    "drained buffered console output during agent shutdown"
                );
            }
        }
        // Final yield: healers blocked on the vm-map lock when the drain
        // began release here, observe the latch, and cleanly abandon
        // their fresh connection. Without this yield the process could
        // exit first and abortively close that connection — recreating
        // the very defect this hook exists to prevent.
        tokio::time::sleep(std::time::Duration::from_millis(250)).await;
    }

    /// Duplicates a console fd for a secondary consumer (broadcaster,
    /// console server). The dup inherits the source fd's blocking mode —
    /// a property of the open file description — while FD_CLOEXEC is
    /// per-descriptor and must be set on each dup.
    fn dup_cloexec(fd: &OwnedFd) -> std::io::Result<OwnedFd> {
        let dup = nix::unistd::dup(fd).map_err(|e| std::io::Error::other(e.to_string()))?;
        if let Err(e) = nix::fcntl::fcntl(&dup, nix::fcntl::F_SETFD(nix::fcntl::FdFlag::FD_CLOEXEC))
        {
            // FD_CLOEXEC is per-descriptor; without it this dup leaks
            // into every subsequently spawned cloud-hypervisor child.
            // Not fatal, but it must be visible in the logs.
            warn!(error = %e, "failed to set FD_CLOEXEC on a console dup");
        }
        Ok(dup)
    }

    /// Revives the console broadcaster if it died while the VM was
    /// running (outer safety net; the broadcaster itself self-heals
    /// across VMM-side connection cycles — see `spawn_pty_broadcaster`).
    /// Obtains a FRESH endpoint, not a dup of the stored fd: for
    /// the Socket transport the stored connection may itself be dead (the
    /// VMM side can close it across serial reconfiguration or shutdown
    /// cycles), and a broadcaster on a dup of a dead connection dies
    /// instantly — silent, unrecoverable console loss. Socket transport
    /// reconnects and swaps the stored connection for the live one; the
    /// pty slave survives guest reboots, so it is re-dup'ed. A failed
    /// reconnect is non-fatal: console capture stays down and is retried
    /// on the next start_vm.
    async fn respawn_broadcaster_if_dead(
        &self,
        vm_id: &str,
        serial_transport: &SerialTransport,
        pty_tx: &tokio::sync::broadcast::Sender<Vec<u8>>,
        pty_scrollback: &Arc<std::sync::RwLock<Vec<u8>>>,
        broadcaster_alive: &Arc<AtomicBool>,
    ) {
        if broadcaster_alive.load(Ordering::SeqCst) {
            return;
        }
        // Graceful agent shutdown: never mint a fresh connection — process
        // exit would abortively close it (see `drain_and_close_consoles`).
        if self.console_draining.load(Ordering::SeqCst) {
            return;
        }
        info!(vm_id = %vm_id, "respawning console broadcaster");
        let broadcaster_fd: Option<OwnedFd> = match serial_transport {
            SerialTransport::Socket(path) => {
                match Self::reconnect_serial_socket(path, &self.console_draining).await {
                    Some(fresh) => {
                        let dup = match Self::dup_cloexec(&fresh) {
                            Ok(d) => d,
                            Err(e) => {
                                warn!(
                                    vm_id = %vm_id,
                                    error = %e,
                                    "serial respawn dup failed; abandoning the fresh connection"
                                );
                                Self::abandon_serial_connection(vm_id, fresh, None).await;
                                return;
                            }
                        };
                        let mut vms = self.vms.write().await;
                        // Post-lock double check of the shutdown latch
                        // (mirrors the broadcaster heal): the drain hook
                        // holds this lock across its passes — if it
                        // latched while this respawn was reconnecting,
                        // abandon the fresh connection cleanly and exit
                        // rather than let process exit abortively close
                        // it (an abortive close resets the connection
                        // and can kill the serial manager).
                        if self.console_draining.load(Ordering::SeqCst) {
                            drop(vms);
                            drop(dup);
                            Self::abandon_serial_connection(vm_id, fresh, None).await;
                            return;
                        }
                        match vms.get_mut(vm_id) {
                            // Supersede check (mirrors the broadcaster
                            // heal): if the entry was replaced — fresh
                            // channel from a VMM re-spawn or re-adoption —
                            // a replacement broadcaster owns the console
                            // now; swapping our endpoint under it would
                            // split the byte stream between two readers of
                            // one socket. Abandon the fresh connection
                            // cleanly instead of dropping it with
                            // possibly-unread data (an abortive close
                            // resets the connection and can kill the
                            // serial manager).
                            Some(proc) if proc.pty_tx.same_channel(pty_tx) => {
                                proc.console_io = fresh;
                                Some(dup)
                            }
                            superseded => {
                                let fanout = superseded
                                    .map(|proc| (proc.pty_tx.clone(), proc.pty_scrollback.clone()));
                                drop(vms);
                                drop(dup);
                                match fanout {
                                    Some((tx, sb)) => {
                                        Self::abandon_serial_connection(
                                            vm_id,
                                            fresh,
                                            Some((&tx, &sb)),
                                        )
                                        .await;
                                    }
                                    None => {
                                        Self::abandon_serial_connection(vm_id, fresh, None).await;
                                    }
                                }
                                None
                            }
                        }
                    }
                    None => {
                        warn!(
                            vm_id = %vm_id,
                            socket = %path.display(),
                            "serial socket reconnect failed; console capture stays down until the next start_vm"
                        );
                        None
                    }
                }
            }
            SerialTransport::Pty => {
                let vms = self.vms.read().await;
                vms.get(vm_id)
                    .and_then(|proc| Self::dup_cloexec(&proc.console_io).ok())
            }
        };
        if let Some(broadcaster_fd) = broadcaster_fd {
            broadcaster_alive.store(true, Ordering::SeqCst);
            Self::spawn_pty_broadcaster(
                self.vms.clone(),
                vm_id.to_string(),
                broadcaster_fd,
                serial_transport.clone(),
                pty_tx.clone(),
                pty_scrollback.clone(),
                broadcaster_alive.clone(),
                self.console_draining.clone(),
            );
        }
    }

    /// Opens the pty slave cloud-hypervisor allocated for the guest serial
    /// console (Pty transport, explicit tuning only). The slave path comes
    /// from `vm.info`; the pty is set to raw mode so the host line
    /// discipline does not buffer or echo keystrokes. On failure the
    /// spawned child is killed.
    async fn open_serial_pty(
        api_socket_path: &Path,
        child: &mut Child,
        vm_id: &str,
        operation_id: Option<&str>,
    ) -> Result<OwnedFd, ChvError> {
        // Query CHV for the PTY slave path it created for the serial device.
        let (info_status, info_body) =
            Self::ch_api_request_with_body(api_socket_path, "GET", "/api/v1/vm.info", None).await?;
        let slave_path = if info_status == 200 {
            if let Ok(v) = serde_json::from_str::<serde_json::Value>(&info_body) {
                v.pointer("/config/serial/file")
                    .and_then(|s| s.as_str())
                    .map(|s| s.to_string())
            } else {
                None
            }
        } else {
            None
        };
        let slave_path = match slave_path {
            Some(path) => path,
            None => {
                let _ = child.start_kill();
                let _ = child.wait().await;
                return Err(ChvError::Internal {
                    reason: format!("vm.info did not return serial PTY path for vm {}", vm_id),
                });
            }
        };

        // Open the PTY slave that CHV created.  This is the I/O endpoint
        // for the guest serial console — we read guest output from it and
        // write user keystrokes to it.
        let pty_slave = match std::fs::OpenOptions::new()
            .read(true)
            .write(true)
            .custom_flags(nix::libc::O_NOCTTY)
            .open(&slave_path)
        {
            Ok(slave) => slave,
            Err(e) => {
                let _ = child.start_kill();
                let _ = child.wait().await;
                return Err(ChvError::Io {
                    path: slave_path.clone(),
                    source: e,
                });
            }
        };
        // Set raw mode so the host line discipline doesn't buffer or echo
        // keystrokes — we want every byte forwarded to the guest immediately.
        if let Ok(mut term) = nix::sys::termios::tcgetattr(&pty_slave) {
            nix::sys::termios::cfmakeraw(&mut term);
            let _ =
                nix::sys::termios::tcsetattr(&pty_slave, nix::sys::termios::SetArg::TCSANOW, &term);
        }
        let pty_master: OwnedFd = pty_slave.into();
        let _ = nix::fcntl::fcntl(
            &pty_master,
            nix::fcntl::F_SETFD(nix::fcntl::FdFlag::FD_CLOEXEC),
        );

        info!(
            vm_id = vm_id,
            pty = %slave_path,
            op = operation_id.unwrap_or("-"),
            "chv serial pty ready"
        );
        Ok(pty_master)
    }

    /// Spawns the console.log persistence task: subscribes to the VM's
    /// console fan-out channel and writes output to `log_path`, capped at
    /// [`CONSOLE_LOG_MAX_BYTES`] with wraparound (in-memory scrollback keeps
    /// the recent tail either way). The task ends when every sender for the
    /// channel drops — i.e. when the VM entry (and its broadcaster) are
    /// replaced or removed.
    fn spawn_console_log_writer(
        vm_id: &str,
        pty_tx: &tokio::sync::broadcast::Sender<Vec<u8>>,
        log_path: std::path::PathBuf,
        mode: ConsoleLogMode,
    ) {
        let vm_id_log = vm_id.to_string();
        let mut pty_rx_log = pty_tx.subscribe();
        tokio::spawn(async move {
            let mut options = tokio::fs::OpenOptions::new();
            options.create(true);
            match mode {
                ConsoleLogMode::Fresh => {
                    options.truncate(true).write(true);
                }
                ConsoleLogMode::Append => {
                    options.append(true);
                }
            }
            let log_file = options.open(&log_path).await;
            let mut writer = match log_file {
                Ok(f) => f,
                Err(e) => {
                    tracing::debug!(vm_id = %vm_id_log, error = %e, "failed to open console.log");
                    return;
                }
            };
            let mut written: u64 = 0;
            loop {
                match pty_rx_log.recv().await {
                    Ok(data) => {
                        if written + data.len() as u64 > CONSOLE_LOG_MAX_BYTES {
                            // Safety cap: truncate and continue. In-memory scrollback
                            // preserves the last 256 KiB so recent output is still
                            // visible via WebSocket.
                            let _ = writer.set_len(0).await;
                            let _ = writer.seek(SeekFrom::Start(0)).await;
                            written = 0;
                        }
                        if writer.write_all(&data).await.is_ok() {
                            written += data.len() as u64;
                        }
                    }
                    Err(tokio::sync::broadcast::error::RecvError::Closed) => break,
                    Err(tokio::sync::broadcast::error::RecvError::Lagged(_)) => {
                        // If lagged, just continue reading
                    }
                }
            }
        });
    }

    /// Spawns the console broadcaster for a VM: reads guest serial output
    /// from the console fd and fans it out to the scrollback buffer and
    /// subscribers. For the Socket transport the broadcaster is
    /// SELF-HEALING: whenever the current connection ends it reconnects
    /// to the listener at the same path, swaps the stored `console_io`
    /// for the live endpoint, and keeps streaming. Connection cycles
    /// arise in two ways: (a) the cloud-hypervisor process dies — every
    /// descriptor it held closes and the reader observes a genuine EOF;
    /// (b) `vm.reboot` tears the VM down and re-creates it, re-binding
    /// the serial listener at the same path — v43's serial manager leaks
    /// the accepted descriptor at thread exit (it is handed to epoll via
    /// `into_raw_fd()` and never closed), so the old connection delivers
    /// neither data nor EOF and `reboot_vm` force-rotates it with
    /// `shutdown(SHUT_RD)` to produce the EOF this loop reacts to. The
    /// VMM-side connection replacement also plays a role: the serial
    /// manager shuts its previous client down when a new one connects, so
    /// reconnecting clients are always the live endpoint. Console capture
    /// therefore survives reboots and VMM death without lifecycle-path
    /// coupling. The Pty transport exits on EOF instead (a reboot
    /// allocates a NEW pty at a different path; re-attachment is a
    /// recorded follow-up) and revival is left to the next `start_vm`
    /// respawn.
    ///
    /// Each connection cycle's reads run on a dedicated blocking-pool
    /// thread ([`Self::drain_console_endpoint`], issue #469): the drain
    /// loop issues back-to-back blocking reads with no inter-read
    /// awaits, which is what lets a v53.0 flush session push the whole
    /// pre-connect backlog in one pass instead of stalling after ~one
    /// socket-fill (the #8322 defect — see that fn's doc comment). The
    /// async task below owns the connection lifecycle only: it parks on
    /// the drain's completion and runs the reconnect/heal bookkeeping
    /// between cycles, exactly as before.
    #[allow(clippy::too_many_arguments)]
    fn spawn_pty_broadcaster(
        vms: Arc<tokio::sync::RwLock<HashMap<String, VmProcess>>>,
        vm_id: String,
        pty_fd: OwnedFd,
        transport: SerialTransport,
        pty_tx: tokio::sync::broadcast::Sender<Vec<u8>>,
        pty_scrollback: Arc<std::sync::RwLock<Vec<u8>>>,
        broadcaster_alive: Arc<AtomicBool>,
        console_draining: Arc<AtomicBool>,
    ) {
        tokio::spawn(async move {
            let _guard = AliveGuard(broadcaster_alive);
            // The canonical console endpoint this broadcaster reads from;
            // the heal path replaces it with the fresh connection.
            let mut current = pty_fd;
            loop {
                // Each connection cycle gets its own dup of `current` for
                // its reader; dropping the cycle's reader closes that dup
                // (and with it the old connection) when the cycle ends.
                let cycle_fd = match Self::dup_cloexec(&current) {
                    Ok(d) => d,
                    Err(_) => break,
                };
                // Drain the cycle on a dedicated blocking-pool thread:
                // the loop inside never awaits, so the socket is re-read
                // the instant data lands (see `drain_console_endpoint`).
                // A panic inside the drain loop ends the broadcaster —
                // the same end state the old in-task read loop panicking
                // produced (AliveGuard drops; the next start_vm respawns).
                let drain_tx = pty_tx.clone();
                let drain_scrollback = pty_scrollback.clone();
                let drained = tokio::task::spawn_blocking(move || {
                    Self::drain_console_endpoint(cycle_fd, &drain_tx, &drain_scrollback)
                })
                .await;
                if drained.is_err() {
                    break;
                }
                // Endpoint lost. Socket transport: re-establish the
                // connection (bounded retry — the VMM re-binds the
                // listener within the same API call that closed the old
                // one), swap the stored endpoint, and keep streaming.
                // Anything else (reconnect exhausted, VM left the map,
                // Pty transport) ends the broadcaster.
                match transport {
                    SerialTransport::Socket(ref path) => {
                        // Graceful agent shutdown: stand down instead of
                        // minting a connection that process exit would
                        // abortively close (see `drain_and_close_consoles`).
                        if console_draining.load(Ordering::SeqCst) {
                            break;
                        }
                        match Self::reconnect_serial_socket(path, &console_draining).await {
                            Some(fresh) => {
                                let next = match Self::dup_cloexec(&fresh) {
                                    Ok(d) => d,
                                    Err(e) => {
                                        warn!(
                                            vm_id = %vm_id,
                                            error = %e,
                                            "serial heal dup failed; abandoning the fresh connection"
                                        );
                                        Self::abandon_serial_connection(&vm_id, fresh, None).await;
                                        break;
                                    }
                                };
                                let mut map = vms.write().await;
                                // Post-lock double check of the shutdown
                                // latch: the drain hook holds this lock
                                // across its passes — if it latched while
                                // this heal was connecting, abandon the
                                // fresh connection cleanly and exit rather
                                // than let process exit abortively close
                                // it.
                                if console_draining.load(Ordering::SeqCst) {
                                    drop(map);
                                    drop(next);
                                    Self::abandon_serial_connection(&vm_id, fresh, None).await;
                                    break;
                                }
                                match map.get_mut(&vm_id) {
                                    Some(proc) => {
                                        // Supersede check: a VMM re-spawn or
                                        // re-adoption replaces the map entry
                                        // (fresh channel, fresh broadcaster).
                                        // If this entry's channel is no
                                        // longer ours, a replacement
                                        // broadcaster owns the console now —
                                        // exit instead of swapping endpoints
                                        // under it. This also drops the last
                                        // Sender of the old channel, so the
                                        // old console.log writer observes
                                        // Closed and exits (no duplicate
                                        // appends). The fresh connection is
                                        // abandoned CLEANLY — dropping it
                                        // with unread receive-queue data
                                        // would reset the connection and
                                        // can kill the (new) serial manager
                                        // (see `abandon_serial_connection`).
                                        if !proc.pty_tx.same_channel(&pty_tx) {
                                            let (tx, sb) =
                                                (proc.pty_tx.clone(), proc.pty_scrollback.clone());
                                            drop(map);
                                            drop(next);
                                            Self::abandon_serial_connection(
                                                &vm_id,
                                                fresh,
                                                Some((&tx, &sb)),
                                            )
                                            .await;
                                            break;
                                        }
                                        proc.console_io = fresh;
                                    }
                                    None => {
                                        // The VM left the map (force stop /
                                        // delete) — the VMM is being torn
                                        // down, but abandon cleanly anyway:
                                        // the same listener can already
                                        // belong to a replacement VM.
                                        drop(map);
                                        drop(next);
                                        Self::abandon_serial_connection(&vm_id, fresh, None).await;
                                        break;
                                    }
                                }
                                drop(map);
                                current = next;
                                continue;
                            }
                            None => break,
                        }
                    }
                    SerialTransport::Pty => break,
                }
            }
            tracing::debug!(vm_id = %vm_id, "pty broadcaster exited");
        });
    }

    /// Re-spawns the cloud-hypervisor process for a tracked VM whose VMM
    /// has exited, then re-creates and boots the VM from the payload
    /// persisted at create time. cloud-hypervisor v43 exits with the
    /// guest (VMM control-loop Exit dispatch → `vmm_shutdown`), so a
    /// start after a graceful stop has no daemon to `vm.boot` against —
    /// the start contract ("make the VM running") is honored by
    /// rebuilding the process. Mirrors `create_vm`'s post-spawn tail:
    /// fail-closed child guard, fresh console endpoint, fresh fan-out
    /// channel; console.log is APPENDED (the stop path already truncated
    /// it by design, and a crash leaves boot history worth keeping).
    async fn respawn_vmm(&self, vm_id: &str, operation_id: Option<&str>) -> Result<(), ChvError> {
        let (api_socket, serial_transport) = {
            let vms = self.vms.read().await;
            let proc = vms.get(vm_id).ok_or_else(|| ChvError::NotFound {
                resource: "vm".to_string(),
                id: vm_id.to_string(),
            })?;
            (proc.api_socket.clone(), proc.serial_transport.clone())
        };
        let vm_dir = api_socket
            .parent()
            .expect("api socket path must have a parent directory")
            .to_path_buf();

        // Stale sockets from an unclean VMM death would fail both binds
        // (api socket, serial listener). Only ever files this adapter
        // owns.
        let _ = tokio::fs::remove_file(&api_socket).await;
        let _ = tokio::fs::remove_file(vm_dir.join("serial.sock")).await;

        let config_path = vm_config_file(&vm_dir);
        let body = tokio::fs::read_to_string(&config_path).await.map_err(|e| {
            ChvError::Internal {
                reason: format!(
                    "cannot restart vm {}: no persisted cloud-hypervisor config at {} ({}); re-create the VM",
                    vm_id,
                    config_path.display(),
                    e
                ),
            }
        })?;

        let mut cmd = tokio::process::Command::new(&self.chv_binary);
        cmd.arg("--api-socket").arg(&api_socket);
        cmd.stdout(Stdio::null());
        let stderr_log_path = vm_dir.join("cloud-hypervisor.stderr.log");
        match std::fs::OpenOptions::new()
            .create(true)
            .append(true)
            .open(&stderr_log_path)
        {
            Ok(f) => {
                cmd.stderr(Stdio::from(f));
            }
            Err(_) => {
                cmd.stderr(Stdio::null());
            }
        }

        info!(
            vm_id = %vm_id,
            socket = %api_socket.display(),
            binary = %self.chv_binary.display(),
            op = operation_id.unwrap_or("-"),
            "re-spawning cloud-hypervisor for stopped vm"
        );
        let child = cmd.spawn().map_err(|e| ChvError::Io {
            path: self.chv_binary.to_string_lossy().to_string(),
            source: e,
        })?;
        // Same cancellation discipline as create_vm: the armed guard
        // SIGKILLs the child if this future is dropped before the map
        // hand-off.
        let mut child = ChildGuard::new(child);
        if let Some(pid) = child.id() {
            let _ = std::fs::write(vm_pid_file(&vm_dir), format!("{pid}"));
        }

        if let Err(e) = Self::wait_for_socket(&api_socket, std::time::Duration::from_secs(10)).await
        {
            let _ = child.start_kill();
            let _ = child.wait().await;
            let stderr_hint = read_stderr_tail(&stderr_log_path);
            return Err(ChvError::Internal {
                reason: format!(
                    "failed to re-start cloud-hypervisor for vm {}: {} stderr: {}",
                    vm_id, e, stderr_hint
                ),
            });
        }
        if let Ok(Some(exit_status)) = child.try_wait() {
            let stderr_hint = read_stderr_tail(&stderr_log_path);
            return Err(ChvError::Internal {
                reason: format!(
                    "cloud-hypervisor exited immediately for vm {} re-spawn with {}: {}",
                    vm_id, exit_status, stderr_hint
                ),
            });
        }

        let (create_status, create_body) =
            Self::ch_api_request_with_body(&api_socket, "PUT", "/api/v1/vm.create", Some(&body))
                .await?;
        if create_status != 200 && create_status != 204 {
            let _ = child.start_kill();
            let _ = child.wait().await;
            return Err(ChvError::Internal {
                reason: format!(
                    "vm.create returned status {} for vm {} re-spawn: {}",
                    create_status, vm_id, create_body
                ),
            });
        }

        // Fresh console endpoint on the new VMM. Socket transport
        // reconnects to the listener vm.create just bound; Pty transport
        // opens the new pty slave reported by vm.info. Both fail closed
        // (the child is killed) exactly like the create path.
        let console_io: OwnedFd = match &serial_transport {
            SerialTransport::Socket(path) => {
                Self::connect_serial_socket(path, &mut child, vm_id, operation_id).await?
            }
            SerialTransport::Pty => {
                Self::open_serial_pty(&api_socket, &mut child, vm_id, operation_id).await?
            }
        };

        let (pty_tx, _) = tokio::sync::broadcast::channel::<Vec<u8>>(4096);
        let pty_scrollback = Arc::new(std::sync::RwLock::new(Vec::new()));
        let broadcaster_fd = Self::dup_cloexec(&console_io).ok();
        // Claim capture alive only when a broadcaster will actually run.
        let broadcaster_alive = Arc::new(AtomicBool::new(broadcaster_fd.is_some()));

        // Hand-off under the write lock with no intervening await, then
        // swap the entry: the replaced entry's fan-out channel closes
        // (the old console.log writer and any lingering broadcaster exit),
        // and lifecycle ownership moves to the new child. The boot
        // watermark pins where THIS VMM generation's output starts: the
        // re-spawn appends to the existing console.log, and everything
        // before this offset is the dead generation's boot — the boot
        // watchdog must not accept its kernel banner or boot-complete
        // marker as evidence for the new boot.
        let boot_watermark = std::fs::metadata(vm_console_log(&vm_dir))
            .map(|m| m.len())
            .unwrap_or(0);
        let mut map = self.vms.write().await;
        let child = child.disarm();
        map.insert(
            vm_id.to_string(),
            VmProcess {
                api_socket: api_socket.clone(),
                child: VmmChild::Owned(child),
                console_io,
                serial_transport: serial_transport.clone(),
                pty_tx: pty_tx.clone(),
                pty_scrollback: pty_scrollback.clone(),
                broadcaster_alive: broadcaster_alive.clone(),
                last_cpu_seconds: 0.0,
                last_cpu_at: None,
                boot_watermark: AtomicU64::new(boot_watermark),
            },
        );
        drop(map);

        if let Some(broadcaster_fd) = broadcaster_fd {
            Self::spawn_pty_broadcaster(
                self.vms.clone(),
                vm_id.to_string(),
                broadcaster_fd,
                serial_transport,
                pty_tx.clone(),
                pty_scrollback.clone(),
                broadcaster_alive,
                self.console_draining.clone(),
            );
        }
        Self::spawn_console_log_writer(
            vm_id,
            &pty_tx,
            vm_console_log(&vm_dir),
            ConsoleLogMode::Append,
        );

        let status = Self::ch_api_request(&api_socket, "PUT", "/api/v1/vm.boot", None).await?;
        if status != 200 && status != 204 {
            warn!(vm_id = %vm_id, status = status, "vm.boot returned non-success after re-spawn (VM may have auto-booted)");
        }
        Ok(())
    }

    /// Lock-free core of [`Self::reboot_vm`]: the caller must already
    /// hold the per-VM lifecycle lock. `start_vm`'s #409 serial heal
    /// calls this directly — it holds the same (non-reentrant) mutex and
    /// must not deadlock against itself.
    async fn reboot_vm_locked(
        &self,
        vm_id: &str,
        operation_id: Option<&str>,
    ) -> Result<(), ChvError> {
        let api_socket = self.get_vm_socket(vm_id).await?;

        info!(vm_id = %vm_id, op = operation_id.unwrap_or("-"), "rebooting vm via ch api");

        // Snapshot the pre-reboot console connection BEFORE the API call.
        // cloud-hypervisor v43's vm.reboot tears the VM down and re-creates
        // it, re-binding the serial listener at the same path — but the OLD
        // accepted connection is orphaned without EOF: the serial manager's
        // accept path hands its descriptor to epoll via `into_raw_fd()` and
        // never closes it, so the broadcaster parked on it would never wake.
        // The forced EOF must land on exactly this connection — the one
        // that predates the reboot — not on whatever a concurrent heal may
        // have swapped into the map meanwhile, so a dup is taken up front:
        // it pins the open file description, making the raw fd impossible
        // to recycle under us. Socket transport only (the pty transport
        // has no socket to shut down; its reboot behavior is a recorded
        // follow-up).
        let pre_reboot_console: Option<OwnedFd> = {
            let vms = self.vms.read().await;
            match vms.get(vm_id) {
                Some(proc) if matches!(proc.serial_transport, SerialTransport::Socket(_)) => {
                    Self::dup_cloexec(&proc.console_io).ok()
                }
                _ => None,
            }
        };

        let status = Self::ch_api_request(&api_socket, "PUT", "/api/v1/vm.reboot", None).await?;
        if status == 0 {
            warn!(
                vm_id = %vm_id,
                "unparseable response from vm.reboot; serial connection not rotated"
            );
            return Ok(());
        }
        if status != 200 && status != 204 {
            warn!(status = status, "unexpected status from vm.reboot");
            return Ok(());
        }
        // A successful vm.reboot starts a NEW boot in the same VMM: bump
        // the entry's boot watermark to the console capture's current
        // size so the boot watchdog scopes its banner/marker evidence to
        // the new boot — the pre-reboot boot's marker must not satisfy
        // the new boot's completion check (the capture keeps appending
        // across a reboot; only a fresh kernel banner after this offset
        // counts).
        {
            let vms = self.vms.read().await;
            if let Some(proc) = vms.get(vm_id) {
                if let Some(vm_dir) = proc.api_socket.parent() {
                    let watermark = std::fs::metadata(vm_console_log(vm_dir))
                        .map(|m| m.len())
                        .unwrap_or(0);
                    proc.boot_watermark.store(watermark, Ordering::SeqCst);
                }
            }
        }
        // A successful vm.reboot re-bound the listener; rotate the pinned
        // connection. shutdown(2) acts on the open file description, so it
        // wakes every blocked reader on it (the broadcaster's dup
        // included): the broadcaster observes EOF and its self-heal
        // reconnects to the re-bound listener, swapping the stored
        // endpoint and streaming the new boot. Queued bytes are NOT
        // discarded by SHUT_RD (reads still drain them, then EOF), and
        // the subsequent close of the rotated descriptors is clean even
        // with data queued — SHUT_RD neutralizes the reset-on-close
        // heuristic. It does make the peer's writes fail EPIPE while the
        // connection is nominally open, which is exactly why SHUT_RD is
        // used ONLY here, on a connection whose VMM peer is already torn
        // down by the reboot — never on a live connection (see
        // `abandon_serial_connection`). Best-effort: a failure means the
        // connection was already gone, which the broadcaster's own EOF
        // handling covers.
        if let Some(fd) = pre_reboot_console {
            if let Err(e) =
                nix::sys::socket::shutdown(fd.as_raw_fd(), nix::sys::socket::Shutdown::Read)
            {
                warn!(
                    vm_id = %vm_id,
                    error = %e,
                    "serial read-side shutdown after vm.reboot failed"
                );
            }
        }
        Ok(())
    }

    /// Issue-#409 self-heal, driven from `start_vm`'s idempotent
    /// already-running path: an ADOPTED VM (a live VMM this agent
    /// re-attached to after a restart) whose cloud-hypervisor
    /// serial-manager thread is PROVABLY gone has a console path no
    /// agent-side fd work can revive — the serial listener stays bound
    /// but is never accepted again, and the guest's UART writes fail
    /// EPIPE (with the THRE interrupt suppressed, a booting guest wedges
    /// half-up while `vm.info` keeps reporting Running). The only
    /// remediation is VMM-level: `vm.reboot` tears the VM down and
    /// re-creates it with a fresh serial manager, re-binding the
    /// listener; the rotation in `reboot_vm_locked` then forces the
    /// parked broadcaster onto the new connection.
    ///
    /// Safety gates — every one must hold before a reboot is issued:
    /// - `Adopted` entry only: a tracked (`Owned`) VM's console path has
    ///   been this agent's own since spawn and cannot be wedged by the
    ///   adoption race this heals;
    /// - Socket transport only (the Pty transport has no serial-manager
    ///   thread at all);
    /// - the serial-manager thread's absence is PROVEN (`Some(false)`):
    ///   an unreadable `/proc` (`None`) or a live thread is a no-op, so
    ///   adopting a VM with a live console stays a pure no-op;
    /// - at most ONE remediation reboot per VMM generation per agent
    ///   process (`serial_heal_reboots`), bounding a stale-detection
    ///   false positive to a single guest restart.
    ///
    /// A failed remediation is logged, never fatal: the VM is running
    /// and `start_vm`'s contract ("make the VM running") is already
    /// satisfied — failing the op's RED metrics over a console heal
    /// would misreport a healthy lifecycle result.
    async fn heal_dead_serial_manager(&self, vm_id: &str, operation_id: Option<&str>) {
        let pid = {
            let vms = self.vms.read().await;
            let Some(proc) = vms.get(vm_id) else {
                return;
            };
            match (&proc.child, &proc.serial_transport) {
                (VmmChild::Adopted(pid), SerialTransport::Socket(_)) => *pid,
                _ => return,
            }
        };
        if *self
            .serial_heal_reboots
            .lock()
            .expect("serial heal lock poisoned")
            .get(vm_id)
            .unwrap_or(&0)
            == pid
        {
            return;
        }
        match vmm_serial_manager_thread_alive(pid) {
            Some(true) => {}
            None => {
                warn!(
                    vm_id = %vm_id,
                    pid = pid,
                    "cannot prove whether the adopted vm's serial-manager thread is alive; leaving the console path untouched"
                );
            }
            Some(false) => {
                warn!(
                    vm_id = %vm_id,
                    pid = pid,
                    op = operation_id.unwrap_or("-"),
                    "adopted vm's serial-manager thread is gone (dead console path, issue #409); rebooting the vm to restore console capture"
                );
                match self.reboot_vm_locked(vm_id, operation_id).await {
                    Ok(()) => {
                        // Mark only after the reboot was issued: a
                        // transport-level failure leaves the budget
                        // unspent so the next start_vm can retry (a
                        // failed request is harmless — no guest restart
                        // happened), while a completed one stops the
                        // reconciler from ever repeating it for this
                        // VMM generation.
                        self.serial_heal_reboots
                            .lock()
                            .expect("serial heal lock poisoned")
                            .insert(vm_id.to_string(), pid);
                        info!(
                            vm_id = %vm_id,
                            pid = pid,
                            "serial-heal reboot issued for the adopted vm; console capture should resume on the new boot"
                        );
                    }
                    Err(e) => {
                        warn!(
                            vm_id = %vm_id,
                            error = %e,
                            "serial-heal reboot failed; the vm keeps running with console capture down (retried on the next start_vm)"
                        );
                    }
                }
            }
        }
    }
}

/// What `start_vm` should do for a VM whose `vm.info` reported `state`.
///
/// Both `Running` and `Paused` map to an idempotent no-op: a paused VM is
/// deliberately left paused. The migration path owns resume-after-pause (see
/// `PausedVmGuard` in chv-agent-core), and user-initiated pauses must survive
/// the reconciler's periodic `start_vm` calls.
enum StartVmAction {
    /// VM is already running (or deliberately paused): idempotent no-op.
    AlreadyRunning,
    /// Any other state: boot the VM.
    Boot,
}

fn start_vm_action(state: &str) -> StartVmAction {
    match state {
        "Running" | "Paused" => StartVmAction::AlreadyRunning,
        _ => StartVmAction::Boot,
    }
}

#[async_trait]
impl CloudHypervisorAdapter for ProcessCloudHypervisorAdapter {
    async fn create_vm(
        &self,
        config: &VmConfig,
        operation_id: Option<&str>,
    ) -> Result<String, ChvError> {
        let mut __guard = VmOpGuard::new("create");
        // Serialize with the other lifecycle ops for this VM (see
        // `lifecycle_locks`): a concurrent stop/delete/start while this
        // create runs must not interleave process spawns and socket
        // cleanups for the same runtime dir.
        let _lifecycle = self.vm_op_lock(&config.vm_id).lock_owned().await;
        if !std::path::Path::new("/dev/kvm").exists() {
            return Err(ChvError::Internal {
                reason: "Host does not have KVM capability (/dev/kvm missing). VMs require hardware virtualization.".into(),
            });
        }
        self.validate_vm_config(config)?;
        self.ensure_no_live_vmm(config).await?;
        if config.api_socket_path.exists() {
            tokio::fs::remove_file(&config.api_socket_path)
                .await
                .map_err(|e| ChvError::Io {
                    path: config.api_socket_path.to_string_lossy().to_string(),
                    source: e,
                })?;
        }
        // A SIGKILLed VMM leaves its serial socket file behind (clean exit
        // removes it); a stale file would make cloud-hypervisor's
        // `vm.create` listener bind fail with EADDRINUSE. Best-effort: the
        // file can only exist when no live VMM owns it.
        if let Some(vm_dir) = config.api_socket_path.parent() {
            let _ = tokio::fs::remove_file(vm_dir.join("serial.sock")).await;
        }

        let mut cmd = tokio::process::Command::new(&self.chv_binary);
        cmd.arg("--api-socket").arg(&config.api_socket_path);

        let vm_runtime_dir = config
            .api_socket_path
            .parent()
            .expect("api_socket_path must have a parent directory");

        // Ensure the VM runtime directory exists so CHV can create its API socket
        // and we can capture stderr logs even when cloud-init seeding is skipped.
        if let Err(e) = tokio::fs::create_dir_all(vm_runtime_dir).await {
            warn!(vm_id = %config.vm_id, error = %e, path = %vm_runtime_dir.display(), "failed to create vm runtime dir");
        }

        // Build cloud-init seed ISO for every VM that has NICs or explicit userdata.
        // The ISO carries the control-plane-assigned static IP configuration so
        // cloud-init images (e.g. Ubuntu cloud images) come up on the correct network.
        let has_nics = !config.nics.is_empty();
        let has_userdata = config
            .cloud_init_userdata
            .as_ref()
            .map(|s| !s.trim().is_empty())
            .unwrap_or(false);
        let seed_iso_path = if has_nics || has_userdata {
            let userdata = config.cloud_init_userdata.as_deref();
            match build_cloud_init_seed(vm_runtime_dir, &config.vm_id, userdata, &config.nics).await
            {
                Ok(path) => Some(path),
                Err(e) => {
                    warn!(vm_id = %config.vm_id, error = %e, "failed to build cloud-init seed ISO, continuing without it");
                    None
                }
            }
        } else {
            None
        };

        cmd.stdout(Stdio::null());

        let stderr_log_path = vm_runtime_dir.join("cloud-hypervisor.stderr.log");
        let stderr_file = std::fs::OpenOptions::new()
            .create(true)
            .append(true)
            .open(&stderr_log_path);
        match stderr_file {
            Ok(f) => {
                cmd.stderr(Stdio::from(f));
            }
            Err(e) => {
                warn!(error = %e, path = %stderr_log_path.display(), "failed to open stderr log, falling back to null");
                cmd.stderr(Stdio::null());
            }
        }

        // Build VM config JSON and create VM via REST API (supports multiple disks)
        let mut disks_json = Vec::new();
        for disk in &config.disks {
            let mut disk_obj = serde_json::Map::new();
            disk_obj.insert(
                "path".into(),
                serde_json::Value::from(disk.path.to_string_lossy().to_string()),
            );
            if disk.read_only {
                disk_obj.insert("readonly".into(), serde_json::Value::from(true));
            }
            let image_type = if disk.path.extension().map(|e| e == "qcow2").unwrap_or(false) {
                "Qcow2"
            } else {
                "Raw"
            };
            disk_obj.insert("image_type".into(), serde_json::Value::from(image_type));
            disks_json.push(serde_json::Value::Object(disk_obj));
        }
        if let Some(ref seed_path) = seed_iso_path {
            let mut disk_obj = serde_json::Map::new();
            disk_obj.insert(
                "path".into(),
                serde_json::Value::from(seed_path.to_string_lossy().to_string()),
            );
            disk_obj.insert("readonly".into(), serde_json::Value::from(true));
            disk_obj.insert("image_type".into(), serde_json::Value::from("Raw"));
            disks_json.push(serde_json::Value::Object(disk_obj));
        }

        let mut net_json = Vec::new();
        for nic in &config.nics {
            if nic.tap_name.is_empty() {
                warn!(mac = %nic.mac_address, "skipping NIC with empty tap_name");
                continue;
            }
            let mut net_obj = serde_json::Map::new();
            net_obj.insert(
                "mac".into(),
                serde_json::Value::from(nic.mac_address.clone()),
            );
            net_obj.insert("tap".into(), serde_json::Value::from(nic.tap_name.clone()));
            net_json.push(serde_json::Value::Object(net_obj));
        }

        let mut payload = serde_json::Map::new();
        if let Some(ref fw) = config.firmware_path {
            payload.insert(
                "firmware".into(),
                serde_json::Value::from(fw.to_string_lossy().to_string()),
            );
        } else {
            payload.insert(
                "kernel".into(),
                serde_json::Value::from(config.kernel_path.to_string_lossy().to_string()),
            );
        }

        let hv = config.hypervisor_overrides.as_ref();

        let cpus = build_cpus_config(config);

        let mut memory = serde_json::json!({ "size": config.memory_bytes });
        if let Some(v) = hv.and_then(|h| h.memory_mergeable) {
            memory["mergeable"] = serde_json::json!(v);
        }
        if let Some(v) = hv.and_then(|h| h.memory_hugepages) {
            memory["hugepages"] = serde_json::json!(v);
        }
        if let Some(v) = hv.and_then(|h| h.memory_shared) {
            memory["shared"] = serde_json::json!(v);
        }
        if let Some(v) = hv.and_then(|h| h.memory_prefault) {
            memory["prefault"] = serde_json::json!(v);
        }

        // Serial transport: cloud-hypervisor v43 gates Pty-mode output
        // until input arrives on the pty (vmm/src/serial_manager.rs starts
        // the serial output gate closed and only an epoll input event on
        // the pty master opens it), so a passive consumer — exactly what
        // the agent's console capture is — receives nothing and console.log
        // stays empty forever. Socket mode streams output to a connected
        // unix-stream client with no gate, so it is the default transport
        // (DEFAULT_SERIAL_MODE, shared with the control plane's global
        // hypervisor settings); an explicit serial_mode tuning is still
        // honored (with the Pty gate semantics that mode implies).
        let serial_mode = hv
            .and_then(|h| h.serial_mode.as_deref())
            .unwrap_or(chv_common::hypervisor::DEFAULT_SERIAL_MODE);
        let console_mode = hv.and_then(|h| h.console_mode.as_deref()).unwrap_or("Off");
        let serial_socket_path = vm_runtime_dir.join("serial.sock");
        let serial_json = Self::serial_console_config(serial_mode, &serial_socket_path);

        let mut vm_config_json = serde_json::json!({
            "cpus": cpus,
            "memory": memory,
            "payload": payload,
            "disks": disks_json,
            "net": net_json,
            "serial": serial_json,
            "console": { "mode": console_mode },
        });

        if let Some(true) = hv.and_then(|h| h.cpu_kvm_hyperv) {
            vm_config_json["platform"] = serde_json::json!({ "kvm_hyperv": true });
        }
        if let Some(v) = hv.and_then(|h| h.iommu) {
            vm_config_json["iommu"] = serde_json::json!(v);
        }
        if let Some(v) = hv.and_then(|h| h.watchdog) {
            vm_config_json["watchdog"] = serde_json::json!(v);
        }
        if let Some(v) = hv.and_then(|h| h.pvpanic) {
            vm_config_json["pvpanic"] = serde_json::json!(v);
        }
        if let Some(v) = hv.and_then(|h| h.landlock_enable) {
            vm_config_json["landlock"] = serde_json::json!(v);
        }
        if let Some(ref src) = hv.and_then(|h| h.rng_src.as_ref()) {
            vm_config_json["rng"] = serde_json::json!({ "src": src });
        }
        if let Some(ref tpm_type) = hv.and_then(|h| h.tpm_type.as_ref()) {
            let tpm_socket = hv
                .and_then(|h| h.tpm_socket_path.as_ref())
                .cloned()
                .unwrap_or_else(|| {
                    vm_runtime_dir
                        .join("tpm.sock")
                        .to_string_lossy()
                        .to_string()
                });
            vm_config_json["tpm"] = serde_json::json!({
                "type": tpm_type,
                "socket": tpm_socket,
            });
        }

        let body = vm_config_json.to_string();

        info!(
            vm_id = %config.vm_id,
            socket = %config.api_socket_path.display(),
            binary = %self.chv_binary.display(),
            op = operation_id.unwrap_or("-"),
            "spawning cloud-hypervisor"
        );

        let child = cmd.spawn().map_err(|e| ChvError::Io {
            path: self.chv_binary.to_string_lossy().to_string(),
            source: e,
        })?;
        // Close the orphan window: `child` is not yet registered in the vm
        // process map, and several awaits separate this spawn from the
        // registration. If an async cancellation (e.g. the core executor's
        // bounded-drain abort) drops this future mid-way, the child must not
        // survive as an unaccounted VMM — the armed `ChildGuard` SIGKILLs it.
        // It is disarmed immediately before the child is handed to the vm
        // process map, which then owns lifecycle.
        let mut child = ChildGuard::new(child);

        // Persist BOTH the VMM pid and the exact vm.create payload BEFORE
        // any await toward the API: the window between spawn and create
        // success is precisely where an agent crash would otherwise strand
        // a VM that adoption can see but start can never re-create (the
        // payload is what `respawn_vmm` needs). Writing the pid before the
        // VM exists trades a small, manageable misclassification — a crash
        // between spawn and vm.create adopts a live VMM with no VM inside,
        // where stop treats it as stopped and delete reaps it by identity —
        // for full coverage of the much larger window. Both writes are
        // best-effort with a warning: without the pidfile, adoption of
        // this VM is skipped; without the config, a later start degrades
        // to a clear re-create-required error.
        if let Some(pid) = child.id() {
            let _ = std::fs::write(vm_pid_file(vm_runtime_dir), format!("{pid}"));
        }
        if let Err(e) = std::fs::write(vm_config_file(vm_runtime_dir), &body) {
            warn!(
                vm_id = %config.vm_id,
                error = %e,
                "failed to persist vm-config.json; vm restart after a VMM exit will require re-create"
            );
        }

        if let Err(e) =
            Self::wait_for_socket(&config.api_socket_path, std::time::Duration::from_secs(10)).await
        {
            let _ = child.start_kill();
            let _ = child.wait().await;
            let stderr_hint = read_stderr_tail(&stderr_log_path);
            warn!(
                vm_id = %config.vm_id,
                stderr = %stderr_hint,
                "cloud-hypervisor failed to create api socket within 10s"
            );
            return Err(ChvError::Internal {
                reason: format!(
                    "failed to start cloud-hypervisor for vm {}: {} stderr: {}",
                    config.vm_id, e, stderr_hint
                ),
            });
        }

        if let Ok(Some(exit_status)) = child.try_wait() {
            let stderr_hint = read_stderr_tail(&stderr_log_path);
            let _ = tokio::fs::remove_file(&config.api_socket_path).await;
            return Err(ChvError::Internal {
                reason: format!(
                    "cloud-hypervisor exited immediately for vm {} with {}: {}",
                    config.vm_id, exit_status, stderr_hint
                ),
            });
        }

        let (create_status, create_body) = Self::ch_api_request_with_body(
            &config.api_socket_path,
            "PUT",
            "/api/v1/vm.create",
            Some(&body),
        )
        .await?;

        if create_status != 200 && create_status != 204 {
            let _ = child.start_kill();
            let _ = child.wait().await;
            let _ = tokio::fs::remove_file(&config.api_socket_path).await;
            return Err(ChvError::Internal {
                reason: format!(
                    "vm.create returned status {} for vm {}: {}",
                    create_status, config.vm_id, create_body
                ),
            });
        }

        // Acquire the guest serial-console I/O endpoint — guest output is
        // read from it and user keystrokes are written to it. Socket mode
        // (the default) connects to the unix listener cloud-hypervisor
        // bound while creating the VM; Pty mode (explicit tuning only)
        // opens the pty slave cloud-hypervisor allocated and reported in
        // vm.info. Both helpers fail closed: on error they kill the
        // spawned child so a console-less VM is never left running.
        let console_io: OwnedFd = if serial_mode == chv_common::hypervisor::DEFAULT_SERIAL_MODE {
            Self::connect_serial_socket(
                &serial_socket_path,
                &mut child,
                &config.vm_id,
                operation_id,
            )
            .await?
        } else {
            Self::open_serial_pty(
                &config.api_socket_path,
                &mut child,
                &config.vm_id,
                operation_id,
            )
            .await?
        };

        let (pty_tx, _) = tokio::sync::broadcast::channel::<Vec<u8>>(4096);
        let pty_scrollback = Arc::new(std::sync::RwLock::new(Vec::new()));
        let serial_transport = if serial_mode == chv_common::hypervisor::DEFAULT_SERIAL_MODE {
            SerialTransport::Socket(serial_socket_path.clone())
        } else {
            SerialTransport::Pty
        };

        // Duplicate the descriptor for the broadcaster while retaining the
        // owned console descriptor for the VM process map.
        let broadcaster_fd = Self::dup_cloexec(&console_io).ok();
        // Claim capture alive only when a broadcaster will actually run.
        let broadcaster_alive = Arc::new(AtomicBool::new(broadcaster_fd.is_some()));

        // Acquire the vm-process-map lock while the guard is still armed so a
        // cancellation landing on this await still SIGKILLs the child; then
        // disarm and insert with no intervening await. From here the map owns
        // lifecycle (stop/delete call start_kill explicitly) and a normal drop
        // of a registered VmProcess (e.g. runtime teardown) does not SIGKILL a
        // VM that is deliberately left running.
        let mut map = self.vms.write().await;
        let child = child.disarm();
        map.insert(
            config.vm_id.clone(),
            VmProcess {
                api_socket: config.api_socket_path.clone(),
                child: VmmChild::Owned(child),
                // The guest serial-console I/O fd: a unix-stream socket to
                // cloud-hypervisor's serial listener by default (Socket
                // transport), or the pty slave under explicit Pty tuning.
                console_io,
                serial_transport: serial_transport.clone(),
                pty_tx: pty_tx.clone(),
                pty_scrollback: pty_scrollback.clone(),
                broadcaster_alive: broadcaster_alive.clone(),
                last_cpu_seconds: 0.0,
                last_cpu_at: None,
                boot_watermark: AtomicU64::new(0),
            },
        );
        drop(map);

        // Spawn background broadcaster: read PTY output and fan out via broadcast channel
        if let Some(broadcaster_fd) = broadcaster_fd {
            Self::spawn_pty_broadcaster(
                self.vms.clone(),
                config.vm_id.clone(),
                broadcaster_fd,
                serial_transport,
                pty_tx.clone(),
                pty_scrollback.clone(),
                broadcaster_alive.clone(),
                self.console_draining.clone(),
            );
        }

        // Subscribe to broadcast channel and persist to console.log
        Self::spawn_console_log_writer(
            &config.vm_id,
            &pty_tx,
            vm_console_log(vm_runtime_dir),
            ConsoleLogMode::Fresh,
        );

        __guard.succeeded = true;
        Ok(config.vm_id.clone())
    }

    async fn start_vm(&self, vm_id: &str, operation_id: Option<&str>) -> Result<(), ChvError> {
        let mut __guard = VmOpGuard::new("start");
        // Serialize with the other lifecycle ops for this VM (see
        // `lifecycle_locks`): two concurrent starts over an exited VMM
        // must never both re-spawn a process for it.
        let _lifecycle = self.vm_op_lock(vm_id).lock_owned().await;

        // cloud-hypervisor v43 exits when the guest exits (VMM control
        // loop Exit dispatch → vmm_shutdown), so a start after a graceful
        // stop — or any guest-side poweroff — has no daemon to boot
        // against. The start contract is "make the VM running": re-spawn
        // the VMM and re-create the VM from the payload persisted at
        // create time instead of failing on a dead api socket. Liveness
        // is proven, not assumed: an indeterminate probe result refuses
        // the re-spawn (a second VMM on one disk is never acceptable)
        // with an error the caller can retry.
        //
        // Force-stop residual: the force paths remove the in-memory
        // entry while the persisted payload survives on disk. Re-derive
        // the entry from the shared layout first so the start completes
        // instead of failing terminally NotFound (the executor has no
        // recoverable retry for a Failed op, and nothing else re-inserts
        // an entry for a still-configured VM).
        if !self.vms.read().await.contains_key(vm_id) {
            self.readopt_stopped_vm(vm_id, operation_id).await?;
        }
        let liveness = {
            let mut vms = self.vms.write().await;
            let Some(proc) = vms.get_mut(vm_id) else {
                return Err(ChvError::NotFound {
                    resource: "vm".to_string(),
                    id: vm_id.to_string(),
                });
            };
            let api_socket = proc.api_socket.clone();
            proc.child.prove_exited(&api_socket)
        };
        match liveness {
            Liveness::Exited => {
                info!(vm_id = %vm_id, op = operation_id.unwrap_or("-"), "vmm process exited, re-spawning");
                self.respawn_vmm(vm_id, operation_id).await?;
                __guard.succeeded = true;
                return Ok(());
            }
            Liveness::Unknown(e) => {
                warn!(vm_id = %vm_id, error = %e, "cannot determine vmm liveness; refusing to re-spawn");
                return Err(ChvError::Internal {
                    reason: format!(
                        "cannot determine whether the cloud-hypervisor process for vm {vm_id} is still running ({e}); refusing to re-spawn — retry the operation"
                    ),
                });
            }
            Liveness::Alive => {}
        }

        let (api_socket, serial_transport, pty_tx, pty_scrollback, broadcaster_alive) = {
            let vms = self.vms.read().await;
            let proc = vms.get(vm_id).ok_or_else(|| ChvError::NotFound {
                resource: "vm".to_string(),
                id: vm_id.to_string(),
            })?;
            (
                proc.api_socket.clone(),
                proc.serial_transport.clone(),
                proc.pty_tx.clone(),
                proc.pty_scrollback.clone(),
                proc.broadcaster_alive.clone(),
            )
        };

        info!(vm_id = %vm_id, op = operation_id.unwrap_or("-"), "booting vm via ch api");

        let (info_status, info_body) =
            Self::ch_api_request_with_body(&api_socket, "GET", "/api/v1/vm.info", None).await?;
        let mut state = String::new();
        let action = if info_status == 200 {
            if let Ok(v) = serde_json::from_str::<serde_json::Value>(&info_body) {
                state = v
                    .get("state")
                    .and_then(|s| s.as_str())
                    .unwrap_or("")
                    .to_string();
                start_vm_action(&state)
            } else {
                start_vm_action("")
            }
        } else {
            start_vm_action("")
        };

        // Respawn broadcaster if it died while the VM was running.
        // This must happen BEFORE the idempotent early return so console
        // output doesn't stall when start_vm is called on an already-running VM.
        self.respawn_broadcaster_if_dead(
            vm_id,
            &serial_transport,
            &pty_tx,
            &pty_scrollback,
            &broadcaster_alive,
        )
        .await;

        match action {
            StartVmAction::AlreadyRunning => {
                // Issue-#409 self-heal, adopted VMs only: the reconciler
                // (and any operator re-drive) lands here shortly after
                // an agent restart re-adopted a live VMM, making this
                // the first reconciliation point that can detect — and
                // reboot away — a serial-manager thread that died when
                // the previous agent process was SIGKILLed mid-boot.
                // Every healthy VM takes the no-op path (see
                // `heal_dead_serial_manager`'s gates); a deliberately
                // `Paused` VM is never touched.
                if state == "Running" {
                    self.heal_dead_serial_manager(vm_id, operation_id).await;
                }
                info!(vm_id = %vm_id, state = %state, "vm already booted, skipping vm.boot");
                // Idempotent success: VM is already in the desired state.
                // The guard's succeeded flag must be set on every Ok return
                // so RED metrics classify this as ok, not err.
                __guard.succeeded = true;
                return Ok(());
            }
            StartVmAction::Boot => {}
        }

        let status = Self::ch_api_request(&api_socket, "PUT", "/api/v1/vm.boot", None).await?;
        if status != 200 && status != 204 {
            warn!(vm_id = %vm_id, status = status, "vm.boot returned non-success (VM may have auto-booted)");
        }

        __guard.succeeded = true;
        Ok(())
    }

    async fn stop_vm(
        &self,
        vm_id: &str,
        force: bool,
        operation_id: Option<&str>,
    ) -> Result<(), ChvError> {
        let mut __guard = VmOpGuard::new("stop");
        // Serialize with the other lifecycle ops for this VM (see
        // `lifecycle_locks`).
        let _lifecycle = self.vm_op_lock(vm_id).lock_owned().await;
        let api_socket = self.get_vm_socket(vm_id).await?;

        info!(vm_id = %vm_id, force = force, op = operation_id.unwrap_or("-"), "stopping vm");

        if force {
            let removed = {
                let mut map = self.vms.write().await;
                map.remove(vm_id)
            };
            let log_path = if let Some(proc) = removed {
                // Clear in-memory scrollback before dropping the process.
                proc.pty_scrollback
                    .write()
                    .expect("scrollback lock poisoned")
                    .clear();
                let vm_dir = proc.api_socket.parent().map(|p| p.to_path_buf());
                // INVARIANT — kill and reap the VMM BEFORE `proc` (and its
                // console_io descriptor, plus any dup the broadcaster still
                // holds) drops: an agent-side close of a serial connection
                // whose receive queue holds unread data resets the
                // connection, which kills cloud-hypervisor v43's serial
                // manager (and with a live manager in the blast radius, can
                // freeze the guest — see `abandon_serial_connection`).
                // With the VMM already dead there is no peer left to reset.
                // Any future reordering of these steps must preserve this.
                // #351: a refused or ineffective kill no longer drops the
                // entry — `kill_removed_vmm_or_restore` restores it instead,
                // so the descriptor never closes over a live VMM on that
                // path either. Reap before dropping the entry: the agent is
                // the parent of an Owned child, and an unreaped exit would
                // linger as a zombie for the agent's lifetime.
                self.kill_removed_vmm_or_restore(vm_id, proc).await?;
                vm_dir
            } else {
                None
            };
            if let Some(vm_dir) = log_path {
                // Rotate, never delete: the console log is the only
                // record of what the guest was doing when it was killed
                // (see `rotate_console_log`).
                match rotate_console_log(&vm_dir).await {
                    Ok(()) => info!(
                        vm_id = %vm_id,
                        path = %vm_console_log(&vm_dir).display(),
                        "rotated console.log → console.log.last on force stop"
                    ),
                    Err(e) => warn!(
                        vm_id = %vm_id,
                        path = %vm_console_log(&vm_dir).display(),
                        error = %e,
                        "failed to rotate console.log on force stop (evidence may be lost)"
                    ),
                }
            }
        } else {
            // Graceful stop: send the ACPI power button so the guest OS can
            // shut itself down cleanly. cloud-hypervisor v43 exits WITH the
            // guest (the VMM control loop's Exit dispatch runs vmm_shutdown),
            // so once the guest reaches Shutdown the VMM process is gone —
            // there is no daemon to keep alive. The VmProcess entry
            // deliberately STAYS in the map (with its child reaped and
            // marked `Dead` — see the zombie-prevention note below) so a
            // later start re-spawns the VMM and re-creates the VM from the
            // payload persisted at create time (see `respawn_vmm`), and
            // stop/delete remain idempotent against the dead process. Poll
            // vm.info for the graceful window (see `GRACEFUL_STOP_WINDOW`)
            // waiting for a non-running terminal state (Shutdown or
            // Created).
            let _ = Self::ch_api_request(&api_socket, "PUT", "/api/v1/vm.power-button", None).await;
            // Poll vm.info waiting for the VM to reach a non-running
            // terminal state (Shutdown or Created). A guest that powers
            // itself off takes the process with it (v43 exits with the
            // guest), so the request failing mid-window is the normal
            // completion signal too.
            let start = std::time::Instant::now();
            let mut graceful_shutdown = false;
            while start.elapsed() < Self::GRACEFUL_STOP_WINDOW {
                tokio::time::sleep(std::time::Duration::from_millis(500)).await;
                if let Ok((200, body)) =
                    Self::ch_api_request_with_body(&api_socket, "GET", "/api/v1/vm.info", None)
                        .await
                {
                    if let Ok(v) = serde_json::from_str::<serde_json::Value>(&body) {
                        let state = v.get("state").and_then(|s| s.as_str()).unwrap_or("");
                        if state == "Shutdown" || state == "Created" {
                            graceful_shutdown = true;
                            break;
                        }
                    }
                } else {
                    // CH process disappeared — treat as stopped
                    graceful_shutdown = true;
                    break;
                }
            }

            if !graceful_shutdown {
                tracing::warn!(vm_id = %vm_id, "VM did not shut down gracefully within timeout, force-killing");
                let removed = {
                    let mut map = self.vms.write().await;
                    map.remove(vm_id)
                };
                let log_path = if let Some(proc) = removed {
                    proc.pty_scrollback
                        .write()
                        .expect("scrollback lock poisoned")
                        .clear();
                    let vm_dir = proc.api_socket.parent().map(|p| p.to_path_buf());
                    // #351: same contract as the force branch above —
                    // the timeout's SIGKILL can be refused or
                    // ineffective, and a stop that reports success
                    // must not leave a live VMM behind (the #345 bug
                    // class). Fail loudly and restore the entry.
                    self.kill_removed_vmm_or_restore(vm_id, proc).await?;
                    vm_dir
                } else {
                    None
                };
                if let Some(vm_dir) = log_path {
                    // Rotate, never delete (see `rotate_console_log`).
                    match rotate_console_log(&vm_dir).await {
                        Ok(()) => info!(
                            vm_id = %vm_id,
                            path = %vm_console_log(&vm_dir).display(),
                            "rotated console.log → console.log.last on force stop after graceful timeout"
                        ),
                        Err(e) => warn!(
                            vm_id = %vm_id,
                            path = %vm_console_log(&vm_dir).display(),
                            error = %e,
                            "failed to rotate console.log on force stop after graceful timeout (evidence may be lost)"
                        ),
                    }
                }
                // Force-kill fallback after graceful-stop timeout is still a
                // successful stop from the caller's point of view: the VM is no
                // longer in the runtime map. Mark the guard before the early
                // return so RED metrics classify this as ok.
                __guard.succeeded = true;
                return Ok(());
            }

            // Clear console caches after graceful shutdown. The VmProcess stays
            // in the map so a later vm.boot can restart it; we truncate the
            // on-disk log so the existing writer task can continue appending.
            //
            // Truncate, NOT rotate (`rotate_console_log`): the entry —
            // and with it the console.log writer task — SURVIVES a
            // graceful stop. Truncating in place keeps `console.log`
            // present (the live console view reads it) and the
            // surviving writer's fd pointed at the live file; a rename
            // would leave console.log absent from that view until the
            // next start re-spawns the VM and its writer, and would
            // point any late bytes at `.last`. The graceful session's
            // evidence is traded for that continuity by design; only
            // the force paths (which drop the entry and its writer)
            // rotate.
            let (pty_scrollback, log_path) = {
                let vms = self.vms.read().await;
                let proc = vms.get(vm_id);
                (
                    proc.map(|p| p.pty_scrollback.clone()),
                    proc.and_then(|p| p.api_socket.parent().map(vm_console_log)),
                )
            };
            if let Some(sb) = pty_scrollback {
                sb.write().expect("scrollback lock poisoned").clear();
            }
            if let Some(path) = log_path {
                match tokio::fs::OpenOptions::new()
                    .create(true)
                    .truncate(true)
                    .write(true)
                    .open(&path)
                    .await
                {
                    Ok(_) => {
                        info!(vm_id = %vm_id, path = %path.display(), "truncated console.log on graceful stop")
                    }
                    Err(e) => {
                        warn!(vm_id = %vm_id, path = %path.display(), error = %e, "failed to truncate console.log")
                    }
                }
            }

            // Complete the stop against the PROCESS, not just the guest
            // (#341/#345). The loop above can end on either premise:
            // vm.info reporting a terminal state, or its dead-socket
            // branch treating an unreachable API as "CH process
            // disappeared". Only the first guarantees the process left.
            // A wedged VMM (guest powered down, control loop stuck — the
            // API dies with it, and SIGTERM routes through the same
            // loop, so it is ineffective) ends the loop on the second
            // premise while the process lives on: it holds the vm dir,
            // sockets, and disk, and blocks the next start
            // (`prove_exited` → Alive → re-spawn refused) — found by the
            // M4.3 qualification (run 5 / issue #345: a graceful stop
            // of an ADOPTED VM left the VMM alive and SIGTERM-immune
            // for minutes, and a follow-up `vm start` was accepted but
            // silently did nothing). A stop that reports success must
            // not leave a live VMM behind: verify liveness, SIGKILL a
            // survivor, and wait it out. Either way the surviving
            // entry's child becomes `Dead` — the truthful state for an
            // exited VMM — and an `Owned` child is reaped (zombie
            // prevention: nothing else reaps it until the next
            // `vm.start` runs `prove_exited`, so a VM stopped and never
            // restarted would otherwise leak a zombie for the agent's
            // lifetime).
            let taken = {
                let mut vms = self.vms.write().await;
                vms.get_mut(vm_id).map(|proc| {
                    let api_socket = proc.api_socket.clone();
                    let liveness = proc.child.prove_exited(&api_socket);
                    (
                        std::mem::replace(&mut proc.child, VmmChild::Dead),
                        api_socket,
                        liveness,
                    )
                })
            };
            if let Some((mut child, api_socket, liveness)) = taken {
                match liveness {
                    Liveness::Exited => {
                        // Normal completion: reap the `Owned` child in a
                        // detached task so a slow exit never blocks this
                        // op or the vms lock (an adopted orphan is
                        // parented to init and reaped there).
                        if let VmmChild::Owned(mut owned) = child {
                            tokio::spawn(async move {
                                let _ = owned.wait().await;
                            });
                        }
                    }
                    Liveness::Alive | Liveness::Unknown(_) => {
                        // The wedge (or an unreadable Owned child — we
                        // own it either way, so killing is safe). Kill
                        // and wait HERE, under the lifecycle op lock
                        // held for the whole stop: a concurrent start
                        // can otherwise re-spawn against a runtime dir
                        // the wedged VMM still holds.
                        warn!(
                            vm_id = %vm_id,
                            liveness = ?liveness,
                            "VMM still alive after the graceful stop window — a \
                             wedged control loop (dead API socket, SIGTERM \
                             ineffective) must not outlive a successful stop; \
                             SIGKilling and waiting"
                        );
                        let signaled = child.kill(&api_socket, self.expected_vmm_exe());
                        // The kill can be REFUSED (an adopted pid whose
                        // identity can no longer be proven — e.g. the
                        // VMM binary was replaced on disk while the
                        // process ran — must never be signalled) or
                        // INEFFECTIVE (a D-state process survives even
                        // SIGKILL). #345's contract — a live VMM must
                        // not outlive a successful stop — extends to the
                        // remediation itself: verify death, never
                        // assume it (#348; the shared confirmation is
                        // `confirm_vmm_death`, used by every
                        // force-kill site since #351).
                        let still_alive = !Self::confirm_vmm_death(&mut child, signaled).await;
                        if still_alive {
                            // Capture before the handle is restored
                            // below: the operator acting on the error
                            // alone gets the pid directly.
                            let pid = child
                                .vmm_pid()
                                .map(|p| p.to_string())
                                .unwrap_or_else(|| "<unknown>".to_string());
                            // Restore the truthful handle: the process
                            // is alive (just proven), so the entry must
                            // keep it — a retry stop or a later start
                            // re-validates (Alive → re-spawn refused)
                            // instead of assuming the VMM is gone and
                            // forking a second one onto the disk it
                            // still holds.
                            {
                                let mut vms = self.vms.write().await;
                                if let Some(proc) = vms.get_mut(vm_id) {
                                    if matches!(proc.child, VmmChild::Dead) {
                                        proc.child = child;
                                    }
                                }
                            }
                            return Err(ChvError::Internal {
                                reason: format!(
                                    "VMM for vm '{vm_id}' (pid {pid}) is still alive after the \
                                     post-stop SIGKILL ({}): manual operator \
                                     intervention required (SIGKILL pid {pid} \
                                     directly — the documented escape)",
                                    if signaled {
                                        "kill ineffective"
                                    } else {
                                        "kill refused: process identity unproven"
                                    }
                                ),
                            });
                        }
                    }
                }
            }
        }
        __guard.succeeded = true;
        Ok(())
    }

    async fn delete_vm(&self, vm_id: &str, operation_id: Option<&str>) -> Result<(), ChvError> {
        let mut __guard = VmOpGuard::new("delete");
        // Serialize with the other lifecycle ops for this VM (see
        // `lifecycle_locks`).
        let _lifecycle = self.vm_op_lock(vm_id).lock_owned().await;
        let removed = {
            let mut map = self.vms.write().await;
            map.remove(vm_id)
        };
        let proc = match removed {
            Some(proc) => proc,
            None => {
                // Force-stop residual / create-window crash: no in-memory
                // entry, but the shared layout may still own artifacts —
                // and possibly a live VMM this agent never tracked.
                // Handling it HERE keeps the whole gate under this VM's
                // lifecycle op lock (already held): a concurrent start
                // cannot spawn a VMM whose identity evidence this delete
                // then removes, and the delete cannot kill a VMM a start
                // just adopted.
                self.delete_untracked_vm(vm_id, operation_id).await?;
                __guard.succeeded = true;
                return Ok(());
            }
        };

        info!(vm_id = %vm_id, op = operation_id.unwrap_or("-"), "deleting vm");

        // #351: the delete's force kill can be REFUSED (an adopted pid
        // whose identity can no longer be proven — e.g. the VMM binary
        // was replaced on disk while the process ran) or INEFFECTIVE (a
        // D-state process survives even SIGKILL). The pre-#351 shape
        // removed the entry, unlinked the artifacts, and reported
        // success over the live VMM — which then kept holding the
        // runtime dir, sockets, and disk with no state referencing it.
        // Mirror #348's stop-path handling: verify death, fail loudly
        // with the operator escape, and keep the entry so a retry
        // re-validates. A VMM that already exited cleanly still deletes
        // successfully (the confirmation sees it gone) — the delete
        // stays idempotent for the already-dead case.
        let api_socket = proc.api_socket.clone();
        let vm_dir = proc.api_socket.parent().map(|p| p.to_path_buf());
        self.kill_removed_vmm_or_restore(vm_id, proc).await?;
        // Remove the runtime artifacts this adapter owns: the api socket,
        // the pid file and the persisted creation payload. Disk images and
        // the VM directory itself belong to the storage/authority layers.
        let _ = tokio::fs::remove_file(&api_socket).await;
        if let Some(vm_dir) = vm_dir {
            let _ = tokio::fs::remove_file(vm_pid_file(&vm_dir)).await;
            let _ = tokio::fs::remove_file(vm_config_file(&vm_dir)).await;
        }
        __guard.succeeded = true;
        Ok(())
    }

    async fn reboot_vm(&self, vm_id: &str, operation_id: Option<&str>) -> Result<(), ChvError> {
        // Serialize with the other lifecycle ops for this VM (see
        // `lifecycle_locks`).
        let _lifecycle = self.vm_op_lock(vm_id).lock_owned().await;
        self.reboot_vm_locked(vm_id, operation_id).await
    }

    async fn resize_vm(
        &self,
        vm_id: &str,
        cpus: Option<u32>,
        memory_bytes: Option<u64>,
        operation_id: Option<&str>,
    ) -> Result<(), ChvError> {
        let api_socket = self.get_vm_socket(vm_id).await?;

        info!(vm_id = %vm_id, ?cpus, ?memory_bytes, op = operation_id.unwrap_or("-"), "resizing vm via ch api");

        let mut obj = serde_json::Map::new();
        if let Some(c) = cpus {
            obj.insert("desired_vcpus".to_string(), serde_json::Value::from(c));
        }
        if let Some(m) = memory_bytes {
            obj.insert("desired_ram".to_string(), serde_json::Value::from(m));
        }
        let body = serde_json::Value::Object(obj).to_string();

        let status =
            Self::ch_api_request(&api_socket, "PUT", "/api/v1/vm.resize", Some(&body)).await?;
        Self::expect_status(status, "vm.resize")?;
        Ok(())
    }

    async fn vm_info(&self, vm_id: &str) -> Result<VmInfo, ChvError> {
        let api_socket = self.get_vm_socket(vm_id).await?;

        let (status, body) =
            Self::ch_api_request_with_body(&api_socket, "GET", "/api/v1/vm.info", None).await?;
        if status != 200 {
            return Err(ChvError::Internal {
                reason: format!("vm.info returned unexpected status {}", status),
            });
        }

        let response_json: serde_json::Value =
            serde_json::from_str(&body).map_err(|e| ChvError::Internal {
                reason: format!("failed to parse vm.info response: {}", e),
            })?;

        let state = response_json
            .get("state")
            .and_then(|s| s.as_str())
            .unwrap_or("Unknown")
            .to_string();
        let cpus = response_json
            .pointer("/config/cpus/boot_vcpus")
            .and_then(|c| c.as_u64())
            .unwrap_or(0) as u32;
        let memory_bytes = response_json
            .pointer("/config/memory/size")
            .and_then(|m| m.as_u64())
            .unwrap_or(0);

        Ok(VmInfo {
            state,
            cpus,
            memory_bytes,
        })
    }

    async fn vm_counters(&self, vm_id: &str) -> Result<VmCounters, ChvError> {
        let api_socket = self.get_vm_socket(vm_id).await?;

        let (status, body) =
            Self::ch_api_request_with_body(&api_socket, "GET", "/api/v1/vm.counters", None).await?;
        if status != 200 {
            return Err(ChvError::Internal {
                reason: format!("vm.counters returned unexpected status {}", status),
            });
        }

        let response_json: serde_json::Value =
            serde_json::from_str(&body).map_err(|e| ChvError::Internal {
                reason: format!("failed to parse vm.counters response: {}", e),
            })?;

        // CPU usage is reported in seconds; compute percentage from delta across ticks.
        let cpu_seconds = response_json
            .pointer("/cpus/usage/cpu_seconds")
            .and_then(|c| c.as_f64())
            .unwrap_or(0.0);

        let mut cpu_percent = 0.0;
        {
            let mut map = self.vms.write().await;
            if let Some(proc) = map.get_mut(vm_id) {
                if let Some(last_at) = proc.last_cpu_at {
                    let delta_secs = cpu_seconds - proc.last_cpu_seconds;
                    let elapsed = last_at.elapsed().as_secs_f64();
                    if elapsed > 0.0 && delta_secs >= 0.0 {
                        // CH reports CPU time across all vCPUs.
                        // Normalize to a percentage of wall-clock time.
                        cpu_percent = (delta_secs / elapsed) * 100.0;
                        // Clamp to a sane max (e.g. 100% per vCPU is unrealistic for long
                        // intervals, but possible for short ones). Let downstream clamp if
                        // they want per-vCPU percentages.
                    }
                }
                proc.last_cpu_seconds = cpu_seconds;
                proc.last_cpu_at = Some(std::time::Instant::now());
            }
        }

        let mut net_rx = 0u64;
        let mut net_tx = 0u64;
        if let Some(net) = response_json.get("net").and_then(|n| n.as_object()) {
            for (_iface, counters) in net {
                if let Some(obj) = counters.as_object() {
                    net_rx += obj.get("rx_bytes").and_then(|x| x.as_u64()).unwrap_or(0);
                    net_tx += obj.get("tx_bytes").and_then(|x| x.as_u64()).unwrap_or(0);
                }
            }
        }

        let mut disk_read = 0u64;
        let mut disk_written = 0u64;
        if let Some(block) = response_json.get("block").and_then(|b| b.as_object()) {
            for (_dev, counters) in block {
                if let Some(obj) = counters.as_object() {
                    disk_read += obj.get("read_bytes").and_then(|x| x.as_u64()).unwrap_or(0);
                    disk_written += obj.get("write_bytes").and_then(|x| x.as_u64()).unwrap_or(0);
                }
            }
        }

        // Memory counters are not exposed by vm.counters; use vm.info config as total
        // and report 0 for used (CH does not expose guest memory usage).
        let memory_total = response_json
            .pointer("/memory/available")
            .and_then(|m| m.as_u64())
            .unwrap_or(0);

        Ok(VmCounters {
            cpu_percent,
            memory_bytes_used: 0,
            memory_bytes_total: memory_total,
            disk_bytes_read: disk_read,
            disk_bytes_written: disk_written,
            net_bytes_rx: net_rx,
            net_bytes_tx: net_tx,
        })
    }

    async fn snapshot_vm(
        &self,
        vm_id: &str,
        destination: &str,
        operation_id: Option<&str>,
    ) -> Result<(), ChvError> {
        let api_socket = self.get_vm_socket(vm_id).await?;

        info!(vm_id = %vm_id, destination = %destination, op = operation_id.unwrap_or("-"), "snapshotting vm via ch api");

        let body =
            serde_json::json!({"destination_url": format!("file://{}", destination)}).to_string();
        let status =
            Self::ch_api_request(&api_socket, "PUT", "/api/v1/vm.snapshot", Some(&body)).await?;
        Self::expect_status(status, "vm.snapshot")?;
        Ok(())
    }

    async fn restore_snapshot(
        &self,
        vm_id: &str,
        source: &str,
        operation_id: Option<&str>,
    ) -> Result<(), ChvError> {
        let api_socket = self.get_vm_socket(vm_id).await?;

        info!(vm_id = %vm_id, source = %source, op = operation_id.unwrap_or("-"), "restoring snapshot via ch api");

        let body = serde_json::json!({"source_url": format!("file://{}", source)}).to_string();
        let status =
            Self::ch_api_request(&api_socket, "PUT", "/api/v1/vm.restore", Some(&body)).await?;
        Self::expect_status(status, "vm.restore")?;
        Ok(())
    }

    async fn pause_vm(&self, vm_id: &str, operation_id: Option<&str>) -> Result<(), ChvError> {
        let mut __guard = VmOpGuard::new("pause");
        let api_socket = self.get_vm_socket(vm_id).await?;

        info!(vm_id = %vm_id, op = operation_id.unwrap_or("-"), "pausing vm via ch api");

        let status = Self::ch_api_request(&api_socket, "PUT", "/api/v1/vm.pause", None).await?;
        Self::expect_status(status, "vm.pause")?;
        __guard.succeeded = true;
        Ok(())
    }

    async fn resume_vm(&self, vm_id: &str, operation_id: Option<&str>) -> Result<(), ChvError> {
        let mut __guard = VmOpGuard::new("resume");
        let api_socket = self.get_vm_socket(vm_id).await?;

        info!(vm_id = %vm_id, op = operation_id.unwrap_or("-"), "resuming vm via ch api");

        let status = Self::ch_api_request(&api_socket, "PUT", "/api/v1/vm.resume", None).await?;
        Self::expect_status(status, "vm.resume")?;
        __guard.succeeded = true;
        Ok(())
    }

    async fn power_button(&self, vm_id: &str, operation_id: Option<&str>) -> Result<(), ChvError> {
        let api_socket = self.get_vm_socket(vm_id).await?;

        info!(vm_id = %vm_id, op = operation_id.unwrap_or("-"), "sending ACPI power button via ch api");

        let status =
            Self::ch_api_request(&api_socket, "PUT", "/api/v1/vm.power-button", None).await?;
        Self::expect_status(status, "vm.power-button")?;
        Ok(())
    }

    async fn add_disk(
        &self,
        vm_id: &str,
        params: &AddDiskParams,
        operation_id: Option<&str>,
    ) -> Result<String, ChvError> {
        let api_socket = self.get_vm_socket(vm_id).await?;

        info!(vm_id = %vm_id, path = %params.path.display(), op = operation_id.unwrap_or("-"), "hot-adding disk via ch api");

        let mut obj = serde_json::Map::new();
        obj.insert(
            "path".to_string(),
            serde_json::Value::from(params.path.to_string_lossy().to_string()),
        );
        obj.insert(
            "readonly".to_string(),
            serde_json::Value::from(params.read_only),
        );
        if let Some(ref id) = params.id {
            obj.insert("id".to_string(), serde_json::Value::from(id.clone()));
        }
        let body = serde_json::Value::Object(obj).to_string();

        let (status, response_body) =
            Self::ch_api_request_with_body(&api_socket, "PUT", "/api/v1/vm.add-disk", Some(&body))
                .await?;
        Self::expect_status(status, "vm.add-disk")?;
        Ok(response_body)
    }

    async fn remove_device(
        &self,
        vm_id: &str,
        device_id: &str,
        operation_id: Option<&str>,
    ) -> Result<(), ChvError> {
        let api_socket = self.get_vm_socket(vm_id).await?;

        info!(vm_id = %vm_id, device_id = %device_id, op = operation_id.unwrap_or("-"), "hot-removing device via ch api");

        let body = serde_json::json!({"id": device_id}).to_string();
        let status =
            Self::ch_api_request(&api_socket, "PUT", "/api/v1/vm.remove-device", Some(&body))
                .await?;
        Self::expect_status(status, "vm.remove-device")?;
        Ok(())
    }

    async fn add_net(
        &self,
        vm_id: &str,
        params: &AddNetParams,
        operation_id: Option<&str>,
    ) -> Result<String, ChvError> {
        let api_socket = self.get_vm_socket(vm_id).await?;

        info!(vm_id = %vm_id, tap = %params.tap_name, mac = %params.mac_address, op = operation_id.unwrap_or("-"), "hot-adding net via ch api");

        let mut obj = serde_json::Map::new();
        obj.insert(
            "tap".to_string(),
            serde_json::Value::from(params.tap_name.clone()),
        );
        obj.insert(
            "mac".to_string(),
            serde_json::Value::from(params.mac_address.clone()),
        );
        if let Some(ref id) = params.id {
            obj.insert("id".to_string(), serde_json::Value::from(id.clone()));
        }
        let body = serde_json::Value::Object(obj).to_string();

        let (status, response_body) =
            Self::ch_api_request_with_body(&api_socket, "PUT", "/api/v1/vm.add-net", Some(&body))
                .await?;
        Self::expect_status(status, "vm.add-net")?;
        Ok(response_body)
    }

    async fn resize_disk(
        &self,
        vm_id: &str,
        disk_id: &str,
        new_size_bytes: u64,
        operation_id: Option<&str>,
    ) -> Result<(), ChvError> {
        let api_socket = self.get_vm_socket(vm_id).await?;

        info!(vm_id = %vm_id, disk_id = %disk_id, new_size = new_size_bytes, op = operation_id.unwrap_or("-"), "resizing disk via ch api");

        let body = format!(r#"{{"id":"{}","new_size":{}}}"#, disk_id, new_size_bytes);
        let status =
            Self::ch_api_request(&api_socket, "PUT", "/api/v1/vm.resize-zone", Some(&body)).await?;
        Self::expect_status(status, "vm.resize-zone")?;
        Ok(())
    }

    async fn ping(&self, vm_id: &str) -> Result<bool, ChvError> {
        let api_socket = self.get_vm_socket(vm_id).await?;

        match Self::ch_api_request(&api_socket, "GET", "/api/v1/vmm.ping", None).await {
            Ok(status) => Ok(status == 200),
            Err(_) => Ok(false),
        }
    }

    async fn send_migration(
        &self,
        vm_id: &str,
        destination_url: &str,
        operation_id: Option<&str>,
    ) -> Result<(), ChvError> {
        let api_socket = self.get_vm_socket(vm_id).await?;

        info!(
            vm_id = %vm_id,
            destination_url = %destination_url,
            op = operation_id.unwrap_or("-"),
            "initiating send-migration via ch api"
        );

        let body = serde_json::json!({"destination_url": destination_url}).to_string();
        // send-migration is a long-running blocking call; use a custom long timeout.
        let (status, response_body) = {
            let mut stream = tokio::net::UnixStream::connect(&api_socket)
                .await
                .map_err(|e| ChvError::Io {
                    path: api_socket.to_string_lossy().to_string(),
                    source: e,
                })?;

            let request = format!(
                "PUT /api/v1/vm.send-migration HTTP/1.1\r\nHost: localhost\r\nContent-Length: {}\r\nContent-Type: application/json\r\n\r\n{}",
                body.len(),
                body
            );

            stream
                .write_all(request.as_bytes())
                .await
                .map_err(|e| ChvError::Io {
                    path: api_socket.to_string_lossy().to_string(),
                    source: e,
                })?;

            let mut buf = Vec::new();
            let mut tmp = [0u8; 4096];
            let read_fut = async {
                loop {
                    let n = stream.read(&mut tmp).await.map_err(|e| ChvError::Io {
                        path: api_socket.to_string_lossy().to_string(),
                        source: e,
                    })?;
                    if n == 0 {
                        break;
                    }
                    buf.extend_from_slice(&tmp[..n]);
                    if let Some(header_end) = buf.windows(4).position(|w| w == b"\r\n\r\n") {
                        let header_bytes = &buf[..header_end];
                        let headers = String::from_utf8_lossy(header_bytes);
                        let content_length = headers
                            .lines()
                            .find(|l| l.to_ascii_lowercase().starts_with("content-length:"))
                            .and_then(|l| l.split_once(':').map(|x| x.1))
                            .and_then(|v| v.trim().parse::<usize>().ok())
                            .unwrap_or(0);
                        let body_start = header_end + 4;
                        if buf.len() >= body_start + content_length {
                            break;
                        }
                    }
                }
                Ok::<(), ChvError>(())
            };
            // Migration can take minutes; allow up to 10 minutes for this blocking call.
            tokio::time::timeout(std::time::Duration::from_secs(600), read_fut)
                .await
                .map_err(|_| ChvError::Internal {
                    reason: format!("send-migration timed out for vm {}", vm_id),
                })??;

            let raw = String::from_utf8_lossy(&buf);
            let status_code = parse_http_status(raw.as_bytes()).unwrap_or(0);
            let resp_body = if let Some(idx) = raw.find("\r\n\r\n") {
                raw[idx + 4..].to_string()
            } else {
                String::new()
            };
            (status_code, resp_body)
        };

        if status != 200 && status != 204 {
            return Err(ChvError::Internal {
                reason: format!(
                    "vm.send-migration returned status {} for vm {}: {}",
                    status, vm_id, response_body
                ),
            });
        }
        Ok(())
    }

    async fn receive_migration(
        &self,
        vm_id: &str,
        receiver_url: &str,
        operation_id: Option<&str>,
    ) -> Result<(), ChvError> {
        let api_socket = self.get_vm_socket(vm_id).await?;

        info!(
            vm_id = %vm_id,
            receiver_url = %receiver_url,
            op = operation_id.unwrap_or("-"),
            "initiating receive-migration via ch api"
        );

        let body = serde_json::json!({"receiver_url": receiver_url}).to_string();
        // receive-migration is also a long-running blocking call.
        let (status, response_body) = {
            let mut stream = tokio::net::UnixStream::connect(&api_socket)
                .await
                .map_err(|e| ChvError::Io {
                    path: api_socket.to_string_lossy().to_string(),
                    source: e,
                })?;

            let request = format!(
                "PUT /api/v1/vm.receive-migration HTTP/1.1\r\nHost: localhost\r\nContent-Length: {}\r\nContent-Type: application/json\r\n\r\n{}",
                body.len(),
                body
            );

            stream
                .write_all(request.as_bytes())
                .await
                .map_err(|e| ChvError::Io {
                    path: api_socket.to_string_lossy().to_string(),
                    source: e,
                })?;

            let mut buf = Vec::new();
            let mut tmp = [0u8; 4096];
            let read_fut = async {
                loop {
                    let n = stream.read(&mut tmp).await.map_err(|e| ChvError::Io {
                        path: api_socket.to_string_lossy().to_string(),
                        source: e,
                    })?;
                    if n == 0 {
                        break;
                    }
                    buf.extend_from_slice(&tmp[..n]);
                    if let Some(header_end) = buf.windows(4).position(|w| w == b"\r\n\r\n") {
                        let header_bytes = &buf[..header_end];
                        let headers = String::from_utf8_lossy(header_bytes);
                        let content_length = headers
                            .lines()
                            .find(|l| l.to_ascii_lowercase().starts_with("content-length:"))
                            .and_then(|l| l.split_once(':').map(|x| x.1))
                            .and_then(|v| v.trim().parse::<usize>().ok())
                            .unwrap_or(0);
                        let body_start = header_end + 4;
                        if buf.len() >= body_start + content_length {
                            break;
                        }
                    }
                }
                Ok::<(), ChvError>(())
            };
            // Migration can take minutes; allow up to 10 minutes.
            tokio::time::timeout(std::time::Duration::from_secs(600), read_fut)
                .await
                .map_err(|_| ChvError::Internal {
                    reason: format!("receive-migration timed out for vm {}", vm_id),
                })??;

            let raw = String::from_utf8_lossy(&buf);
            let status_code = parse_http_status(raw.as_bytes()).unwrap_or(0);
            let resp_body = if let Some(idx) = raw.find("\r\n\r\n") {
                raw[idx + 4..].to_string()
            } else {
                String::new()
            };
            (status_code, resp_body)
        };

        if status != 200 && status != 204 {
            return Err(ChvError::Internal {
                reason: format!(
                    "vm.receive-migration returned status {} for vm {}: {}",
                    status, vm_id, response_body
                ),
            });
        }
        Ok(())
    }

    async fn get_vm_state(&self, vm_id: &str) -> Result<String, ChvError> {
        let info = self.vm_info(vm_id).await?;
        Ok(info.state)
    }

    async fn coredump(
        &self,
        vm_id: &str,
        destination: &str,
        operation_id: Option<&str>,
    ) -> Result<(), ChvError> {
        let api_socket = self.get_vm_socket(vm_id).await?;

        info!(vm_id = %vm_id, destination = %destination, op = operation_id.unwrap_or("-"), "generating coredump via ch api");

        let body = format!(r#"{{"destination_url":"file://{}"}}"#, destination);
        let status =
            Self::ch_api_request(&api_socket, "PUT", "/api/v1/vm.coredump", Some(&body)).await?;
        Self::expect_status(status, "vm.coredump")?;
        Ok(())
    }

    async fn pty_master(&self, vm_id: &str) -> Option<OwnedFd> {
        let map = self.vms.read().await;
        let proc = map.get(vm_id)?;
        Self::dup_cloexec(&proc.console_io).ok()
    }

    async fn pty_output_rx(
        &self,
        vm_id: &str,
    ) -> Option<tokio::sync::broadcast::Receiver<Vec<u8>>> {
        let map = self.vms.read().await;
        let proc = map.get(vm_id)?;
        Some(proc.pty_tx.subscribe())
    }

    async fn pty_scrollback(&self, vm_id: &str) -> Option<Vec<u8>> {
        let map = self.vms.read().await;
        let proc = map.get(vm_id)?;
        // A sync lock is deliberate (issue #469): the broadcaster's drain
        // loop appends from its blocking-pool thread and must never await;
        // this critical section is a bounded clone with no awaits inside.
        let sb = proc
            .pty_scrollback
            .read()
            .expect("scrollback lock poisoned");
        Some(sb.clone())
    }
}

use cellhv_core_runtime_ownership::ProcessIdentity;

#[derive(Debug, Clone)]
pub struct AdoptedVmHandle {
    pub vm_id: String,
    pub api_socket: std::path::PathBuf,
    pub identity: ProcessIdentity,
    pub proc_path: std::path::PathBuf,
    pub runtime_root: std::path::PathBuf,
}

impl AdoptedVmHandle {
    pub fn new(vm_id: String, api_socket: std::path::PathBuf, identity: ProcessIdentity) -> Self {
        Self {
            vm_id,
            api_socket,
            identity,
            proc_path: std::path::PathBuf::from("/proc"),
            runtime_root: std::path::PathBuf::from("/"),
        }
    }

    pub fn with_runtime_root(mut self, path: std::path::PathBuf) -> Self {
        self.runtime_root = path;
        self
    }

    pub fn with_proc_path(mut self, path: std::path::PathBuf) -> Self {
        self.proc_path = path;
        self
    }

    pub fn revalidate(&self) -> Result<(), ChvError> {
        let vm_id = cellhv_core_types::VmId::new(&self.vm_id).map_err(|_| ChvError::Internal {
            reason: "invalid vm_id".to_string(),
        })?;
        let observer = crate::linux_observation::LinuxOwnershipObservation::open_with_proc(
            &self.runtime_root,
            &self.proc_path,
            self.identity.pid,
            vm_id,
        )
        .map_err(|e| ChvError::Internal {
            reason: format!("failed to open observer: {}", e),
        })?;

        let current_identity = observer
            .process(self.identity.pid)
            .map_err(|e| ChvError::Internal {
                reason: format!("failed to get process identity: {}", e),
            })?
            .ok_or_else(|| ChvError::Internal {
                reason: "process exited".to_string(),
            })?;

        if current_identity.pid != self.identity.pid
            || current_identity.start_ticks != self.identity.start_ticks
            || current_identity.boot_id != self.identity.boot_id
            || current_identity.executable != self.identity.executable
            || current_identity.uid != self.identity.uid
            || current_identity.gid != self.identity.gid
            || current_identity.cgroup_fingerprint != self.identity.cgroup_fingerprint
        {
            return Err(ChvError::Internal {
                reason: "process identity changed".to_string(),
            });
        }

        Ok(())
    }

    pub async fn api_request(
        &self,
        method: &str,
        path: &str,
        body: Option<&str>,
    ) -> Result<u16, ChvError> {
        self.revalidate()?;
        crate::ch_api::CloudHypervisorApiClient::default()
            .request(&self.api_socket, method, path, body)
            .await
    }

    pub async fn api_request_with_body(
        &self,
        method: &str,
        path: &str,
        body: Option<&str>,
    ) -> Result<(u16, String), ChvError> {
        self.revalidate()?;
        crate::ch_api::CloudHypervisorApiClient::default()
            .request_with_body(&self.api_socket, method, path, body)
            .await
    }
}

impl ProcessCloudHypervisorAdapter {
    /// Re-derives a runtime map entry from the shared on-disk layout for
    /// a VM whose in-memory entry is gone — the force-stop residual (the
    /// force paths' only lasting effect is removing the entry; the
    /// persisted creation payload survives) — so a later start is
    /// completable instead of terminally NotFound (M2.5 finding: after a
    /// force stop, only `create_vm` registration and startup adoption
    /// could re-insert an entry, and neither runs for a still-configured
    /// VM — the executor finishes a retried StartVm as Failed/NOT_FOUND
    /// forever).
    ///
    /// Mirrors `adopt_running_vms`'s per-VM re-derivation with one
    /// difference: a missing pidfile does not abort the re-derivation.
    /// Liveness is established by scanning `/proc` for a live VMM owning
    /// the api socket:
    /// - a live owner (agent crash in the create window before the
    ///   pidfile write, or skipped/failed adoption) is adopted honestly:
    ///   `start_vm` will see it `Alive` and boot against it instead of
    ///   forking a second VMM onto one disk;
    /// - no live owner → `VmmChild::Dead`: provably nothing to signal,
    ///   wait for, or prove, and `start_vm` re-spawns from the payload.
    ///
    /// Returns `NotFound` when the VM demonstrably never ran on this
    /// node (no runtime dir, no persisted payload, unsafe id, or
    /// adoption never recorded a runtime root) — the misroute rule: a
    /// wrongly-addressed op must not be silently absorbed. One
    /// deliberate exception: while the agent's graceful shutdown is in
    /// progress (the `console_draining` latch), the shutdown refusal
    /// short-circuits BEFORE the NotFound checks — during that window
    /// every start is doomed regardless of routing, and failing closed
    /// with a retryable error (rather than touching `/proc` or the
    /// serial socket mid-drain) is the cheaper, uniform contract (the
    /// heal and respawn paths stand down on the same latch).
    async fn readopt_stopped_vm(
        &self,
        vm_id: &str,
        operation_id: Option<&str>,
    ) -> Result<(), ChvError> {
        let not_found = || ChvError::NotFound {
            resource: "vm".to_string(),
            id: vm_id.to_string(),
        };
        // Graceful agent shutdown: never mint a fresh serial connection —
        // process exit would abortively close it, which resets the
        // connection and can kill cloud-hypervisor v43's serial manager
        // (the freeze hazard `drain_and_close_consoles` exists to
        // prevent; the heal and respawn paths check the same latch).
        // The start fails closed and is retryable once the agent has
        // restarted — the on-disk state this path re-derives from is
        // untouched.
        if self.console_draining.load(Ordering::SeqCst) {
            return Err(shutting_down(vm_id));
        }
        let Some(vms_root) = self
            .vms_root
            .read()
            .expect("vms_root lock poisoned")
            .clone()
        else {
            // Adoption never ran (non-standard construction): keep
            // today's NotFound semantics rather than guess a layout.
            return Err(not_found());
        };
        // Layer-B path-safety: the directory name becomes a map key and
        // (via start) a re-spawn source; never build an entry for an id
        // the authority layer would reject (mirrors adoption).
        if !is_safe_resource_id(vm_id) {
            return Err(not_found());
        }
        let vm_dir = vms_root.join("vms").join(vm_id);
        // The persisted creation payload is what makes a start
        // completable; without it the caller's contract is
        // re-create-required, not NotFound-absorb.
        if !vm_config_file(&vm_dir).is_file() {
            return Err(not_found());
        }
        let api_socket = vm_dir.join("vm.sock");

        // Loose (cmdline-only) classification, fail-closed on an
        // unreadable /proc: we must never classify "no live owner"
        // without a completed scan — that is the second-VMM-on-one-disk
        // hazard. A found owner with a mismatched exe name is still
        // adopted: prove_exited is equally loose, while the kill paths
        // stay exe-strict.
        let live_pid = match scan_live_vmm_on_socket(&api_socket) {
            UntrackedVmmScan::Found(pid) => Some(pid),
            UntrackedVmmScan::None => None,
            UntrackedVmmScan::Unreadable(e) => {
                return Err(ChvError::Internal {
                    reason: format!(
                        "cannot determine whether a live VMM still owns vm {vm_id}'s runtime dir ({e}); refusing to re-spawn — retry the operation"
                    ),
                });
            }
        };
        let child = match live_pid {
            Some(pid) => VmmChild::Adopted(pid),
            None => VmmChild::Dead,
        };
        let serial_sock = vm_dir.join("serial.sock");
        let serial_transport = if serial_sock.exists() {
            SerialTransport::Socket(serial_sock)
        } else {
            SerialTransport::Pty
        };

        // Re-attach the console only for a live VMM on the Socket
        // transport (mirrors adoption); anything else gets the EOF
        // placeholder — an honest "no console" endpoint that
        // `respawn_vmm`'s fresh entry will replace anyway.
        let (console_io, console_live) = match (&child, &serial_transport) {
            (VmmChild::Adopted(_), SerialTransport::Socket(path)) => {
                match Self::connect_serial_socket_once(path).await {
                    Ok(fd) => (fd, true),
                    Err(e) => {
                        warn!(
                            vm_id = %vm_id,
                            error = %e,
                            "serial re-attach failed during re-adoption; console capture stays down"
                        );
                        (Self::eof_placeholder_fd(), false)
                    }
                }
            }
            _ => (Self::eof_placeholder_fd(), false),
        };

        let (pty_tx, _) = tokio::sync::broadcast::channel::<Vec<u8>>(4096);
        let pty_scrollback = Arc::new(std::sync::RwLock::new(Vec::new()));
        // Take the broadcaster's endpoint BEFORE the entry consumes
        // console_io (mirrors adoption); capture is only claimed alive
        // when the dup (and with it the broadcaster spawn) happens.
        let broadcaster_fd = if console_live {
            Self::dup_cloexec(&console_io).ok()
        } else {
            None
        };
        let broadcaster_alive = Arc::new(AtomicBool::new(broadcaster_fd.is_some()));

        {
            let mut map = self.vms.write().await;
            // Never over a tracked entry (mirrors adoption): the op lock
            // serializes lifecycle ops, but a concurrent re-adoption or
            // split-brain peer must not replace an Owned child. Note
            // this early return drops any freshly minted connection
            // without an explicit abandon — unreachable in practice
            // (start_vm only calls readopt when the map lacks the id,
            // under the same op lock) and pre-dates the drain latch.
            if map.contains_key(vm_id) {
                info!(
                    vm_id = %vm_id,
                    op = operation_id.unwrap_or("-"),
                    "re-adoption skipped: vm is already tracked"
                );
                return Ok(());
            }
            // Post-lock double check of the shutdown latch (mirrors the
            // heal and respawn paths): the drain hook holds this lock
            // across its passes — if it latched while this readopt was
            // connecting, abandon the fresh connection cleanly and fail
            // the start rather than let process exit abortively close
            // it.
            if self.console_draining.load(Ordering::SeqCst) {
                drop(map);
                drop(broadcaster_fd);
                if console_live {
                    Self::abandon_serial_connection(vm_id, console_io, None).await;
                } else {
                    drop(console_io);
                }
                return Err(shutting_down(vm_id));
            }
            map.insert(
                vm_id.to_string(),
                VmProcess {
                    api_socket: api_socket.clone(),
                    child,
                    console_io,
                    serial_transport: serial_transport.clone(),
                    pty_tx: pty_tx.clone(),
                    pty_scrollback: pty_scrollback.clone(),
                    broadcaster_alive: broadcaster_alive.clone(),
                    last_cpu_seconds: 0.0,
                    last_cpu_at: None,
                    boot_watermark: AtomicU64::new(0),
                },
            );
        }

        if let Some(broadcaster_fd) = broadcaster_fd {
            Self::spawn_pty_broadcaster(
                self.vms.clone(),
                vm_id.to_string(),
                broadcaster_fd,
                serial_transport,
                pty_tx.clone(),
                pty_scrollback.clone(),
                broadcaster_alive,
                self.console_draining.clone(),
            );
            Self::spawn_console_log_writer(
                vm_id,
                &pty_tx,
                vm_console_log(&vm_dir),
                ConsoleLogMode::Append,
            );
        }
        match live_pid {
            Some(pid) => info!(
                vm_id = %vm_id,
                pid = pid,
                op = operation_id.unwrap_or("-"),
                "re-derived runtime entry: adopted a live untracked VMM"
            ),
            None => info!(
                vm_id = %vm_id,
                op = operation_id.unwrap_or("-"),
                "re-derived runtime entry: no live VMM, start will re-spawn from the persisted payload"
            ),
        }
        Ok(())
    }

    /// The no-entry delete path (force-stop residual, create-window
    /// crash): the in-memory entry is gone while the persisted payload
    /// and stale sockets survive on disk. A delete's runtime goal is
    /// "no live VMM, no adapter-owned artifacts", so this proves no
    /// live VMM owns the runtime dir — reaping an untracked owner if
    /// one exists — and then removes the same artifact set as the
    /// tracked path. MUST be called with the VM's lifecycle op lock
    /// held (see `delete_vm`).
    ///
    /// Fail-closed discipline:
    /// - an unreadable `/proc` refuses the delete (a hidden live VMM is
    ///   exactly the stranded-guest hazard);
    /// - a live owner that survives the bounded SIGKILL+wait refuses
    ///   the delete with a retryable error — success is never claimed
    ///   while a VMM may still own the disk. The kill is exe-strict
    ///   (like every tracked kill), so an owner whose executable name
    ///   does not match `chv_binary` also lands here, conservatively.
    ///
    /// Returns `NotFound` when the VM demonstrably never ran on this
    /// node (no recorded runtime root, unsafe id, no persisted payload)
    /// — the misroute rule: a wrongly-addressed delete must surface,
    /// not be silently absorbed.
    async fn delete_untracked_vm(
        &self,
        vm_id: &str,
        operation_id: Option<&str>,
    ) -> Result<(), ChvError> {
        let not_found = || ChvError::NotFound {
            resource: "vm".to_string(),
            id: vm_id.to_string(),
        };
        let Some(vms_root) = self
            .vms_root
            .read()
            .expect("vms_root lock poisoned")
            .clone()
        else {
            // Adoption never ran (non-standard construction): keep
            // today's NotFound semantics rather than guess a layout.
            return Err(not_found());
        };
        // Layer-B path-safety (mirrors readopt_stopped_vm).
        if !is_safe_resource_id(vm_id) {
            return Err(not_found());
        }
        let vm_dir = vms_root.join("vms").join(vm_id);
        // The persisted creation payload is the evidence this VM once
        // ran on this node; without it the caller's contract is
        // re-create-required, not NotFound-absorb.
        if !vm_config_file(&vm_dir).is_file() {
            return Err(not_found());
        }
        let api_socket = vm_dir.join("vm.sock");

        match scan_live_vmm_on_socket(&api_socket) {
            UntrackedVmmScan::None => {}
            UntrackedVmmScan::Unreadable(e) => {
                warn!(
                    vm_id = %vm_id,
                    op = operation_id.unwrap_or("-"),
                    error = %e,
                    "delete refused: cannot prove no live VMM owns the runtime dir"
                );
                return Err(ChvError::Internal {
                    reason: format!(
                        "cannot delete vm {vm_id}: cannot determine whether a live cloud-hypervisor still owns its runtime dir ({e}); terminate any such process and retry"
                    ),
                });
            }
            UntrackedVmmScan::Found(pid) => {
                warn!(
                    vm_id = %vm_id,
                    op = operation_id.unwrap_or("-"),
                    pid = pid,
                    "reaping an untracked live VMM that owns the runtime dir"
                );
                let mut child = VmmChild::Adopted(pid);
                child.kill(&api_socket, self.expected_vmm_exe());
                child.wait().await;
                if pid_exists(pid) {
                    return Err(ChvError::Internal {
                        reason: format!(
                            "cannot delete vm {vm_id}: a live cloud-hypervisor process (pid {pid}) still owns its runtime dir and could not be reaped; terminate pid {pid} and retry"
                        ),
                    });
                }
            }
        }

        // The same adapter-owned artifact set as the tracked path; disk
        // images and the VM directory itself belong to the
        // storage/authority layers.
        let _ = tokio::fs::remove_file(&api_socket).await;
        let _ = tokio::fs::remove_file(vm_pid_file(&vm_dir)).await;
        let _ = tokio::fs::remove_file(vm_config_file(&vm_dir)).await;
        info!(
            vm_id = %vm_id,
            op = operation_id.unwrap_or("-"),
            "deleted untracked vm runtime (force-stop residual or crash window)"
        );
        Ok(())
    }

    /// Rebuilds the in-memory VM map from on-disk runtime state after an
    /// agent restart.
    ///
    /// The map is agent-process state; the VMMs it describes are not. A
    /// restart while VMs are running leaves re-parented orphans the new
    /// agent cannot see — every lifecycle op then fails with NotFound
    /// while the VMs keep running (proven by M2.5 qualification run 7:
    /// the post-restart stop and delete both failed this way). This scan
    /// rebuilds one entry per `{runtime_root}/vms/<vm_id>/` directory:
    ///
    /// - liveness and identity come from the persisted `ch.pid` plus a
    ///   `/proc/<pid>/cmdline` re-validation against the VM's api-socket
    ///   path (`pid_is_cloud_hypervisor`) — pid recycling can never
    ///   redirect a kill;
    /// - a live orphan gets its serial console re-attached (Socket
    ///   transport: reconnect to the listener the orphan still serves;
    ///   the broadcaster and console.log writer resume in append mode,
    ///   preserving pre-restart history) and is tracked as
    ///   [`VmmChild::Adopted`];
    /// - a dead VMM (cloud-hypervisor v43 exits with the guest) still
    ///   gets an entry — stop/delete are then idempotent and the next
    ///   start re-spawns from the persisted payload;
    /// - entries without a parseable `ch.pid` are skipped with a warning
    ///   (ops on them keep today's NotFound semantics rather than
    ///   guessing at process identity);
    /// - Pty-transport VMs are adopted for lifecycle only: the console
    ///   endpoint cannot be re-derived without a live `vm.info` and is a
    ///   recorded follow-up.
    ///
    /// Failures are per-directory (warn + skip); only an unreadable base
    /// directory fails the call.
    pub async fn adopt_running_vms(&self, runtime_root: &std::path::Path) -> Result<(), ChvError> {
        // Record the runtime root BEFORE any early return: lifecycle
        // paths (start after a force stop, the delete liveness gate)
        // need to re-derive entries from this layout even when there is
        // nothing to adopt yet (empty or missing vms/ tree).
        *self.vms_root.write().expect("vms_root lock poisoned") = Some(runtime_root.to_path_buf());
        let vms_base = runtime_root.join("vms");
        let entries = match std::fs::read_dir(&vms_base) {
            Ok(entries) => entries,
            Err(e) if e.kind() == std::io::ErrorKind::NotFound => {
                // No VMs have ever been created on this node.
                return Ok(());
            }
            Err(e) => {
                return Err(ChvError::Io {
                    path: vms_base.to_string_lossy().to_string(),
                    source: e,
                });
            }
        };

        for entry in entries.flatten() {
            let Ok(file_type) = entry.file_type() else {
                continue;
            };
            if !file_type.is_dir() {
                continue;
            }
            let vm_id = entry.file_name().to_string_lossy().to_string();
            // Layer-B path-safety: the directory name becomes a map key
            // and (via start) a re-spawn source; never build entries for
            // ids the authority layer would reject.
            if !is_safe_resource_id(&vm_id) {
                warn!(vm_id = %vm_id, "skipping vm runtime dir with unsafe id during adoption");
                continue;
            }
            let vm_dir = entry.path();
            let api_socket = vm_dir.join("vm.sock");

            // Never adopt over a tracked entry: a second adoption pass
            // (or a split-brain peer agent on the same runtime root) must
            // not replace an Owned child with an Adopted pid — dropping
            // the Child would orphan a VMM this agent is responsible for
            // reaping.
            if self.vms.read().await.contains_key(&vm_id) {
                warn!(
                    vm_id = %vm_id,
                    "skipping adoption: vm is already tracked by this agent"
                );
                continue;
            }

            let pid = std::fs::read_to_string(vm_pid_file(&vm_dir))
                .ok()
                .and_then(|raw| raw.trim().parse::<u32>().ok());
            let Some(pid) = pid else {
                warn!(
                    vm_id = %vm_id,
                    "skipping vm runtime dir without a parseable ch.pid during adoption"
                );
                continue;
            };

            let vmm_alive = pid_is_cloud_hypervisor(pid, &api_socket, self.expected_vmm_exe());
            let serial_sock = vm_dir.join("serial.sock");
            let serial_transport = if serial_sock.exists() {
                SerialTransport::Socket(serial_sock)
            } else {
                SerialTransport::Pty
            };

            // Re-attach the console only for a live VMM on the Socket
            // transport; anything else gets the EOF placeholder (an
            // honest "no console" endpoint — the broadcaster, if ever
            // spawned on it, exits immediately).
            let (console_io, console_live) = if vmm_alive {
                match &serial_transport {
                    SerialTransport::Socket(path) => {
                        match Self::connect_serial_socket_once(path).await {
                            Ok(fd) => (fd, true),
                            Err(e) => {
                                warn!(
                                    vm_id = %vm_id,
                                    error = %e,
                                    "serial re-attach failed during adoption; console capture stays down"
                                );
                                (Self::eof_placeholder_fd(), false)
                            }
                        }
                    }
                    SerialTransport::Pty => (Self::eof_placeholder_fd(), false),
                }
            } else {
                (Self::eof_placeholder_fd(), false)
            };

            let (pty_tx, _) = tokio::sync::broadcast::channel::<Vec<u8>>(4096);
            let pty_scrollback = Arc::new(std::sync::RwLock::new(Vec::new()));
            // Take the broadcaster's endpoint BEFORE the entry consumes
            // console_io, so the map never needs to be re-read on the
            // just-inserted entry. Capture is only claimed alive when the
            // dup (and with it the broadcaster spawn) actually happens.
            let broadcaster_fd = if console_live {
                Self::dup_cloexec(&console_io).ok()
            } else {
                None
            };
            let broadcaster_alive = Arc::new(AtomicBool::new(broadcaster_fd.is_some()));

            {
                let mut map = self.vms.write().await;
                map.insert(
                    vm_id.clone(),
                    VmProcess {
                        api_socket: api_socket.clone(),
                        child: VmmChild::Adopted(pid),
                        console_io,
                        serial_transport: serial_transport.clone(),
                        pty_tx: pty_tx.clone(),
                        pty_scrollback: pty_scrollback.clone(),
                        broadcaster_alive: broadcaster_alive.clone(),
                        last_cpu_seconds: 0.0,
                        last_cpu_at: None,
                        boot_watermark: AtomicU64::new(0),
                    },
                );
            }

            if let Some(broadcaster_fd) = broadcaster_fd {
                Self::spawn_pty_broadcaster(
                    self.vms.clone(),
                    vm_id.clone(),
                    broadcaster_fd,
                    serial_transport,
                    pty_tx.clone(),
                    pty_scrollback.clone(),
                    broadcaster_alive,
                    self.console_draining.clone(),
                );
                Self::spawn_console_log_writer(
                    &vm_id,
                    &pty_tx,
                    vm_console_log(&vm_dir),
                    ConsoleLogMode::Append,
                );
                info!(
                    vm_id = %vm_id,
                    pid = pid,
                    "adopted running vm after agent restart; console capture resumed"
                );
            } else if vmm_alive {
                info!(
                    vm_id = %vm_id,
                    pid = pid,
                    "adopted running vm after agent restart (console not re-attached)"
                );
            } else {
                info!(
                    vm_id = %vm_id,
                    "adopted stopped vm runtime dir after agent restart"
                );
            }
        }
        Ok(())
    }

    /// A read-only fd whose reads return EOF immediately — the
    /// placeholder console endpoint for adopted entries with no live
    /// connection. Lifecycle paths see an honest "no console" state
    /// instead of a guessed-at endpoint. Reachability notes: `reboot_vm`'s
    /// forced rotation can never touch it (rotation happens only after a
    /// 2xx `vm.reboot`, which a dead VMM's missing api socket can never
    /// answer), and console keystrokes written to it fail with EPIPE —
    /// an honest error for a VM whose console is down.
    fn eof_placeholder_fd() -> OwnedFd {
        match nix::unistd::pipe() {
            // Dropping the write end makes the read end return EOF.
            Ok((read_end, write_end)) => {
                drop(write_end);
                read_end
            }
            Err(_) => {
                // /dev/null reads EOF forever — the last-resort stand-in.
                std::fs::File::open("/dev/null")
                    .expect("/dev/null must open")
                    .into()
            }
        }
    }
}

#[cfg(test)]
mod tests {
    use super::build_cpus_config;
    use super::cloud_init_meta_data;
    use super::parse_http_status;
    use super::ProcessCloudHypervisorAdapter;
    use super::SerialTransport;
    use super::VmProcess;
    use super::VmmChild;
    use crate::adapter::{CloudHypervisorAdapter, VmConfig, VmDiskConfig};
    use chv_common::hypervisor::HypervisorOverrides;
    use chv_errors::ChvError;
    use std::os::fd::{AsRawFd, OwnedFd};
    use std::path::PathBuf;
    use std::sync::atomic::{AtomicBool, AtomicU64, Ordering};
    use std::sync::Arc;

    #[test]
    fn parse_http_status_extracts_200() {
        let bytes = b"HTTP/1.1 200 OK\r\nContent-Length: 0\r\n\r\n";
        assert_eq!(parse_http_status(bytes), Some(200));
    }

    // #374: an all-digit vm_id must stay a YAML STRING in the NoCloud
    // seed's meta-data. Unquoted, `local-hostname: 74074613` parses as an
    // int and crashes cloud-init 26.1's metadata standardization — the
    // entire datasource is then discarded and userdata/network-config are
    // silently never applied. Found by the M4.5 storage scenario (run 2):
    // the VM's id was all digits; M4.4's VMs (ids containing letters) never
    // triggered it.
    #[test]
    fn cloud_init_meta_data_is_string_typed_for_all_digit_ids() {
        let meta_data = cloud_init_meta_data("74074613");
        let parsed: serde_yaml::Value =
            serde_yaml::from_str(&meta_data).expect("meta-data must be valid YAML");
        assert!(
            parsed["local-hostname"].is_string(),
            "local-hostname must be a YAML string, got: {:?}",
            parsed["local-hostname"]
        );
        assert!(
            parsed["instance-id"].is_string(),
            "instance-id must be a YAML string, got: {:?}",
            parsed["instance-id"]
        );
        assert_eq!(parsed["local-hostname"].as_str(), Some("74074613"));
        assert_eq!(parsed["instance-id"].as_str(), Some("74074613"));
    }

    // Control for #374: ids containing letters were always strings — the
    // hostname VALUE must be unchanged by the fix (only its YAML type).
    #[test]
    fn cloud_init_meta_data_preserves_the_hostname_value() {
        let meta_data = cloud_init_meta_data("17b2c9d5");
        let parsed: serde_yaml::Value =
            serde_yaml::from_str(&meta_data).expect("meta-data must be valid YAML");
        assert_eq!(parsed["local-hostname"].as_str(), Some("17b2c9d5"));
        assert_eq!(parsed["instance-id"].as_str(), Some("17b2c9d5"));
    }

    #[test]
    fn parse_http_status_extracts_204() {
        let bytes = b"HTTP/1.1 204 No Content\r\n";
        assert_eq!(parse_http_status(bytes), Some(204));
    }

    #[test]
    fn parse_http_status_returns_none_for_garbage() {
        assert_eq!(parse_http_status(b"garbage"), None);
    }

    #[test]
    fn parse_http_status_handles_empty() {
        assert_eq!(parse_http_status(b""), None);
    }

    #[test]
    fn serial_console_config_socket_mode_carries_listener_path() {
        // Socket is the default transport: the config must point
        // cloud-hypervisor at the per-VM listener the agent connects to —
        // a bare mode string would silently fall back to the pty, whose
        // v43 output gate swallows passive console capture.
        let value = ProcessCloudHypervisorAdapter::serial_console_config(
            "Socket",
            std::path::Path::new("/run/chv/vms/vm-1/serial.sock"),
        );
        assert_eq!(value["mode"], serde_json::json!("Socket"));
        assert_eq!(
            value["socket"],
            serde_json::json!("/run/chv/vms/vm-1/serial.sock")
        );
    }

    #[test]
    fn serial_console_config_passes_other_modes_through() {
        for mode in ["Pty", "File", "Null", "Off"] {
            let value = ProcessCloudHypervisorAdapter::serial_console_config(
                mode,
                std::path::Path::new("/run/chv/vms/vm-1/serial.sock"),
            );
            assert_eq!(value["mode"], serde_json::json!(mode));
            assert!(value.get("socket").is_none());
        }
    }

    #[tokio::test]
    async fn connect_serial_socket_returns_blocking_cloexec_fd() {
        let dir = tempfile::tempdir_in(std::env::current_dir().unwrap()).unwrap();
        let socket_path = dir.path().join("serial.sock");
        let listener = tokio::net::UnixListener::bind(&socket_path).unwrap();
        let mut child = tokio::process::Command::new("sleep")
            .arg("30")
            .spawn()
            .unwrap();

        let fd = ProcessCloudHypervisorAdapter::connect_serial_socket(
            &socket_path,
            &mut child,
            "vm-test",
            None,
        )
        .await
        .expect("connect must succeed against a bound listener");

        // The broadcaster and console server issue plain blocking
        // reads/writes; a non-blocking fd would EAGAIN and silently kill
        // console capture.
        let status_flags =
            nix::fcntl::fcntl(&fd, nix::fcntl::F_GETFL).expect("fd flags must be readable");
        assert_eq!(
            nix::fcntl::OFlag::from_bits_retain(status_flags) & nix::fcntl::OFlag::O_NONBLOCK,
            nix::fcntl::OFlag::empty(),
            "serial socket fd must be blocking"
        );
        let fd_flags =
            nix::fcntl::fcntl(&fd, nix::fcntl::F_GETFD).expect("fd flags must be readable");
        assert_ne!(
            fd_flags & nix::fcntl::FdFlag::FD_CLOEXEC.bits(),
            0,
            "serial socket fd must be CLOEXEC"
        );
        // The connect contract keeps the spawned VMM alive on success —
        // only the failure path kills the child.
        assert!(
            child.try_wait().unwrap().is_none(),
            "child must still be running after a successful serial connect"
        );
        // The accepted listener end must be drained by the helper's
        // connect having completed the handshake (no deadlock risk from an
        // unread backlog is asserted implicitly by the connect succeeding).
        drop(listener);
        let _ = child.start_kill();
        let _ = child.wait().await;
    }

    #[tokio::test]
    async fn connect_serial_socket_fails_closed_and_kills_child_without_listener() {
        let dir = tempfile::tempdir_in(std::env::current_dir().unwrap()).unwrap();
        let socket_path = dir.path().join("serial.sock");
        let mut child = tokio::process::Command::new("sleep")
            .arg("30")
            .spawn()
            .unwrap();

        let err = ProcessCloudHypervisorAdapter::connect_serial_socket(
            &socket_path,
            &mut child,
            "vm-test",
            None,
        )
        .await
        .expect_err("connect must fail with no listener");

        assert!(matches!(err, ChvError::Io { .. }));
        let status = child.try_wait().unwrap().expect("child must be reaped");
        assert!(!status.success(), "the spawned child must be killed");
    }

    #[test]
    fn dup_cloexec_sets_cloexec_and_carries_data() {
        use std::io::Write as _;

        let (a, mut b) = std::os::unix::net::UnixStream::pair().unwrap();
        let owned: OwnedFd = a.into();
        let dup = ProcessCloudHypervisorAdapter::dup_cloexec(&owned).expect("dup must succeed");

        // FD_CLOEXEC is per-descriptor: the dup must carry it.
        let fd_flags = nix::fcntl::fcntl(&dup, nix::fcntl::F_GETFD).unwrap();
        assert_ne!(
            fd_flags & nix::fcntl::FdFlag::FD_CLOEXEC.bits(),
            0,
            "dup must be CLOEXEC"
        );

        // The dup is a live view of the same open file description: data
        // written to the peer arrives through the dup...
        b.write_all(b"x").unwrap();
        let mut buf = [0u8; 1];
        let n = nix::unistd::read(&dup, &mut buf).unwrap();
        assert_eq!((n, buf[0]), (1, b'x'));

        // ...and the source fd is still open and usable (the dup did not
        // consume it).
        b.write_all(b"y").unwrap();
        let mut buf = [0u8; 1];
        let n = nix::unistd::read(&owned, &mut buf).unwrap();
        assert_eq!((n, buf[0]), (1, b'y'));
    }

    #[tokio::test]
    async fn respawn_broadcaster_reconnects_and_swaps_dead_socket() {
        use std::io::Write as _;

        let dir = tempfile::tempdir_in(std::env::current_dir().unwrap()).unwrap();
        let vm_dir = dir.path().join("vm-respawn");
        std::fs::create_dir_all(&vm_dir).unwrap();
        let sock_path = dir.path().join("serial.sock");

        // Stand in for cloud-hypervisor's serial listener: accept one
        // connection and immediately stream a probe byte (guest output).
        let listener = std::os::unix::net::UnixListener::bind(&sock_path).unwrap();
        let acceptor = std::thread::spawn(move || {
            let (mut conn, _) = listener.accept().expect("accept");
            conn.write_all(b"probe").expect("write probe");
            std::thread::sleep(std::time::Duration::from_millis(1500));
        });

        let adapter = ProcessCloudHypervisorAdapter::new(dir.path().join("chv"));
        let (pty_tx, _) = tokio::sync::broadcast::channel::<Vec<u8>>(4096);
        let pty_scrollback = Arc::new(std::sync::RwLock::new(Vec::new()));
        let broadcaster_alive = Arc::new(AtomicBool::new(false));
        let mut child = tokio::process::Command::new("true").spawn().unwrap();
        let _ = child.wait().await;
        // A dead stand-in for a VMM-closed serial connection.
        let dead_console_io: OwnedFd = std::fs::File::open("/dev/null").unwrap().into();
        let dead_fd = dead_console_io.as_raw_fd();

        {
            let mut map = adapter.vms.write().await;
            map.insert(
                "vm-respawn".to_string(),
                VmProcess {
                    api_socket: vm_dir.join("vm.sock"),
                    child: VmmChild::Owned(child),
                    console_io: dead_console_io,
                    serial_transport: SerialTransport::Socket(sock_path.clone()),
                    pty_tx: pty_tx.clone(),
                    pty_scrollback: pty_scrollback.clone(),
                    broadcaster_alive: broadcaster_alive.clone(),
                    last_cpu_seconds: 0.0,
                    last_cpu_at: None,
                    boot_watermark: AtomicU64::new(0),
                },
            );
        }

        // Subscribe before the respawn so the broadcaster's fan-out is
        // observable.
        let mut rx = pty_tx.subscribe();
        adapter
            .respawn_broadcaster_if_dead(
                "vm-respawn",
                &SerialTransport::Socket(sock_path),
                &pty_tx,
                &pty_scrollback,
                &broadcaster_alive,
            )
            .await;

        assert!(
            broadcaster_alive.load(Ordering::SeqCst),
            "broadcaster must be alive after respawn"
        );

        // The stored connection was swapped for the live one (the dead
        // fd stays owned by the map entry until the swap, so the numbers
        // must differ).
        let map = adapter.vms.read().await;
        let proc = map.get("vm-respawn").unwrap();
        assert_ne!(
            proc.console_io.as_raw_fd(),
            dead_fd,
            "stored console fd must be swapped for the reconnected one"
        );
        drop(map);

        // The respawned broadcaster streams guest output from the fresh
        // connection through the fan-out channel.
        let got = tokio::time::timeout(std::time::Duration::from_secs(3), rx.recv())
            .await
            .expect("probe must arrive through the fan-out")
            .expect("channel must be live");
        assert_eq!(got, b"probe".to_vec());

        // The reconnect handshake completed on the listener side too.
        acceptor.join().expect("acceptor thread");
    }

    #[tokio::test]
    async fn respawn_broadcaster_redups_pty_transport() {
        use std::io::Write as _;

        let dir = tempfile::tempdir_in(std::env::current_dir().unwrap()).unwrap();
        let vm_dir = dir.path().join("vm-respawn-pty");
        std::fs::create_dir_all(&vm_dir).unwrap();

        let adapter = ProcessCloudHypervisorAdapter::new(dir.path().join("chv"));
        let (pty_tx, _) = tokio::sync::broadcast::channel::<Vec<u8>>(4096);
        let pty_scrollback = Arc::new(std::sync::RwLock::new(Vec::new()));
        let broadcaster_alive = Arc::new(AtomicBool::new(false));
        let mut child = tokio::process::Command::new("true").spawn().unwrap();
        let _ = child.wait().await;
        let (a, mut b) = std::os::unix::net::UnixStream::pair().unwrap();
        let console_io: OwnedFd = a.into();
        let original_fd = console_io.as_raw_fd();

        {
            let mut map = adapter.vms.write().await;
            map.insert(
                "vm-respawn-pty".to_string(),
                VmProcess {
                    api_socket: vm_dir.join("vm.sock"),
                    child: VmmChild::Owned(child),
                    console_io,
                    serial_transport: SerialTransport::Pty,
                    pty_tx: pty_tx.clone(),
                    pty_scrollback: pty_scrollback.clone(),
                    broadcaster_alive: broadcaster_alive.clone(),
                    last_cpu_seconds: 0.0,
                    last_cpu_at: None,
                    boot_watermark: AtomicU64::new(0),
                },
            );
        }

        let mut rx = pty_tx.subscribe();
        adapter
            .respawn_broadcaster_if_dead(
                "vm-respawn-pty",
                &SerialTransport::Pty,
                &pty_tx,
                &pty_scrollback,
                &broadcaster_alive,
            )
            .await;

        assert!(
            broadcaster_alive.load(Ordering::SeqCst),
            "broadcaster must be alive after respawn"
        );

        // The pty transport re-dups the stored slave; the stored fd is NOT
        // swapped (the kernel keeps the pty pair alive across reboots).
        let map = adapter.vms.read().await;
        let proc = map.get("vm-respawn-pty").unwrap();
        assert_eq!(
            proc.console_io.as_raw_fd(),
            original_fd,
            "pty transport must keep the stored slave fd"
        );
        drop(map);

        // The broadcaster reads through the dup: output written to the
        // peer end arrives through the fan-out channel.
        b.write_all(b"probe").unwrap();
        let got = tokio::time::timeout(std::time::Duration::from_secs(3), rx.recv())
            .await
            .expect("probe must arrive through the fan-out")
            .expect("channel must be live");
        assert_eq!(got, b"probe".to_vec());
    }

    #[tokio::test]
    async fn broadcaster_self_heals_across_listener_rebind() {
        use std::io::Write as _;

        let dir = tempfile::tempdir_in(std::env::current_dir().unwrap()).unwrap();
        let vm_dir = dir.path().join("vm-heal");
        std::fs::create_dir_all(&vm_dir).unwrap();
        let sock_path = dir.path().join("serial.sock");

        // Stand in for cloud-hypervisor's serial lifecycle across a
        // vm.reboot: SerialManager::drop closes the accepted connection
        // AND removes the socket file while dropping the listener, then
        // pre_create_console_devices re-binds a fresh listener at the same
        // path and the new guest's output must flow to a reconnecting
        // client.
        let rebind_path = sock_path.clone();
        let listener1 = std::os::unix::net::UnixListener::bind(&sock_path).unwrap();
        let server = std::thread::spawn(move || {
            let (mut conn1, _) = listener1.accept().expect("accept 1");
            conn1.write_all(b"first").expect("write first");
            // vm.reboot: tear the serial device down — the listener first
            // (so no reconnect can land in a doomed accept backlog), then
            // the accepted connection (whose close is what signals EOF to
            // the broadcaster) — and re-bind a fresh listener at the same
            // path, exactly as pre_create_console_devices does after
            // SerialManager::drop removed the socket file.
            drop(listener1);
            drop(conn1);
            std::fs::remove_file(&rebind_path).unwrap();
            let listener2 = std::os::unix::net::UnixListener::bind(&rebind_path).unwrap();
            let (mut conn2, _) = listener2.accept().expect("accept 2");
            conn2.write_all(b"second").expect("write second");
            // Hold the new connection open while the test asserts.
            std::thread::sleep(std::time::Duration::from_millis(2500));
        });

        let adapter = ProcessCloudHypervisorAdapter::new(dir.path().join("chv"));
        let (pty_tx, _) = tokio::sync::broadcast::channel::<Vec<u8>>(4096);
        let pty_scrollback = Arc::new(std::sync::RwLock::new(Vec::new()));
        let broadcaster_alive = Arc::new(AtomicBool::new(false));
        let mut child = tokio::process::Command::new("true").spawn().unwrap();
        let _ = child.wait().await;
        // A dead stand-in for a VMM-closed serial connection.
        let dead_console_io: OwnedFd = std::fs::File::open("/dev/null").unwrap().into();
        let dead_fd = dead_console_io.as_raw_fd();

        {
            let mut map = adapter.vms.write().await;
            map.insert(
                "vm-heal".to_string(),
                VmProcess {
                    api_socket: vm_dir.join("vm.sock"),
                    child: VmmChild::Owned(child),
                    console_io: dead_console_io,
                    serial_transport: SerialTransport::Socket(sock_path.clone()),
                    pty_tx: pty_tx.clone(),
                    pty_scrollback: pty_scrollback.clone(),
                    broadcaster_alive: broadcaster_alive.clone(),
                    last_cpu_seconds: 0.0,
                    last_cpu_at: None,
                    boot_watermark: AtomicU64::new(0),
                },
            );
        }

        let mut rx = pty_tx.subscribe();
        adapter
            .respawn_broadcaster_if_dead(
                "vm-heal",
                &SerialTransport::Socket(sock_path.clone()),
                &pty_tx,
                &pty_scrollback,
                &broadcaster_alive,
            )
            .await;
        assert!(
            broadcaster_alive.load(Ordering::SeqCst),
            "broadcaster must be alive after respawn"
        );

        // First probe arrives through the first connection, and the dead
        // stored fd was swapped for the live one.
        let got = tokio::time::timeout(std::time::Duration::from_secs(3), rx.recv())
            .await
            .expect("first probe must arrive through the fan-out")
            .expect("channel must be live");
        assert_eq!(got, b"first".to_vec());
        let fd_after_first = {
            let map = adapter.vms.read().await;
            let proc = map.get("vm-heal").unwrap();
            assert_ne!(
                proc.console_io.as_raw_fd(),
                dead_fd,
                "stored console fd must be swapped for the reconnected one"
            );
            proc.console_io.as_raw_fd()
        };

        // Across the simulated reboot (connection closed, listener dropped
        // and re-bound at the same path), the broadcaster SELF-HEALS: the
        // second probe arrives through the new connection, the stored fd
        // is swapped again, and the broadcaster never dies.
        let got = tokio::time::timeout(std::time::Duration::from_secs(5), rx.recv())
            .await
            .expect("second probe must arrive after the self-heal")
            .expect("channel must be live");
        assert_eq!(got, b"second".to_vec());
        assert!(
            broadcaster_alive.load(Ordering::SeqCst),
            "broadcaster must survive the connection cycle without respawning"
        );
        {
            let map = adapter.vms.read().await;
            let proc = map.get("vm-heal").unwrap();
            assert_ne!(
                proc.console_io.as_raw_fd(),
                fd_after_first,
                "stored console fd must be swapped across the self-heal"
            );
        }

        server.join().expect("server thread");
    }

    /// Issue #469, leg-02 §4.3 (E3/E3f): pins the drain-continuously
    /// property of the console reader against a stand-in that reproduces
    /// cloud-hypervisor v53.0's #8322 flush behavior — the backlog is
    /// written ONE byte per `write()` syscall on a NON-BLOCKING socket,
    /// and a `WouldBlock` (EAGAIN, ~one socket-fill of one-byte skbs)
    /// ends the flush session: delivery only resumes on the next
    /// "guest output" trigger. A reader with inter-read gaps truncates
    /// every session (quiet guest: ~278 B hard stop; trickling guest:
    /// ~0.6–1.3 KB/s crawl — the measured crawl regime); a reader that
    /// drains continuously keeps the socket empty and the FIRST session
    /// pushes the whole backlog in one pass (E3f: ~72.7 KB in 0.4 s).
    /// The stand-in grants only a few re-trigger rounds, so a reader
    /// that parks between reads cannot recover a 96 KiB backlog (a
    /// parked reader moves ~one socket-fill, ~278 B, per round).
    #[tokio::test]
    async fn broadcaster_recovers_the_full_backlog_from_ch_flush_sessions() {
        use std::io::Write as _;

        let dir = tempfile::tempdir_in(std::env::current_dir().unwrap()).unwrap();
        let vm_dir = dir.path().join("vm-flush");
        std::fs::create_dir_all(&vm_dir).unwrap();
        let sock_path = dir.path().join("serial.sock");

        // The backlog: 96 KiB of patterned "console" bytes — far past one
        // socket-fill, in the E3f regime (a ~74 KiB boot's worth).
        let backlog: Vec<u8> = (0..96 * 1024).map(|i| (i % 251) as u8).collect();
        let breaks = Arc::new(std::sync::atomic::AtomicUsize::new(0));

        // Stand-in for cloud-hypervisor v53.0's serial-manager flush
        // sessions (see the test doc): accept, then push the backlog one
        // byte per write; a WouldBlock ENDS the session (CH has no
        // EPOLLOUT retry — the defect), and the next "guest output"
        // trigger starts a new one 100 ms later.
        let listener = std::os::unix::net::UnixListener::bind(&sock_path).unwrap();
        let standin_breaks = breaks.clone();
        let standin_backlog = backlog.clone();
        let standin = std::thread::spawn(move || {
            let (mut conn, _) = listener.accept().expect("accept");
            conn.set_nonblocking(true).expect("set nonblocking");
            let mut written = 0usize;
            while written < standin_backlog.len() {
                match conn.write(&standin_backlog[written..written + 1]) {
                    Ok(_) => written += 1,
                    Err(e) if e.kind() == std::io::ErrorKind::WouldBlock => {
                        // Flush session broke on EAGAIN — exactly CH's
                        // silent `flush()` break. Wait for the next guest
                        // output trigger before retrying.
                        standin_breaks.fetch_add(1, Ordering::SeqCst);
                        std::thread::sleep(std::time::Duration::from_millis(100));
                    }
                    Err(e) => panic!("stand-in write failed: {e}"),
                }
            }
            // Hold the connection open while the test asserts (a close
            // would rotate the broadcaster into a reconnect).
            std::thread::sleep(std::time::Duration::from_millis(2500));
            conn
        });

        let adapter = ProcessCloudHypervisorAdapter::new(dir.path().join("chv"));
        let (pty_tx, _) = tokio::sync::broadcast::channel::<Vec<u8>>(4096);
        let pty_scrollback = Arc::new(std::sync::RwLock::new(Vec::new()));
        let broadcaster_alive = Arc::new(AtomicBool::new(false));
        let mut child = tokio::process::Command::new("true").spawn().unwrap();
        let _ = child.wait().await;
        let dead_console_io: OwnedFd = std::fs::File::open("/dev/null").unwrap().into();

        {
            let mut map = adapter.vms.write().await;
            map.insert(
                "vm-flush".to_string(),
                VmProcess {
                    api_socket: vm_dir.join("vm.sock"),
                    child: VmmChild::Owned(child),
                    console_io: dead_console_io,
                    serial_transport: SerialTransport::Socket(sock_path.clone()),
                    pty_tx: pty_tx.clone(),
                    pty_scrollback: pty_scrollback.clone(),
                    broadcaster_alive: broadcaster_alive.clone(),
                    last_cpu_seconds: 0.0,
                    last_cpu_at: None,
                    boot_watermark: AtomicU64::new(0),
                },
            );
        }

        // Reattach the reader — the same path adoption and the
        // broadcaster heal use.
        adapter
            .respawn_broadcaster_if_dead(
                "vm-flush",
                &SerialTransport::Socket(sock_path),
                &pty_tx,
                &pty_scrollback,
                &broadcaster_alive,
            )
            .await;
        assert!(
            broadcaster_alive.load(Ordering::SeqCst),
            "broadcaster must be alive after respawn"
        );

        // The whole backlog must land in the scrollback, byte-exact, well
        // inside the deadline — the E3f one-pass behavior.
        let deadline = std::time::Instant::now() + std::time::Duration::from_secs(10);
        loop {
            let received = pty_scrollback
                .read()
                .expect("scrollback lock poisoned")
                .clone();
            if received == backlog {
                break;
            }
            assert!(
                std::time::Instant::now() < deadline,
                "the drain-continuously reader must recover the full backlog; \
                 got {}/{} bytes",
                received.len(),
                backlog.len()
            );
            tokio::time::sleep(std::time::Duration::from_millis(25)).await;
        }

        // The fan-out channel is fed as well: the drain loop broadcasts
        // every chunk. (The scrollback check above pins byte-exactness;
        // existing tests — e.g. `respawn_broadcaster_reconnects_and_
        // swaps_dead_socket` — pin the channel path, and a receiver that
        // falls behind a 96 KiB single-pass backlog legitimately Lags —
        // the broadcast contract, same as the console.log writer.)
        assert!(
            broadcaster_alive.load(Ordering::SeqCst),
            "the broadcaster must still be alive after the full-backlog pass"
        );

        // The whole backlog landed without the stand-in ever seeing its
        // flush sessions truncated by a full socket: a continuously
        // draining reader needs ~zero re-trigger rounds, while a reader
        // that parks between reads needs one round per ~278 B socket-fill
        // (96 KiB would need ~350). The bound leaves generous scheduling
        // slack while still discriminating decisively.
        assert!(
            breaks.load(Ordering::SeqCst) <= 16,
            "flush sessions kept breaking on backpressure ({} breaks) — \
             the reader is not draining continuously",
            breaks.load(Ordering::SeqCst)
        );

        drop(standin.join().expect("stand-in thread"));
    }

    /// Issue #469, v43-era family (leg 02 §4.2): a serial manager whose
    /// client socket writes BLOCK (v43's shape) stalls the VMM vCPU when
    /// the client stops draining — each UART byte is a separate 1-byte
    /// skb filling `sk_sndbuf`. The agent reader must therefore keep
    /// draining a continuous stream even when the peer's send buffer is
    /// tiny: this stand-in writes 128 KiB one byte at a time on a
    /// BLOCKING socket with a minimal `SO_SNDBUF`; a reader that parks
    /// blocks the stand-in forever (the write side fills) and the test
    /// times out, while a continuously draining reader lets the whole
    /// stream through.
    #[tokio::test]
    async fn broadcaster_keeps_draining_a_blocking_serial_stream() {
        use std::io::Write as _;

        let dir = tempfile::tempdir_in(std::env::current_dir().unwrap()).unwrap();
        let vm_dir = dir.path().join("vm-blocking");
        std::fs::create_dir_all(&vm_dir).unwrap();
        let sock_path = dir.path().join("serial.sock");

        let stream: Vec<u8> = (0..128 * 1024).map(|i| (i % 249) as u8).collect();
        let listener = std::os::unix::net::UnixListener::bind(&sock_path).unwrap();
        let standin_stream = stream.clone();
        let standin = std::thread::spawn(move || {
            let (mut conn, _) = listener.accept().expect("accept");
            nix::sys::socket::setsockopt(&conn, nix::sys::socket::sockopt::SndBuf, &4096usize)
                .expect("shrink SO_SNDBUF");
            for byte in &standin_stream {
                conn.write_all(std::slice::from_ref(byte))
                    .expect("stand-in write must not stall on a draining reader");
            }
            std::thread::sleep(std::time::Duration::from_millis(2500));
            conn
        });

        let adapter = ProcessCloudHypervisorAdapter::new(dir.path().join("chv"));
        let (pty_tx, _) = tokio::sync::broadcast::channel::<Vec<u8>>(4096);
        let pty_scrollback = Arc::new(std::sync::RwLock::new(Vec::new()));
        let broadcaster_alive = Arc::new(AtomicBool::new(false));
        let mut child = tokio::process::Command::new("true").spawn().unwrap();
        let _ = child.wait().await;
        let dead_console_io: OwnedFd = std::fs::File::open("/dev/null").unwrap().into();

        {
            let mut map = adapter.vms.write().await;
            map.insert(
                "vm-blocking".to_string(),
                VmProcess {
                    api_socket: vm_dir.join("vm.sock"),
                    child: VmmChild::Owned(child),
                    console_io: dead_console_io,
                    serial_transport: SerialTransport::Socket(sock_path.clone()),
                    pty_tx: pty_tx.clone(),
                    pty_scrollback: pty_scrollback.clone(),
                    broadcaster_alive: broadcaster_alive.clone(),
                    last_cpu_seconds: 0.0,
                    last_cpu_at: None,
                    boot_watermark: AtomicU64::new(0),
                },
            );
        }

        adapter
            .respawn_broadcaster_if_dead(
                "vm-blocking",
                &SerialTransport::Socket(sock_path),
                &pty_tx,
                &pty_scrollback,
                &broadcaster_alive,
            )
            .await;
        assert!(
            broadcaster_alive.load(Ordering::SeqCst),
            "broadcaster must be alive after respawn"
        );

        let deadline = std::time::Instant::now() + std::time::Duration::from_secs(10);
        loop {
            let received = pty_scrollback
                .read()
                .expect("scrollback lock poisoned")
                .clone();
            if received == stream {
                break;
            }
            assert!(
                std::time::Instant::now() < deadline,
                "the reader must keep draining a continuous blocking stream; \
                 got {}/{} bytes",
                received.len(),
                stream.len()
            );
            tokio::time::sleep(std::time::Duration::from_millis(25)).await;
        }

        drop(standin.join().expect("stand-in thread"));
    }

    /// Pins the exact AF_UNIX kernel semantics the clean-disconnect
    /// machinery relies on. Root cause of the M2.5 guest freeze: an
    /// agent-side close with unread receive-queue data RESETS the
    /// connection, and cloud-hypervisor v43's serial manager dies
    /// silently on the resulting ECONNRESET. If a kernel behavior change
    /// ever breaks these assertions, the drain-before-close discipline
    /// must be re-evaluated.
    #[tokio::test]
    async fn serial_close_semantics_regression() {
        use std::io::{Read as _, Write as _};

        // Negative control — the defect model itself: the "serial
        // manager" writes a burst, the client closes WITHOUT draining,
        // and the manager's next read observes ECONNRESET (not EOF).
        {
            let (mut manager, client) = std::os::unix::net::UnixStream::pair().unwrap();
            manager.write_all(b"guest boot burst").unwrap();
            // Let the bytes land in the client's receive queue.
            std::thread::sleep(std::time::Duration::from_millis(50));
            drop(client); // abortive: unread data still queued
            let mut buf = [0u8; 64];
            let err = manager.read(&mut buf).unwrap_err();
            assert_eq!(
                err.kind(),
                std::io::ErrorKind::ConnectionReset,
                "close with unread receive-queue data must reset the connection (defect model)"
            );
        }

        // The fix's semantics: half-close, settle, drain, then drop —
        // the manager observes a clean EOF instead.
        {
            let (mut manager, client) = std::os::unix::net::UnixStream::pair().unwrap();
            manager.write_all(b"guest boot burst").unwrap();
            std::thread::sleep(std::time::Duration::from_millis(50));
            let client_fd: OwnedFd = client.into();
            ProcessCloudHypervisorAdapter::abandon_serial_connection(
                "vm-semantics",
                client_fd,
                None,
            )
            .await;
            let mut buf = [0u8; 64];
            let n = manager
                .read(&mut buf)
                .unwrap_or_else(|e| panic!("manager must observe a clean EOF, not {e:?}"));
            assert_eq!(n, 0, "manager must observe EOF after a clean abandon");
        }
    }

    /// `drain_and_close_consoles` converts agent shutdown into the clean
    /// close cloud-hypervisor handles correctly: the serial-manager
    /// stand-in observes a clean EOF — never the ECONNRESET an undrained
    /// close produces — and the buffered guest output is preserved
    /// through the console fan-out (scrollback + console.log evidence).
    #[tokio::test]
    async fn drain_and_close_consoles_closes_cleanly() {
        use std::io::{Read as _, Write as _};

        let dir = tempfile::tempdir_in(std::env::current_dir().unwrap()).unwrap();
        let vm_dir = dir.path().join("vm-drain");
        std::fs::create_dir_all(&vm_dir).unwrap();
        let sock_path = dir.path().join("serial.sock");

        // Stand in for cloud-hypervisor's serial manager: one accepted
        // client connection that streams guest output.
        let listener = std::os::unix::net::UnixListener::bind(&sock_path).unwrap();
        let server = std::thread::spawn(move || {
            let (mut conn, _) = listener.accept().expect("accept");
            // Simulate a mid-burst guest: console output the agent has
            // not read yet when shutdown begins.
            conn.write_all(b"late guest output").expect("write burst");
            conn
        });

        let adapter = ProcessCloudHypervisorAdapter::new(dir.path().join("chv"));
        let (pty_tx, _) = tokio::sync::broadcast::channel::<Vec<u8>>(4096);
        let pty_scrollback = Arc::new(std::sync::RwLock::new(Vec::new()));
        let broadcaster_alive = Arc::new(AtomicBool::new(false));
        let mut child = tokio::process::Command::new("true").spawn().unwrap();
        let _ = child.wait().await;

        let client = std::os::unix::net::UnixStream::connect(&sock_path).unwrap();
        let console_io: OwnedFd = client.into();
        {
            let mut map = adapter.vms.write().await;
            map.insert(
                "vm-drain".to_string(),
                VmProcess {
                    api_socket: vm_dir.join("vm.sock"),
                    child: VmmChild::Owned(child),
                    console_io,
                    serial_transport: SerialTransport::Socket(sock_path.clone()),
                    pty_tx: pty_tx.clone(),
                    pty_scrollback: pty_scrollback.clone(),
                    broadcaster_alive: broadcaster_alive.clone(),
                    last_cpu_seconds: 0.0,
                    last_cpu_at: None,
                    boot_watermark: AtomicU64::new(0),
                },
            );
        }

        // Subscribe BEFORE the drain: broadcast sends without a
        // receiver are dropped, and the drained bytes are the assertion
        // target.
        let mut rx = pty_tx.subscribe();
        // Let the burst land in the receive queue, then run the
        // graceful-shutdown drain.
        tokio::time::sleep(std::time::Duration::from_millis(100)).await;
        adapter.drain_and_close_consoles().await;

        // The buffered guest output was preserved through the fan-out.
        let got = tokio::time::timeout(std::time::Duration::from_secs(1), rx.recv())
            .await
            .expect("drained output must reach the console fan-out")
            .expect("channel must be live");
        assert_eq!(got, b"late guest output".to_vec());
        assert!(pty_scrollback
            .read()
            .expect("scrollback lock poisoned")
            .ends_with(b"late guest output"));

        // The serial manager observes a clean EOF — never a reset.
        let mut conn = server.join().expect("server thread");
        let mut buf = [0u8; 64];
        let n = conn
            .read(&mut buf)
            .unwrap_or_else(|e| panic!("serial manager must observe EOF, not {e:?}"));
        assert_eq!(n, 0, "serial manager must observe a clean EOF");

        // Idempotent: the multiple process-exit paths can each call it.
        adapter.drain_and_close_consoles().await;
    }

    /// While the shutdown drain latch is set, a broadcaster whose
    /// connection ends must stand down instead of reconnecting: a
    /// connection minted during shutdown would be abortively closed by
    /// process exit — recreating the very freeze the drain prevents. The
    /// serial-manager stand-in keeps its listener bound and must observe
    /// no second connection.
    #[tokio::test]
    async fn drain_latch_suppresses_broadcaster_reconnect() {
        use std::io::Write as _;

        let dir = tempfile::tempdir_in(std::env::current_dir().unwrap()).unwrap();
        let vm_dir = dir.path().join("vm-latch");
        std::fs::create_dir_all(&vm_dir).unwrap();
        let sock_path = dir.path().join("serial.sock");

        let listener = std::os::unix::net::UnixListener::bind(&sock_path).unwrap();
        listener.set_nonblocking(true).unwrap();

        let adapter = ProcessCloudHypervisorAdapter::new(dir.path().join("chv"));
        let (pty_tx, _) = tokio::sync::broadcast::channel::<Vec<u8>>(4096);
        let pty_scrollback = Arc::new(std::sync::RwLock::new(Vec::new()));
        let broadcaster_alive = Arc::new(AtomicBool::new(false));
        let mut child = tokio::process::Command::new("true").spawn().unwrap();
        let _ = child.wait().await;

        let client = std::os::unix::net::UnixStream::connect(&sock_path).unwrap();
        let console_io: OwnedFd = client.into();
        let broadcaster_fd = ProcessCloudHypervisorAdapter::dup_cloexec(&console_io).unwrap();
        {
            let mut map = adapter.vms.write().await;
            map.insert(
                "vm-latch".to_string(),
                VmProcess {
                    api_socket: vm_dir.join("vm.sock"),
                    child: VmmChild::Owned(child),
                    console_io,
                    serial_transport: SerialTransport::Socket(sock_path.clone()),
                    pty_tx: pty_tx.clone(),
                    pty_scrollback: pty_scrollback.clone(),
                    broadcaster_alive: broadcaster_alive.clone(),
                    last_cpu_seconds: 0.0,
                    last_cpu_at: None,
                    boot_watermark: AtomicU64::new(0),
                },
            );
        }
        // The alive flag is set by the spawner (the guard only clears it
        // on exit) — mirror the production call sites.
        broadcaster_alive.store(true, Ordering::SeqCst);
        ProcessCloudHypervisorAdapter::spawn_pty_broadcaster(
            adapter.vms.clone(),
            "vm-latch".to_string(),
            broadcaster_fd,
            SerialTransport::Socket(sock_path.clone()),
            pty_tx.clone(),
            pty_scrollback.clone(),
            broadcaster_alive.clone(),
            adapter.console_draining.clone(),
        );
        // Subscribe before writing the probe so the send has a receiver.
        let mut rx = pty_tx.subscribe();

        // Accept the agent's connection (retry: the listener is
        // non-blocking) and stream one probe through it.
        let mut conn = loop {
            match listener.accept() {
                Ok((conn, _)) => break conn,
                Err(ref e) if e.kind() == std::io::ErrorKind::WouldBlock => {
                    tokio::time::sleep(std::time::Duration::from_millis(10)).await;
                }
                Err(e) => panic!("accept: {e}"),
            }
        };
        conn.write_all(b"probe").unwrap();
        let got = tokio::time::timeout(std::time::Duration::from_secs(1), rx.recv())
            .await
            .expect("probe must arrive through the fan-out")
            .expect("channel must be live");
        assert_eq!(got, b"probe".to_vec());
        assert!(
            broadcaster_alive.load(Ordering::SeqCst),
            "broadcaster must be alive and streaming"
        );

        // Begin the graceful-shutdown drain, then end the manager side
        // of the connection: the broadcaster wakes with EOF and its
        // heal must stand down — the listener stays bound, so a wrongful
        // reconnect would be observable as a pending connection.
        adapter.drain_and_close_consoles().await;
        drop(conn);

        let deadline = std::time::Instant::now() + std::time::Duration::from_secs(2);
        while broadcaster_alive.load(Ordering::SeqCst) && std::time::Instant::now() < deadline {
            tokio::time::sleep(std::time::Duration::from_millis(25)).await;
        }
        assert!(
            !broadcaster_alive.load(Ordering::SeqCst),
            "broadcaster must stand down during the shutdown drain instead of reconnecting"
        );

        // No second connection may land on the still-bound listener.
        let watch_until = std::time::Instant::now() + std::time::Duration::from_millis(300);
        while std::time::Instant::now() < watch_until {
            match listener.accept() {
                Ok((conn, _)) => {
                    drop(conn);
                    panic!("broadcaster reconnected during the shutdown drain");
                }
                Err(ref e) if e.kind() == std::io::ErrorKind::WouldBlock => {}
                Err(e) => panic!("accept: {e}"),
            }
            tokio::time::sleep(std::time::Duration::from_millis(25)).await;
        }
    }

    /// `vm.reboot` in cloud-hypervisor v43 tears the VM down and
    /// re-creates it, re-binding the serial listener at the same path —
    /// but the OLD connection is orphaned without an EOF: the serial
    /// manager's accept path hands the descriptor to epoll via
    /// `into_raw_fd()` and never closes it, so a reader parked on it sees
    /// neither data nor EOF. `reboot_vm` must force-rotate the connection
    /// (`shutdown(SHUT_RD)` — description-level, so it also wakes the
    /// broadcaster's dup) after a successful reboot; the broadcaster's
    /// self-heal then reconnects to the re-bound listener and console
    /// capture follows the new boot.
    #[tokio::test]
    async fn reboot_vm_rotates_zombie_serial_connection() {
        use std::io::{Read as _, Write as _};

        let dir = tempfile::tempdir_in(std::env::current_dir().unwrap()).unwrap();
        let vm_dir = dir.path().join("vm-reboot-rotate");
        std::fs::create_dir_all(&vm_dir).unwrap();
        let sock_path = dir.path().join("serial.sock");
        let api_sock_path = vm_dir.join("vm.sock");

        // Fake cloud-hypervisor API socket: answer vm.reboot with 204.
        let api_listener = std::os::unix::net::UnixListener::bind(&api_sock_path).unwrap();
        let api_server = std::thread::spawn(move || {
            let (mut conn, _) = api_listener.accept().expect("api accept");
            let mut request = [0u8; 1024];
            let _ = conn.read(&mut request);
            conn.write_all(b"HTTP/1.1 204 No Content\r\nContent-Length: 0\r\n\r\n")
                .expect("api respond");
        });

        // The zombie's peer is still open for the whole test — nobody
        // closed it — proving the rotation did not rely on the VMM
        // closing the connection.
        let (_zombie_peer_stays_open, zombie_agent_end) =
            std::os::unix::net::UnixStream::pair().unwrap();

        // The re-bound listener vm.reboot "left behind": the broadcaster's
        // self-heal must connect here and receive the new boot's output.
        let listener2 = std::os::unix::net::UnixListener::bind(&sock_path).unwrap();
        let rebind_server = std::thread::spawn(move || {
            let (mut conn, _) = listener2.accept().expect("rebind accept");
            conn.write_all(b"second-boot").expect("write second boot");
            // Hold the connection open while the test asserts.
            std::thread::sleep(std::time::Duration::from_millis(2500));
        });

        let adapter = ProcessCloudHypervisorAdapter::new(dir.path().join("chv"));
        let (pty_tx, _) = tokio::sync::broadcast::channel::<Vec<u8>>(4096);
        let pty_scrollback = Arc::new(std::sync::RwLock::new(Vec::new()));
        let broadcaster_alive = Arc::new(AtomicBool::new(true));
        let mut child = tokio::process::Command::new("true").spawn().unwrap();
        let _ = child.wait().await;
        let zombie_console_io: OwnedFd = zombie_agent_end.into();
        let zombie_fd = zombie_console_io.as_raw_fd();

        {
            let mut map = adapter.vms.write().await;
            map.insert(
                "vm-reboot-rotate".to_string(),
                VmProcess {
                    api_socket: api_sock_path.clone(),
                    child: VmmChild::Owned(child),
                    console_io: zombie_console_io,
                    serial_transport: SerialTransport::Socket(sock_path.clone()),
                    pty_tx: pty_tx.clone(),
                    pty_scrollback: pty_scrollback.clone(),
                    broadcaster_alive: broadcaster_alive.clone(),
                    last_cpu_seconds: 0.0,
                    last_cpu_at: None,
                    boot_watermark: AtomicU64::new(0),
                },
            );
        }

        // The broadcaster is ALIVE and parked on the zombie connection —
        // the exact production state after create + reboot. Without the
        // rotation it would stay parked forever (this is the bug).
        let broadcaster_fd = ProcessCloudHypervisorAdapter::dup_cloexec(
            &adapter
                .vms
                .read()
                .await
                .get("vm-reboot-rotate")
                .unwrap()
                .console_io,
        )
        .unwrap();
        ProcessCloudHypervisorAdapter::spawn_pty_broadcaster(
            adapter.vms.clone(),
            "vm-reboot-rotate".to_string(),
            broadcaster_fd,
            SerialTransport::Socket(sock_path.clone()),
            pty_tx.clone(),
            pty_scrollback.clone(),
            broadcaster_alive.clone(),
            adapter.console_draining.clone(),
        );
        let mut rx = pty_tx.subscribe();

        adapter.reboot_vm("vm-reboot-rotate", None).await.unwrap();
        api_server.join().expect("api server thread");

        // The broadcaster observed the forced EOF, reconnected to the
        // re-bound listener, and streams the new boot's output.
        let got = tokio::time::timeout(std::time::Duration::from_secs(5), rx.recv())
            .await
            .expect("second-boot probe must arrive through the fan-out")
            .expect("channel must be live");
        assert_eq!(got, b"second-boot".to_vec());
        assert!(
            broadcaster_alive.load(Ordering::SeqCst),
            "broadcaster must survive the forced rotation"
        );
        {
            let map = adapter.vms.read().await;
            let proc = map.get("vm-reboot-rotate").unwrap();
            assert_ne!(
                proc.console_io.as_raw_fd(),
                zombie_fd,
                "stored console fd must be swapped for the reconnected one"
            );
        }

        rebind_server.join().expect("rebind server thread");
    }

    /// A failed `vm.reboot` (non-2xx) must NOT rotate the serial
    /// connection — the listener was not re-bound, so a forced EOF would
    /// kill console capture for a VM that is still running on the old
    /// connection.
    #[tokio::test]
    async fn reboot_vm_failure_leaves_serial_connection_alone() {
        use std::io::{Read as _, Write as _};

        let dir = tempfile::tempdir_in(std::env::current_dir().unwrap()).unwrap();
        let vm_dir = dir.path().join("vm-reboot-fail");
        std::fs::create_dir_all(&vm_dir).unwrap();
        let api_sock_path = vm_dir.join("vm.sock");

        // Fake cloud-hypervisor API socket: answer vm.reboot with 500.
        let api_listener = std::os::unix::net::UnixListener::bind(&api_sock_path).unwrap();
        let api_server = std::thread::spawn(move || {
            let (mut conn, _) = api_listener.accept().expect("api accept");
            let mut request = [0u8; 1024];
            let _ = conn.read(&mut request);
            conn.write_all(b"HTTP/1.1 500 Internal Server Error\r\nContent-Length: 0\r\n\r\n")
                .expect("api respond");
        });

        // A healthy, live connection: the peer stays open and responsive.
        let (mut peer, agent_end) = std::os::unix::net::UnixStream::pair().unwrap();
        peer.write_all(b"still-streaming").unwrap();
        let console_io: OwnedFd = agent_end.into();
        let original_fd = console_io.as_raw_fd();

        let adapter = ProcessCloudHypervisorAdapter::new(dir.path().join("chv"));
        let (pty_tx, _) = tokio::sync::broadcast::channel::<Vec<u8>>(4096);
        let pty_scrollback = Arc::new(std::sync::RwLock::new(Vec::new()));
        let broadcaster_alive = Arc::new(AtomicBool::new(true));
        let mut child = tokio::process::Command::new("true").spawn().unwrap();
        let _ = child.wait().await;

        {
            let mut map = adapter.vms.write().await;
            map.insert(
                "vm-reboot-fail".to_string(),
                VmProcess {
                    api_socket: api_sock_path.clone(),
                    child: VmmChild::Owned(child),
                    console_io,
                    serial_transport: SerialTransport::Socket(vm_dir.join("serial.sock")),
                    pty_tx: pty_tx.clone(),
                    pty_scrollback: pty_scrollback.clone(),
                    broadcaster_alive: broadcaster_alive.clone(),
                    last_cpu_seconds: 0.0,
                    last_cpu_at: None,
                    boot_watermark: AtomicU64::new(0),
                },
            );
        }

        let mut rx = pty_tx.subscribe();

        // The broadcaster streams from the live connection.
        let broadcaster_fd = ProcessCloudHypervisorAdapter::dup_cloexec(
            &adapter
                .vms
                .read()
                .await
                .get("vm-reboot-fail")
                .unwrap()
                .console_io,
        )
        .unwrap();
        ProcessCloudHypervisorAdapter::spawn_pty_broadcaster(
            adapter.vms.clone(),
            "vm-reboot-fail".to_string(),
            broadcaster_fd,
            SerialTransport::Socket(vm_dir.join("serial.sock")),
            pty_tx.clone(),
            pty_scrollback.clone(),
            broadcaster_alive.clone(),
            adapter.console_draining.clone(),
        );
        let got = tokio::time::timeout(std::time::Duration::from_secs(3), rx.recv())
            .await
            .expect("probe must arrive before the reboot attempt")
            .expect("channel must be live");
        assert_eq!(got, b"still-streaming".to_vec());

        adapter.reboot_vm("vm-reboot-fail", None).await.unwrap();
        api_server.join().expect("api server thread");

        // The connection was NOT rotated: the stored fd is unchanged and
        // the connection is still fully functional end-to-end — new peer
        // output flows through the unchanged broadcaster.
        {
            let map = adapter.vms.read().await;
            let proc = map.get("vm-reboot-fail").unwrap();
            assert_eq!(
                proc.console_io.as_raw_fd(),
                original_fd,
                "failed vm.reboot must not rotate the serial connection"
            );
        }
        peer.write_all(b"post-reboot").unwrap();
        let got = tokio::time::timeout(std::time::Duration::from_secs(3), rx.recv())
            .await
            .expect("post-reboot probe must arrive through the untouched connection")
            .expect("channel must be live");
        assert_eq!(got, b"post-reboot".to_vec());
    }

    /// `vmm_serial_manager_thread_alive` discriminates by thread `comm`:
    /// provable absence (`Some(false)`), a live thread (`Some(true)`),
    /// and an unscannable pid (`None` — never a false "dead" verdict,
    /// which would reboot a healthy VM).
    #[test]
    fn serial_manager_thread_liveness_follows_thread_comm() {
        let own_pid = std::process::id();
        // No thread of this test process is named "serial-manager" (only
        // this test spawns one, further down): absence is provable.
        assert_eq!(
            super::vmm_serial_manager_thread_alive(own_pid),
            Some(false),
            "a live process without a serial-manager thread must classify as provably absent"
        );
        // A dead pid cannot be scanned: absence is unprovable, never
        // false — the fail-safe that keeps the heal off unreadable
        // /proc mounts.
        assert_eq!(
            super::vmm_serial_manager_thread_alive(4_000_000),
            None,
            "an unscannable pid must never classify as provably absent"
        );

        let stop = Arc::new(AtomicBool::new(false));
        let thread_stop = stop.clone();
        let thread = std::thread::Builder::new()
            .name("serial-manager".to_string())
            .spawn(move || {
                while !thread_stop.load(Ordering::SeqCst) {
                    std::thread::sleep(std::time::Duration::from_millis(10));
                }
            })
            .unwrap();
        // The thread's task entry (with its comm) is published by
        // clone(), but poll so the test stays robust.
        let deadline = std::time::Instant::now() + std::time::Duration::from_secs(5);
        loop {
            if super::vmm_serial_manager_thread_alive(own_pid) == Some(true) {
                break;
            }
            assert!(
                std::time::Instant::now() < deadline,
                "spawned serial-manager thread must become visible in /proc"
            );
        }

        // Once the thread exits, its task entry disappears and the
        // verdict returns to provable absence — a revived-or-recreated
        // manager is distinguishable from a dead one.
        stop.store(true, Ordering::SeqCst);
        thread.join().unwrap();
        let deadline = std::time::Instant::now() + std::time::Duration::from_secs(5);
        loop {
            if super::vmm_serial_manager_thread_alive(own_pid) == Some(false) {
                break;
            }
            assert!(
                std::time::Instant::now() < deadline,
                "exited serial-manager thread must disappear from /proc"
            );
        }
    }

    /// Issue #409, the fix's remediation path: an adopted, Running,
    /// Socket-transport VM whose VMM provably has no serial-manager
    /// thread gets exactly ONE remediation reboot out of start_vm's
    /// idempotent already-running path — the broadcaster, parked on the
    /// wedged (connected-but-never-accepted) connection, is rotated onto
    /// the re-bound listener and console capture resumes on the new
    /// boot — and a second start_vm does not reboot again.
    #[tokio::test]
    async fn start_vm_heals_adopted_vm_with_dead_serial_manager() {
        use std::io::Write as _;

        let dir = tempfile::tempdir_in(std::env::current_dir().unwrap()).unwrap();
        let vm_dir = dir.path().join("vm-heal");
        std::fs::create_dir_all(&vm_dir).unwrap();
        let sock_path = dir.path().join("serial.sock");
        let api_sock_path = vm_dir.join("vm.sock");

        // The stand-in VMM: a live process with the api-socket argv (so
        // the Adopted entry's identity checks hold) and NO
        // serial-manager thread — the provable absence that is the wedge
        // signature.
        let bin = write_vmm_standin_binary(dir.path());
        let standin = StandinVmm(spawn_vmm_standin(&bin, &api_sock_path));
        wait_for_standin_argv(standin.pid());
        assert_eq!(
            super::vmm_serial_manager_thread_alive(standin.pid()),
            Some(false),
            "test precondition: the stand-in must provably lack a serial-manager thread"
        );

        // The wedged console connection: connected from the agent side
        // (adoption's reconnect succeeds into the kernel's accept
        // backlog) but never accepted — the peer stays open and silent,
        // so the broadcaster parked on it never sees a byte.
        let (wedge_peer, wedge_agent_end) = std::os::unix::net::UnixStream::pair().unwrap();
        let wedge_console_io: OwnedFd = wedge_agent_end.into();
        let wedge_fd = wedge_console_io.as_raw_fd();

        // The re-bound listener vm.reboot "leaves behind": the
        // broadcaster's self-heal must connect here and stream the new
        // boot's output.
        let listener = std::os::unix::net::UnixListener::bind(&sock_path).unwrap();
        let rebind_server = std::thread::spawn(move || {
            let (mut conn, _) = listener.accept().expect("rebind accept");
            conn.write_all(b"second-boot").expect("write second boot");
            // Hold the connection open while the test asserts.
            std::thread::sleep(std::time::Duration::from_millis(2500));
        });

        // Fake cloud-hypervisor API: vm.info → Running, vm.reboot → 204.
        // Three requests are expected (vm.info, vm.reboot, vm.info) and
        // one slot of slack: a spurious second reboot would be recorded
        // and fail the count assertions below.
        let api = MockChApiHandle::spawn(&api_sock_path, 4);
        api.set_vm_info_state("Running");

        // Prior capture history: the heal's watermark bump must scope
        // the new boot past the frozen bytes.
        std::fs::write(vm_console_log(&vm_dir), "frozen console\n").unwrap();

        let adapter = ProcessCloudHypervisorAdapter::new(bin.clone());
        let (pty_tx, _) = tokio::sync::broadcast::channel::<Vec<u8>>(4096);
        let pty_scrollback = Arc::new(std::sync::RwLock::new(Vec::new()));
        let broadcaster_alive = Arc::new(AtomicBool::new(true));
        {
            let mut map = adapter.vms.write().await;
            map.insert(
                "vm-heal".to_string(),
                VmProcess {
                    api_socket: api_sock_path.clone(),
                    child: VmmChild::Adopted(standin.pid()),
                    console_io: wedge_console_io,
                    serial_transport: SerialTransport::Socket(sock_path.clone()),
                    pty_tx: pty_tx.clone(),
                    pty_scrollback: pty_scrollback.clone(),
                    broadcaster_alive: broadcaster_alive.clone(),
                    last_cpu_seconds: 0.0,
                    last_cpu_at: None,
                    boot_watermark: AtomicU64::new(0),
                },
            );
        }

        // The broadcaster is alive and parked on the wedged connection —
        // the exact production state after the agent restart.
        let broadcaster_fd = ProcessCloudHypervisorAdapter::dup_cloexec(
            &adapter.vms.read().await.get("vm-heal").unwrap().console_io,
        )
        .unwrap();
        ProcessCloudHypervisorAdapter::spawn_pty_broadcaster(
            adapter.vms.clone(),
            "vm-heal".to_string(),
            broadcaster_fd,
            SerialTransport::Socket(sock_path.clone()),
            pty_tx.clone(),
            pty_scrollback.clone(),
            broadcaster_alive.clone(),
            adapter.console_draining.clone(),
        );
        let mut rx = pty_tx.subscribe();

        // start_vm stays idempotent-successful AND heals on the way
        // through: the op must not turn into an error over a console
        // remediation.
        adapter.start_vm("vm-heal", None).await.unwrap();

        // The remediation reboot rotated the broadcaster onto the
        // re-bound listener: the new boot's output flows again.
        let got = tokio::time::timeout(std::time::Duration::from_secs(5), rx.recv())
            .await
            .expect("second-boot probe must arrive through the healed console")
            .expect("channel must be live");
        assert_eq!(got, b"second-boot".to_vec());
        {
            let map = adapter.vms.read().await;
            let proc = map.get("vm-heal").unwrap();
            assert_ne!(
                proc.console_io.as_raw_fd(),
                wedge_fd,
                "the wedged connection must be swapped for the healed one"
            );
            assert_eq!(
                proc.boot_watermark.load(Ordering::SeqCst),
                "frozen console\n".len() as u64,
                "the heal's reboot must scope the new boot past the frozen capture"
            );
        }
        assert_eq!(api.reboot_requests(), 1, "exactly one remediation reboot");

        // A second start_vm (the reconciler's next pass) stays a no-op:
        // the one-reboot-per-VMM-generation budget is spent.
        adapter.start_vm("vm-heal", None).await.unwrap();
        assert_eq!(
            api.reboot_requests(),
            1,
            "the serial heal must not reboot the same VMM generation twice"
        );
        assert_eq!(api.vm_info_requests(), 2);

        rebind_server.join().expect("rebind server thread");
        drop(wedge_peer);
    }

    /// The heal's safety gates: an adopted VM WITH a live serial-manager
    /// thread, and a tracked (Owned) VM, are never rebooted by start_vm —
    /// adopting a VM with a live console stays a pure no-op, and the
    /// tracked console path is untouched by the heal.
    #[tokio::test]
    async fn start_vm_leaves_vms_with_live_serial_manager_alone() {
        let dir = tempfile::tempdir_in(std::env::current_dir().unwrap()).unwrap();
        let vm_live_dir = dir.path().join("vm-live-thread");
        let vm_owned_dir = dir.path().join("vm-owned");
        std::fs::create_dir_all(&vm_live_dir).unwrap();
        std::fs::create_dir_all(&vm_owned_dir).unwrap();
        let api_sock_path = vm_live_dir.join("vm.sock");

        let bin = write_vmm_standin_binary(dir.path());

        // The adopted stand-in renames its main thread to
        // "serial-manager" — the /proc signature of a VMM whose console
        // path is alive.
        let live_standin = StandinVmm(spawn_vmm_standin_script(
            &bin,
            &api_sock_path,
            "echo serial-manager > /proc/self/comm; while true; do sleep 30; done",
        ));
        wait_for_standin_argv(live_standin.pid());
        let deadline = std::time::Instant::now() + std::time::Duration::from_secs(5);
        loop {
            if super::vmm_serial_manager_thread_alive(live_standin.pid()) == Some(true) {
                break;
            }
            assert!(
                std::time::Instant::now() < deadline,
                "stand-in must publish its serial-manager comm"
            );
        }

        // One shared fake API: both VMs report Running; any vm.reboot
        // would be recorded and fail the assertions below.
        let api = MockChApiHandle::spawn(&api_sock_path, 4);
        api.set_vm_info_state("Running");

        let adapter = ProcessCloudHypervisorAdapter::new(bin.clone());
        let (live_peer, live_agent_end) = std::os::unix::net::UnixStream::pair().unwrap();
        let (owned_peer, owned_agent_end) = std::os::unix::net::UnixStream::pair().unwrap();
        let live_fd = live_agent_end.as_raw_fd();
        let owned_fd = owned_agent_end.as_raw_fd();
        let (live_tx, _) = tokio::sync::broadcast::channel::<Vec<u8>>(16);
        let (owned_tx, _) = tokio::sync::broadcast::channel::<Vec<u8>>(16);
        let owned_child = tokio::process::Command::new("sleep")
            .arg("60")
            .spawn()
            .unwrap();
        {
            let mut map = adapter.vms.write().await;
            map.insert(
                "vm-live-thread".to_string(),
                VmProcess {
                    api_socket: api_sock_path.clone(),
                    child: VmmChild::Adopted(live_standin.pid()),
                    console_io: OwnedFd::from(live_agent_end),
                    serial_transport: SerialTransport::Socket(vm_live_dir.join("serial.sock")),
                    pty_tx: live_tx,
                    pty_scrollback: Arc::new(std::sync::RwLock::new(Vec::new())),
                    broadcaster_alive: Arc::new(AtomicBool::new(true)),
                    last_cpu_seconds: 0.0,
                    last_cpu_at: None,
                    boot_watermark: AtomicU64::new(0),
                },
            );
            map.insert(
                "vm-owned".to_string(),
                VmProcess {
                    api_socket: api_sock_path.clone(),
                    child: VmmChild::Owned(owned_child),
                    console_io: OwnedFd::from(owned_agent_end),
                    serial_transport: SerialTransport::Socket(vm_owned_dir.join("serial.sock")),
                    pty_tx: owned_tx,
                    pty_scrollback: Arc::new(std::sync::RwLock::new(Vec::new())),
                    broadcaster_alive: Arc::new(AtomicBool::new(true)),
                    last_cpu_seconds: 0.0,
                    last_cpu_at: None,
                    boot_watermark: AtomicU64::new(0),
                },
            );
        }

        // Both start_vm calls succeed idempotently...
        adapter.start_vm("vm-live-thread", None).await.unwrap();
        adapter.start_vm("vm-owned", None).await.unwrap();

        // ...and neither VM was rebooted: a live console path (adopted)
        // and a tracked VM (Owned) are both outside the heal's gates.
        assert_eq!(
            api.reboot_requests(),
            0,
            "no vm.reboot may be issued for a VM with a live serial manager or a tracked VM"
        );
        assert_eq!(api.vm_info_requests(), 2);
        assert!(
            adapter.serial_heal_reboots.lock().unwrap().is_empty(),
            "no serial-heal budget may be spent"
        );
        {
            let map = adapter.vms.read().await;
            assert_eq!(
                map.get("vm-live-thread").unwrap().console_io.as_raw_fd(),
                live_fd,
                "the adopted VM's live console endpoint must be untouched"
            );
            assert_eq!(
                map.get("vm-owned").unwrap().console_io.as_raw_fd(),
                owned_fd,
                "the tracked VM's console endpoint must be untouched"
            );
        }

        teardown_watchdog_vm(&adapter, "vm-owned").await;
        drop(live_peer);
        drop(owned_peer);
    }

    /// Between `spawn()` returning and the child's `execve` completing there
    /// is a small window in which `/proc/<pid>/cmdline` still reads the
    /// PARENT's (the test runner's) argv — posix_spawn's child shares the
    /// parent's memory until exec — so waiting for a merely NON-EMPTY
    /// cmdline is not enough: an identity assertion directly after it can
    /// race a pre-exec read and fail under parallel test load. Tests that
    /// assert on process identity therefore wait for a needle only the
    /// stand-in's own post-exec argv contains (typically its api-socket
    /// path).
    async fn wait_for_cmdline_containing(pid: u32, needle: &str) -> String {
        let deadline = std::time::Instant::now() + std::time::Duration::from_secs(2);
        loop {
            if let Some(cmdline) = super::proc_cmdline(pid) {
                if cmdline.contains(needle) {
                    return cmdline;
                }
            }
            assert!(
                std::time::Instant::now() < deadline,
                "cmdline for pid {pid} never contained {needle:?}"
            );
            tokio::time::sleep(std::time::Duration::from_millis(5)).await;
        }
    }

    /// VmmChild semantics: an Owned child is killed and reaped through
    /// kill/wait; an Adopted pid is only signalled when /proc/<pid>/cmdline
    /// AND the executable name still prove identity against the VM's
    /// api-socket path — a mismatching (e.g. recycled or argv-spoofed) pid
    /// is refused, and a vanished pid is absorbed without panicking.
    #[tokio::test]
    async fn vmm_child_owned_and_adopted_semantics() {
        let dir = tempfile::tempdir_in(std::env::current_dir().unwrap()).unwrap();
        let api_socket = dir.path().join("vm.sock");

        // Owned: spawn → live → kill → wait → exited.
        let owned_child = tokio::process::Command::new("sleep")
            .arg("60")
            .spawn()
            .unwrap();
        let mut owned = VmmChild::Owned(owned_child);
        assert!(matches!(
            owned.prove_exited(&api_socket),
            super::Liveness::Alive
        ));
        owned.kill(&api_socket, None);
        owned.wait().await;
        assert!(matches!(
            owned.prove_exited(&api_socket),
            super::Liveness::Exited
        ));

        // Adopted with a matching command line. `sh -c "sleep 5; true"`
        // never execs (compound command), so the process keeps its argv —
        // including the api-socket flag and path — for its lifetime.
        let mut adopted_proc = tokio::process::Command::new("sh")
            .arg("-c")
            .arg("sleep 5; true")
            .arg("--api-socket")
            .arg(&api_socket)
            .spawn()
            .unwrap();
        let adopted_pid = adopted_proc.id().expect("freshly spawned child has a pid");
        wait_for_cmdline_containing(adopted_pid, &api_socket.to_string_lossy()).await;
        // The stand-in's real executable — what the exe cross-check
        // compares against (the adapter passes its chv_binary's file
        // name in production).
        let adopted_exe = std::fs::read_link(format!("/proc/{adopted_pid}/exe")).unwrap();
        let adopted_exe_name = adopted_exe.file_name().unwrap().to_owned();
        assert!(
            super::pid_is_cloud_hypervisor(
                adopted_pid,
                &api_socket,
                Some(adopted_exe_name.as_os_str())
            ),
            "argv + exe identity must match for the live stand-in"
        );
        // A correct argv with a WRONG expected executable is refused:
        // crafted argv alone must never authorize a signal.
        assert!(!super::pid_is_cloud_hypervisor(
            adopted_pid,
            &api_socket,
            Some(std::ffi::OsStr::new("definitely-not-cloud-hypervisor"))
        ));
        let mut adopted = VmmChild::Adopted(adopted_pid);
        assert!(matches!(
            adopted.prove_exited(&api_socket),
            super::Liveness::Alive
        ));
        adopted.kill(&api_socket, Some(adopted_exe_name.as_os_str()));
        adopted.wait().await;
        assert!(matches!(
            adopted.prove_exited(&api_socket),
            super::Liveness::Exited
        ));
        let _ = adopted_proc.wait().await;

        // Adopted with a NON-matching command line: the kill must be
        // refused — an unrelated process must never be signalled.
        let mut unrelated = tokio::process::Command::new("sleep")
            .arg("30")
            .spawn()
            .unwrap();
        let unrelated_pid = unrelated.id().expect("freshly spawned child has a pid");
        let unrelated_cmdline = wait_for_cmdline_containing(unrelated_pid, "sleep").await;
        assert!(
            unrelated_cmdline.contains("sleep"),
            "stand-in must be running"
        );
        assert!(!super::pid_is_cloud_hypervisor(
            unrelated_pid,
            &api_socket,
            None
        ));
        let mut mismatched = VmmChild::Adopted(unrelated_pid);
        mismatched.kill(&api_socket, None);
        // The refusal left the process alive.
        assert!(
            super::pid_exists(unrelated_pid),
            "kill must be refused for a pid without identity proof"
        );
        // Liveness for the re-spawn decision is about OUR VMM: a live but
        // unproven pid (recycled) counts as exited — the runtime dir is
        // ours to take over, the unrelated process is not ours to signal.
        assert!(matches!(
            mismatched.prove_exited(&api_socket),
            super::Liveness::Exited
        ));
        let _ = unrelated.start_kill();
        let _ = unrelated.wait().await;

        // Adopted with a vanished pid: no panic, absorbed as exited.
        let mut vanished = VmmChild::Adopted(4_000_000);
        assert!(matches!(
            vanished.prove_exited(&api_socket),
            super::Liveness::Exited
        ));
        vanished.kill(&api_socket, None);
        vanished.wait().await;
    }

    /// The adoption scan rebuilds the in-memory map from on-disk runtime
    /// state: a live orphan (pid + cmdline identity + serial listener)
    /// is re-attached with console capture resumed and console.log
    /// APPENDED (pre-restart history preserved); a dead VMM still gets
    /// an entry (idempotent stop/delete, re-spawnable start); dirs
    /// without a pidfile or with unsafe ids are skipped.
    #[tokio::test]
    async fn adopt_rebuilds_map_from_runtime_dir() {
        use std::io::Write as _;

        let dir = tempfile::tempdir_in(std::env::current_dir().unwrap()).unwrap();
        let runtime_root = dir.path().join("runtime");
        let vms_base = runtime_root.join("vms");

        // vm-live: a live orphan with a serial listener and prior history.
        let live_dir = vms_base.join("vm-live");
        std::fs::create_dir_all(&live_dir).unwrap();
        let live_api_socket = live_dir.join("vm.sock");
        let serial_sock = live_dir.join("serial.sock");
        let mut orphan = tokio::process::Command::new("sh")
            .arg("-c")
            .arg("sleep 5; true")
            .arg("--api-socket")
            .arg(&live_api_socket)
            .spawn()
            .unwrap();
        let orphan_pid = orphan.id().expect("freshly spawned child has a pid");
        wait_for_cmdline_containing(orphan_pid, &live_api_socket.to_string_lossy()).await;
        std::fs::write(live_dir.join("ch.pid"), format!("{orphan_pid}")).unwrap();
        std::fs::write(live_dir.join("vm-config.json"), "{}").unwrap();
        std::fs::write(live_dir.join("console.log"), "history\n").unwrap();
        // The orphan's serial listener: accept the agent's reconnect and
        // stream a probe (with a small delay so the test can subscribe to
        // the fan-out channel before the bytes flow).
        let serial_listener = std::os::unix::net::UnixListener::bind(&serial_sock).unwrap();
        let acceptor = std::thread::spawn(move || {
            let (mut conn, _) = serial_listener.accept().expect("serial accept");
            std::thread::sleep(std::time::Duration::from_millis(500));
            conn.write_all(b"resumed").expect("write resumed probe");
            std::thread::sleep(std::time::Duration::from_millis(2500));
        });

        // vm-dead: a reaped pid, no serial socket.
        let dead_dir = vms_base.join("vm-dead");
        std::fs::create_dir_all(&dead_dir).unwrap();
        let mut dead_child = tokio::process::Command::new("true").spawn().unwrap();
        let dead_pid = dead_child.id().expect("freshly spawned child has a pid");
        let _ = dead_child.wait().await;
        std::fs::write(dead_dir.join("ch.pid"), format!("{dead_pid}")).unwrap();

        // vm-nopid: no pidfile → skipped with today's NotFound semantics.
        std::fs::create_dir_all(vms_base.join("vm-nopid")).unwrap();

        // Unsafe id (contains a path separator character): skipped.
        let unsafe_dir = vms_base.join("bad\\id");
        std::fs::create_dir_all(&unsafe_dir).unwrap();
        std::fs::write(unsafe_dir.join("ch.pid"), "1").unwrap();

        // The adapter's chv_binary file name is what the exe cross-check
        // expects adopted VMMs to run — point it at the stand-in's real
        // executable so identity validation runs in its production shape.
        let orphan_exe = std::fs::read_link(format!("/proc/{orphan_pid}/exe")).unwrap();
        let adapter = ProcessCloudHypervisorAdapter::new(orphan_exe.clone());
        adapter.adopt_running_vms(&runtime_root).await.unwrap();

        let mut live_rx;
        {
            let vms = adapter.vms.read().await;
            let live = vms.get("vm-live").expect("live orphan must be adopted");
            let VmmChild::Adopted(live_pid) = &live.child else {
                panic!("live orphan must be tracked as Adopted");
            };
            assert_eq!(*live_pid, orphan_pid);
            assert!(super::pid_is_cloud_hypervisor(
                *live_pid,
                &live_api_socket,
                orphan_exe.file_name()
            ));
            assert!(
                live.broadcaster_alive.load(Ordering::SeqCst),
                "console capture must resume for the adopted orphan"
            );
            live_rx = live.pty_tx.subscribe();

            let dead = vms.get("vm-dead").expect("dead VMM dir must be adopted");
            let VmmChild::Adopted(dead_tracked_pid) = &dead.child else {
                panic!("dead VMM must be tracked as Adopted");
            };
            assert_eq!(*dead_tracked_pid, dead_pid);
            assert!(
                !super::pid_is_cloud_hypervisor(*dead_tracked_pid, &dead_dir.join("vm.sock"), None),
                "dead VMM must classify as exited"
            );
            assert!(
                !dead.broadcaster_alive.load(Ordering::SeqCst),
                "no broadcaster may be spawned for a dead VMM"
            );

            assert!(
                !vms.contains_key("vm-nopid"),
                "dir without pidfile must be skipped"
            );
            assert!(!vms.contains_key("bad\\id"), "unsafe id must be skipped");
        }

        // Console capture actually resumed: the serial probe flows through
        // the fan-out channel and console.log gains it WITHOUT losing the
        // pre-restart history (append semantics).
        let got = tokio::time::timeout(std::time::Duration::from_secs(5), live_rx.recv())
            .await
            .expect("resumed probe must arrive through the adopted console")
            .expect("channel must be live");
        assert_eq!(got, b"resumed".to_vec());

        let log_path = live_dir.join("console.log");
        let deadline = std::time::Instant::now() + std::time::Duration::from_secs(3);
        loop {
            let contents = std::fs::read_to_string(&log_path).unwrap_or_default();
            if contents.contains("history") && contents.contains("resumed") {
                break;
            }
            assert!(
                std::time::Instant::now() < deadline,
                "console.log must contain history + resumed, got: {contents:?}"
            );
            tokio::time::sleep(std::time::Duration::from_millis(50)).await;
        }

        let _ = orphan.start_kill();
        let _ = orphan.wait().await;
        acceptor.join().expect("acceptor thread");
    }

    /// start_vm on a tracked VM whose VMM has exited routes to the
    /// re-spawn path: without a persisted config it fails fast with a
    /// clear re-create-required error while PRESERVING the entry
    /// (stop/delete stay functional); with a config but a missing binary
    /// the spawn failure surfaces.
    #[tokio::test]
    async fn start_vm_respawns_dead_vmm() {
        let dir = tempfile::tempdir_in(std::env::current_dir().unwrap()).unwrap();
        let vm_dir = dir.path().join("vm-rs");
        std::fs::create_dir_all(&vm_dir).unwrap();

        // The chv binary does not exist: any re-spawn attempt surfaces the
        // spawn failure immediately instead of hanging.
        let adapter = ProcessCloudHypervisorAdapter::new(dir.path().join("chv-missing"));
        let (pty_tx, _) = tokio::sync::broadcast::channel::<Vec<u8>>(4096);
        let mut child = tokio::process::Command::new("true").spawn().unwrap();
        let _ = child.wait().await;
        {
            let mut map = adapter.vms.write().await;
            map.insert(
                "vm-rs".to_string(),
                VmProcess {
                    api_socket: vm_dir.join("vm.sock"),
                    child: VmmChild::Owned(child),
                    console_io: std::fs::File::open("/dev/null").unwrap().into(),
                    serial_transport: SerialTransport::Socket(vm_dir.join("serial.sock")),
                    pty_tx,
                    pty_scrollback: Arc::new(std::sync::RwLock::new(Vec::new())),
                    broadcaster_alive: Arc::new(AtomicBool::new(false)),
                    last_cpu_seconds: 0.0,
                    last_cpu_at: None,
                    boot_watermark: AtomicU64::new(0),
                },
            );
        }

        // No persisted config → clear re-create-required error, entry kept.
        let err = adapter.start_vm("vm-rs", None).await.unwrap_err();
        match &err {
            ChvError::Internal { reason } => {
                assert!(
                    reason.contains("re-create"),
                    "error must tell the operator to re-create: {reason}"
                );
            }
            other => panic!("expected Internal, got {other:?}"),
        }
        assert!(
            adapter.vms.read().await.contains_key("vm-rs"),
            "a failed re-spawn must preserve the tracked entry"
        );

        // Persisted config + missing binary → the spawn failure surfaces.
        std::fs::write(vm_dir.join("vm-config.json"), r#"{"cpus":1}"#).unwrap();
        let err = adapter.start_vm("vm-rs", None).await.unwrap_err();
        assert!(
            matches!(err, ChvError::Io { .. }),
            "expected Io from the failed spawn, got {err:?}"
        );
        assert!(adapter.vms.read().await.contains_key("vm-rs"));
    }

    /// Writes the stand-in "cloud-hypervisor" binary for the untracked-VMM
    /// tests: a copy of `sh` named `cloud-hypervisor`, so both the exe
    /// (/proc/<pid>/exe resolves to the copy) and the file name match the
    /// adapter's `chv_binary` identity checks.
    fn write_vmm_standin_binary(dir: &std::path::Path) -> std::path::PathBuf {
        use std::os::unix::fs::PermissionsExt;
        let bin = dir.join("cloud-hypervisor");
        std::fs::copy("/bin/sh", &bin).unwrap();
        std::fs::set_permissions(&bin, std::fs::Permissions::from_mode(0o755)).unwrap();
        bin
    }

    /// Spawns the stand-in VMM: the shell keeps its `--api-socket` argv
    /// and sleeps as a CHILD (no exec — the argv must stay visible in
    /// /proc), in its own process group so teardown can reap the whole
    /// tree. Retries on ETXTBSY: executing a file immediately after
    /// writing it can transiently fail on overlayfs-style filesystems
    /// under parallel test load.
    fn spawn_vmm_standin(
        bin: &std::path::Path,
        api_socket: &std::path::Path,
    ) -> std::process::Child {
        spawn_vmm_standin_script(bin, api_socket, "sleep 300")
    }

    /// Generalized stand-in spawner: runs `script` under the stand-in
    /// binary with the `--api-socket` argv appended (visible in `/proc`
    /// for identity checks). The #409 heal tests use it to run a
    /// stand-in whose main-thread `comm` reads "serial-manager" — the
    /// `/proc` signature of a VMM with a live serial-manager thread.
    fn spawn_vmm_standin_script(
        bin: &std::path::Path,
        api_socket: &std::path::Path,
        script: &str,
    ) -> std::process::Child {
        use std::os::unix::process::CommandExt as _;
        let deadline = std::time::Instant::now() + std::time::Duration::from_secs(5);
        loop {
            match std::process::Command::new(bin)
                .arg("-c")
                .arg(script)
                .arg("--api-socket")
                .arg(api_socket)
                .process_group(0)
                .spawn()
            {
                Ok(child) => return child,
                Err(e)
                    if e.kind() == std::io::ErrorKind::ExecutableFileBusy
                        && std::time::Instant::now() < deadline =>
                {
                    std::thread::sleep(std::time::Duration::from_millis(25));
                }
                Err(e) => panic!("spawn stand-in VMM {}: {e}", bin.display()),
            }
        }
    }

    /// Waits until the stand-in's `/proc/<pid>/cmdline` shows its final
    /// argv — `spawn()` returns before `exec()`, so identity checks
    /// racing the exec would read the parent's (test binary's) cmdline.
    fn wait_for_standin_argv(pid: u32) {
        let cmdline = format!("/proc/{pid}/cmdline");
        let deadline = std::time::Instant::now() + std::time::Duration::from_secs(5);
        while std::time::Instant::now() < deadline {
            if let Ok(raw) = std::fs::read(&cmdline) {
                if raw
                    .windows(b"--api-socket".len())
                    .any(|w| w == b"--api-socket")
                {
                    return;
                }
            }
            std::thread::sleep(std::time::Duration::from_millis(25));
        }
    }

    /// Reaps the stand-in's whole process group (the shell's `sleep`
    /// child is orphaned when only the shell is killed).
    /// RAII ownership of a stand-in VMM's process group: kills and reaps
    /// the whole group on drop, so a mid-test panic cannot leak the
    /// shell and its `sleep` child for the full sleep duration.
    struct StandinVmm(std::process::Child);

    impl StandinVmm {
        fn pid(&self) -> u32 {
            self.0.id()
        }

        fn try_wait(&mut self) -> std::io::Result<Option<std::process::ExitStatus>> {
            self.0.try_wait()
        }
    }

    impl Drop for StandinVmm {
        fn drop(&mut self) {
            let _ = nix::sys::signal::killpg(
                nix::unistd::Pid::from_raw(self.0.id() as i32),
                nix::sys::signal::Signal::SIGKILL,
            );
            let _ = self.0.wait();
        }
    }

    /// The force-stop residual (M2.5 finding): the force paths remove the
    /// in-memory entry while the persisted creation payload survives on
    /// disk, and nothing re-inserts an entry for a still-configured VM —
    /// a later start used to fail NotFound, terminally (the executor
    /// finishes a Failed op for good). The start must re-derive the entry
    /// from the shared layout and proceed to the re-spawn.
    #[tokio::test]
    async fn start_after_force_stop_respawns_from_disk() {
        let dir = tempfile::tempdir_in(std::env::current_dir().unwrap()).unwrap();
        let runtime_root = dir.path().join("runtime");
        // Startup FIRST (nothing to adopt yet): the force-stop residual
        // happens at RUNTIME, between the force fallback dropping the
        // entry and any agent restart — startup adoption must not mask
        // it by re-inserting the entry itself.
        let adapter = ProcessCloudHypervisorAdapter::new(dir.path().join("chv-missing"));
        adapter.adopt_running_vms(&runtime_root).await.unwrap();

        let vm_dir = runtime_root.join("vms").join("vm-fs");
        std::fs::create_dir_all(&vm_dir).unwrap();
        // Force-stop leftovers: the entry is gone (never inserted here),
        // the payload and the stale socket/pid files remain.
        std::fs::write(vm_dir.join("vm-config.json"), r#"{"cpus":1}"#).unwrap();
        std::fs::write(vm_dir.join("ch.pid"), "999999\n").unwrap();

        // Before the fix this was NotFound (adoption already ran; nothing
        // else re-inserts an entry until an agent restart). The chv
        // binary does not exist, so the re-spawn surfaces the spawn
        // failure immediately instead of hanging.
        let err = adapter.start_vm("vm-fs", None).await.unwrap_err();
        assert!(
            matches!(err, ChvError::Io { .. }),
            "expected the re-spawn's spawn failure, got {err:?}"
        );
        // The re-derived entry must be tracked so a retry — and stop or
        // delete — works against it.
        assert!(
            adapter.vms.read().await.contains_key("vm-fs"),
            "the re-derived entry must stay tracked"
        );

        // A VM with neither an entry nor a runtime dir never ran on this
        // node: NotFound must still surface (the misroute rule).
        let err = adapter.start_vm("vm-never", None).await.unwrap_err();
        assert!(matches!(err, ChvError::NotFound { .. }), "got {err:?}");
    }

    /// The shutdown latch guards `readopt_stopped_vm` (union-review
    /// finding): a start racing graceful agent shutdown must never mint
    /// a fresh serial connection the drain cannot reach — process exit
    /// would abortively close it, the v43 serial-manager freeze hazard
    /// `drain_and_close_consoles` exists to prevent. The start fails
    /// closed (retryable after restart) and inserts no entry.
    ///
    /// This exercises the PRE-CONNECT check (the latch set before the
    /// start). The post-lock abandon branch is only reachable when the
    /// drain latches between that check and the map-lock acquisition —
    /// a genuinely concurrent window this test cannot pin without
    /// fragile timing; its mechanics (drop guard + dup, abandon the
    /// fresh connection) are the same as the respawn path's post-lock
    /// branch, which `drain_latch_suppresses_broadcaster_reconnect`
    /// does cover.
    #[tokio::test]
    async fn start_during_console_drain_fails_closed() {
        use super::vm_config_file;

        let dir = tempfile::tempdir_in(std::env::current_dir().unwrap()).unwrap();
        let runtime_root = dir.path().join("runtime");
        let adapter = ProcessCloudHypervisorAdapter::new(dir.path().join("chv-missing"));
        adapter.adopt_running_vms(&runtime_root).await.unwrap();

        // The force-stop residual: a configured VM with no map entry —
        // exactly the state readopt exists for.
        let vm_dir = runtime_root.join("vms").join("vm-dr");
        std::fs::create_dir_all(&vm_dir).unwrap();
        std::fs::write(vm_config_file(&vm_dir), r#"{"cpus":1}"#).unwrap();

        // Graceful shutdown in progress (the one-way latch).
        adapter
            .console_draining
            .store(true, std::sync::atomic::Ordering::SeqCst);

        let err = adapter.start_vm("vm-dr", None).await.unwrap_err();
        assert!(
            err.to_string().contains("shutdown in progress"),
            "got {err:?}"
        );
        assert!(
            !adapter.vms.read().await.contains_key("vm-dr"),
            "no entry may be inserted while the drain latch is set"
        );
    }

    // =====================================================================
    // Guest-liveness (boot) watchdog
    // =====================================================================

    use super::{vm_console_log, BootWatchdogConfig, VmWatchState};

    /// Backdate a VM's stall clock so a pass can be evaluated without
    /// real-time waiting.
    fn backdate_watchdog_stall(adapter: &ProcessCloudHypervisorAdapter, vm_id: &str, secs: u64) {
        let mut guard = adapter.boot_watchdog.write().unwrap();
        let wd = guard.as_mut().expect("watchdog configured");
        let state = wd.vms.get_mut(vm_id).expect("watch state exists");
        state.last_change -= std::time::Duration::from_secs(secs);
    }

    /// Backdate a VM's healthy-stretch clock (for budget-reset tests).
    fn backdate_watchdog_health(adapter: &ProcessCloudHypervisorAdapter, vm_id: &str, secs: u64) {
        let mut guard = adapter.boot_watchdog.write().unwrap();
        let wd = guard.as_mut().expect("watchdog configured");
        let state = wd.vms.get_mut(vm_id).expect("watch state exists");
        let healthy_since = state.healthy_since.expect("healthy_since set");
        state.healthy_since = Some(healthy_since - std::time::Duration::from_secs(secs));
    }

    fn watchdog_state_exists(adapter: &ProcessCloudHypervisorAdapter, vm_id: &str) -> bool {
        adapter
            .boot_watchdog
            .read()
            .unwrap()
            .as_ref()
            .expect("watchdog configured")
            .vms
            .contains_key(vm_id)
    }

    fn watchdog_boot_complete(adapter: &ProcessCloudHypervisorAdapter, vm_id: &str) -> bool {
        adapter
            .boot_watchdog
            .read()
            .unwrap()
            .as_ref()
            .expect("watchdog configured")
            .vms
            .get(vm_id)
            .expect("watch state exists")
            .boot_complete
    }

    fn test_watchdog_config() -> BootWatchdogConfig {
        BootWatchdogConfig {
            boot_marker: "systemd-logind".to_string(),
            stall_secs: 60,
            max_reboots: 2,
            healthy_reset_secs: 900,
        }
    }

    /// A fake cloud-hypervisor API endpoint for watchdog tests: answers
    /// `GET /api/v1/vm.info` with a configurable state (200 + JSON) and
    /// `PUT /api/v1/vm.reboot` with 204, recording every request line.
    /// Accepts up to `max_requests` connections, then drops the listener
    /// (an unexpected extra request fails loudly with a refused
    /// connection). `pause()`/`resume()` hold vm.info responses so tests
    /// can interleave mutations mid-pass (bounded at 30 s so a failed
    /// test cannot hang the thread forever).
    #[derive(Clone)]
    struct MockChApiHandle {
        requests: Arc<std::sync::Mutex<Vec<String>>>,
        vm_info_state: Arc<std::sync::Mutex<String>>,
        paused: Arc<(std::sync::Mutex<bool>, std::sync::Condvar)>,
    }

    impl MockChApiHandle {
        fn spawn(api_sock_path: &std::path::Path, max_requests: usize) -> Self {
            use std::io::{Read as _, Write as _};
            if let Some(parent) = api_sock_path.parent() {
                std::fs::create_dir_all(parent).unwrap();
            }
            let listener = std::os::unix::net::UnixListener::bind(api_sock_path).unwrap();
            let handle = MockChApiHandle {
                requests: Arc::new(std::sync::Mutex::new(Vec::new())),
                vm_info_state: Arc::new(std::sync::Mutex::new("Running".to_string())),
                paused: Arc::new((std::sync::Mutex::new(false), std::sync::Condvar::new())),
            };
            let requests = handle.requests.clone();
            let vm_info_state = handle.vm_info_state.clone();
            let paused = handle.paused.clone();
            std::thread::spawn(move || {
                for _ in 0..max_requests {
                    let Ok((mut conn, _)) = listener.accept() else {
                        break;
                    };
                    let mut buf = [0u8; 1024];
                    let n = conn.read(&mut buf).unwrap_or(0);
                    let request = String::from_utf8_lossy(&buf[..n]).into_owned();
                    let request_line = request.lines().next().unwrap_or("").to_string();
                    requests.lock().unwrap().push(request_line.clone());
                    if request_line.starts_with("GET /api/v1/vm.info") {
                        {
                            let (lock, cv) = &*paused;
                            let mut gated = lock.lock().unwrap();
                            while *gated {
                                let (g, timeout) = cv
                                    .wait_timeout(gated, std::time::Duration::from_secs(30))
                                    .unwrap();
                                gated = g;
                                if timeout.timed_out() {
                                    break;
                                }
                            }
                        }
                        let body = format!(
                            "{{\"state\":\"{}\"}}",
                            vm_info_state.lock().unwrap().clone()
                        );
                        let _ = conn.write_all(
                            format!(
                                "HTTP/1.1 200 OK\r\nContent-Type: application/json\r\nContent-Length: {}\r\n\r\n{}",
                                body.len(),
                                body
                            )
                            .as_bytes(),
                        );
                    } else if request_line.starts_with("PUT /api/v1/vm.reboot") {
                        let _ =
                            conn.write_all(b"HTTP/1.1 204 No Content\r\nContent-Length: 0\r\n\r\n");
                    } else {
                        let _ =
                            conn.write_all(b"HTTP/1.1 404 Not Found\r\nContent-Length: 0\r\n\r\n");
                    }
                }
            });
            handle
        }

        fn set_vm_info_state(&self, state: &str) {
            *self.vm_info_state.lock().unwrap() = state.to_string();
        }

        fn reboot_requests(&self) -> usize {
            self.requests()
                .iter()
                .filter(|r| r.starts_with("PUT /api/v1/vm.reboot"))
                .count()
        }

        fn vm_info_requests(&self) -> usize {
            self.requests()
                .iter()
                .filter(|r| r.starts_with("GET /api/v1/vm.info"))
                .count()
        }

        fn requests(&self) -> Vec<String> {
            self.requests.lock().unwrap().clone()
        }

        fn pause(&self) {
            *self.paused.0.lock().unwrap() = true;
        }

        fn resume(&self) {
            let (lock, cv) = &*self.paused;
            let mut gated = lock.lock().unwrap();
            *gated = false;
            cv.notify_all();
        }

        async fn wait_for_vm_info_request(&self) {
            for _ in 0..1000 {
                if self.vm_info_requests() > 0 {
                    return;
                }
                tokio::time::sleep(std::time::Duration::from_millis(10)).await;
            }
            panic!("vm.info request never arrived at the mock");
        }
    }

    /// A watchdog-test VM entry: a live stand-in VMM child, a live
    /// broadcaster flag, a Socket-transport console on a socketpair,
    /// and the given console.log content and boot watermark. Returns
    /// the console socketpair's peer end — hold it for the test's
    /// lifetime so the entry's fd stays a connected socket.
    async fn insert_watchdog_vm(
        adapter: &ProcessCloudHypervisorAdapter,
        vm_id: &str,
        vm_dir: &std::path::Path,
        console_log: &str,
        watermark: u64,
    ) -> std::os::unix::net::UnixStream {
        std::fs::create_dir_all(vm_dir).unwrap();
        std::fs::write(vm_console_log(vm_dir), console_log).unwrap();
        let (proc, console_peer) = watchdog_vm_process(vm_dir, watermark);
        adapter.vms.write().await.insert(vm_id.to_string(), proc);
        console_peer
    }

    fn watchdog_vm_process(
        vm_dir: &std::path::Path,
        watermark: u64,
    ) -> (VmProcess, std::os::unix::net::UnixStream) {
        let (console_peer, console_agent_end) = std::os::unix::net::UnixStream::pair().unwrap();
        let child = tokio::process::Command::new("sleep")
            .arg("60")
            .spawn()
            .unwrap();
        let (pty_tx, _) = tokio::sync::broadcast::channel::<Vec<u8>>(16);
        (
            VmProcess {
                api_socket: vm_dir.join("vm.sock"),
                child: VmmChild::Owned(child),
                console_io: OwnedFd::from(console_agent_end),
                serial_transport: SerialTransport::Socket(vm_dir.join("serial.sock")),
                pty_tx,
                pty_scrollback: Arc::new(std::sync::RwLock::new(Vec::new())),
                broadcaster_alive: Arc::new(AtomicBool::new(true)),
                boot_watermark: AtomicU64::new(watermark),
                last_cpu_seconds: 0.0,
                last_cpu_at: None,
            },
            console_peer,
        )
    }

    /// Remove a watchdog-test entry and reap its stand-in child.
    async fn teardown_watchdog_vm(adapter: &ProcessCloudHypervisorAdapter, vm_id: &str) {
        if let Some(mut proc) = adapter.vms.write().await.remove(vm_id) {
            proc.child.kill(&proc.api_socket, None);
            proc.child.wait().await;
        }
    }

    #[test]
    fn boot_evidence_scopes_to_the_current_boot() {
        let derive = |capture: &str, watermark: u64, marker: &str| {
            VmWatchState::boot_complete_at_init(capture.as_bytes(), watermark, marker)
        };
        // Marker after the (only) banner, watermark at the start: boot
        // complete.
        assert!(derive(
            "firmware\nLinux version 6.8.0\nsystemd-logind started\n",
            0,
            "systemd-logind"
        ));
        // Marker from an EARLIER boot only: the current boot (after the
        // last banner) is incomplete — the same-entry vm.reboot case
        // whose writer keeps appending.
        assert!(!derive(
            "Linux version 6.8.0\nsystemd-logind\nprompt\nLinux version 6.8.0\npartial\n",
            0,
            "systemd-logind"
        ));
        // Watermark past the old boot's banner+marker (a re-spawned VMM
        // appending to the same log): the old boot's marker must not
        // satisfy the current boot — this is the masking case the
        // watermark exists to close. 42 = len("Linux version 6.8.0\n" +
        // "systemd-logind started\n"), i.e. just before "prompt\n".
        assert!(!derive(
            "Linux version 6.8.0\nsystemd-logind started\nprompt\n",
            42,
            "systemd-logind"
        ));
        // The same bytes, watermark at the old banner: complete (the
        // old boot IS the current one).
        assert!(derive(
            "Linux version 6.8.0\nsystemd-logind started\n",
            0,
            "systemd-logind"
        ));
        // No banner at all (frozen-at-firmware signature): the boot has
        // not reached its kernel, so it is incomplete — even if a stray
        // marker from a wrapped-away earlier boot is present in the
        // capture.
        assert!(!derive(
            "firmware only\nsystemd-logind\n",
            0,
            "systemd-logind"
        ));
        assert!(!derive("firmware only\n", 0, "systemd-logind"));
        // Degenerate marker: unsatisfiable detection must not fire.
        assert!(derive("anything", 0, ""));
        // Custom marker for non-systemd guests.
        assert!(derive("Linux version 6.8.0\nlogin:\n", 0, "login:"));
    }

    #[test]
    fn console_delta_evidence_tracks_boots() {
        let scan = |prev_tail: &str, delta: &str, marker: &str| {
            VmWatchState::scan_delta_evidence(prev_tail.as_bytes(), delta.as_bytes(), marker)
        };
        use super::ConsoleDeltaEvidence::*;
        // A marker completing a boot whose banner preceded the delta.
        assert!(matches!(
            scan("", "systemd-logind started\n", "systemd-logind"),
            BootComplete
        ));
        // A new boot began and has not completed.
        assert!(matches!(
            scan("", "Linux version 6.8.0\npartial boot\n", "systemd-logind"),
            NewBoot
        ));
        // A new boot began and completed within the delta.
        assert!(matches!(
            scan(
                "",
                "Linux version 6.8.0\nsystemd-logind started\n",
                "systemd-logind"
            ),
            BootComplete
        ));
        // Marker then a new boot's banner: the reboot wins — incomplete.
        assert!(matches!(
            scan(
                "",
                "systemd-logind\nLinux version 6.8.0\npartial\n",
                "systemd-logind"
            ),
            NewBoot
        ));
        // Runtime output only: no event.
        assert!(matches!(
            scan("", "some service output\n", "systemd-logind"),
            NoEvent
        ));
        // A marker split across the scan boundary is found through the
        // overlap tail.
        assert!(matches!(
            scan("systemd-lo", "gind started\n", "systemd-logind"),
            BootComplete
        ));
        // A banner split across the scan boundary is found too.
        assert!(matches!(
            scan("Linux vers", "ion 6.8.0\npartial\n", "systemd-logind"),
            NewBoot
        ));
    }

    #[tokio::test]
    async fn boot_watchdog_reboots_a_stalled_frozen_boot() {
        let dir = tempfile::tempdir_in(std::env::current_dir().unwrap()).unwrap();
        let vm_dir = dir.path().join("vm-wd-frozen");
        let adapter = ProcessCloudHypervisorAdapter::new(dir.path().join("chv"));
        adapter.configure_boot_watchdog(test_watchdog_config());
        let mock = MockChApiHandle::spawn(&vm_dir.join("vm.sock"), 16);
        let _console_peer = insert_watchdog_vm(
            &adapter,
            "vm-wd-frozen",
            &vm_dir,
            // The frozen-boot signature: firmware output only, no kernel
            // banner, no marker (run 9's boot 3).
            "[INFO] Booting with PVH Boot Protocol\n[INFO] Page tables setup\n",
            0,
        )
        .await;

        // First pass initializes the observation state.
        adapter.boot_watchdog_tick().await;
        // Backdate the stall clock past the window and re-evaluate: the
        // pre-fire gates pass (vm.info Running, same VMM pid, not
        // draining) and the reboot fires.
        backdate_watchdog_stall(&adapter, "vm-wd-frozen", 120);
        adapter.boot_watchdog_tick().await;

        assert_eq!(
            mock.vm_info_requests(),
            1,
            "the pre-fire gate queries vm.info once"
        );
        assert_eq!(
            mock.reboot_requests(),
            1,
            "the watchdog must issue exactly one recovery reboot"
        );
        teardown_watchdog_vm(&adapter, "vm-wd-frozen").await;
    }

    #[tokio::test]
    async fn boot_watchdog_ignores_a_booted_vm() {
        let dir = tempfile::tempdir_in(std::env::current_dir().unwrap()).unwrap();
        let vm_dir = dir.path().join("vm-wd-healthy");
        let adapter = ProcessCloudHypervisorAdapter::new(dir.path().join("chv"));
        adapter.configure_boot_watchdog(test_watchdog_config());
        let mock = MockChApiHandle::spawn(&vm_dir.join("vm.sock"), 16);
        let _console_peer = insert_watchdog_vm(
            &adapter,
            "vm-wd-healthy",
            &vm_dir,
            // Boot complete: marker after the banner. However quiet the
            // console goes afterwards, the watchdog must stay silent.
            "Linux version 6.8.0\nsystemd-logind started\n",
            0,
        )
        .await;

        adapter.boot_watchdog_tick().await;
        backdate_watchdog_stall(&adapter, "vm-wd-healthy", 3600);
        adapter.boot_watchdog_tick().await;

        assert_eq!(
            mock.reboot_requests(),
            0,
            "a marker-healthy VM must never be rebooted"
        );
        assert_eq!(
            mock.vm_info_requests(),
            0,
            "a healthy VM never reaches the pre-fire gates"
        );
        teardown_watchdog_vm(&adapter, "vm-wd-healthy").await;
    }

    #[tokio::test]
    async fn boot_watchdog_treats_console_progress_as_alive() {
        let dir = tempfile::tempdir_in(std::env::current_dir().unwrap()).unwrap();
        let vm_dir = dir.path().join("vm-wd-slow");
        let adapter = ProcessCloudHypervisorAdapter::new(dir.path().join("chv"));
        adapter.configure_boot_watchdog(test_watchdog_config());
        let mock = MockChApiHandle::spawn(&vm_dir.join("vm.sock"), 16);
        let log = vm_console_log(&vm_dir);
        let _console_peer = insert_watchdog_vm(
            &adapter,
            "vm-wd-slow",
            &vm_dir,
            "Linux version 6.8.0\n[   12.3] some service starting\n",
            0,
        )
        .await;

        adapter.boot_watchdog_tick().await;
        // A slow-but-alive boot keeps emitting: the stall clock resets
        // on every growth, however old the previous observation was.
        backdate_watchdog_stall(&adapter, "vm-wd-slow", 3600);
        std::fs::write(
            &log,
            "Linux version 6.8.0\n[   12.3] some service starting\n[   42.0] more services\n",
        )
        .unwrap();
        adapter.boot_watchdog_tick().await;
        // Still within the stall window after that growth.
        backdate_watchdog_stall(&adapter, "vm-wd-slow", 10);
        adapter.boot_watchdog_tick().await;

        assert_eq!(
            mock.reboot_requests(),
            0,
            "a progressing boot must not be rebooted"
        );
        teardown_watchdog_vm(&adapter, "vm-wd-slow").await;
    }

    /// Issue #469 (leg 02 §4.3, the v53.0 #8322 crawl regime): after a
    /// late attach the console can deliver its backlog at a crawl
    /// (~0.6–1.3 KB/s measured with a gap-prone reader) — a boot marker
    /// that already exists in the stream sits up to minutes behind the
    /// head of the backlog. The watchdog's stall window is PROGRESS-based
    /// (any arriving console byte resets it), so a crawling-but-alive
    /// stream must never time out no matter how far past a "full-rate"
    /// boot's timeline the crawl stretches — while a stream that goes
    /// genuinely silent must still fire. This test drives both sides of
    /// that contract: repeated crawling deltas each followed by a
    /// near-the-edge stall check (no fire), then a truly dead window
    /// (fire, exactly once).
    #[tokio::test]
    async fn boot_watchdog_extends_the_stall_window_while_console_bytes_arrive() {
        let dir = tempfile::tempdir_in(std::env::current_dir().unwrap()).unwrap();
        let vm_dir = dir.path().join("vm-wd-crawl");
        let adapter = ProcessCloudHypervisorAdapter::new(dir.path().join("chv"));
        adapter.configure_boot_watchdog(test_watchdog_config());
        let mock = MockChApiHandle::spawn(&vm_dir.join("vm.sock"), 16);
        let log = vm_console_log(&vm_dir);
        let mut console = String::from("Linux version 6.8.0\n[    0.000000] booting\n");
        let _console_peer = insert_watchdog_vm(&adapter, "vm-wd-crawl", &vm_dir, &console, 0).await;

        // First pass initializes the observation state.
        adapter.boot_watchdog_tick().await;

        // The crawl: six rounds, each delivering a small marker-less
        // delta (backlog bytes arriving slowly) and then a stall check
        // just inside the window. A wait that assumed full-rate delivery
        // (marker ~15 s behind the backlog head) would have fired in the
        // first round; the progress-based window must keep extending.
        for round in 0..6u32 {
            console.push_str(&format!("[  {round:>4}.5] crawling kernel log line\n"));
            std::fs::write(&log, &console).unwrap();
            adapter.boot_watchdog_tick().await; // growth: the clock resets
                                                // Simulate the next pass arriving near the end of the stall
                                                // window — the crawl is slower than the window, but alive.
            backdate_watchdog_stall(&adapter, "vm-wd-crawl", 59);
            adapter.boot_watchdog_tick().await;
            assert_eq!(
                mock.reboot_requests(),
                0,
                "a crawling-but-alive console must never time out (round {round})"
            );
        }

        // The stream goes genuinely dead: no further bytes, the window
        // elapses — the frozen signature. The watchdog must still fire.
        backdate_watchdog_stall(&adapter, "vm-wd-crawl", 120);
        adapter.boot_watchdog_tick().await;
        assert_eq!(
            mock.reboot_requests(),
            1,
            "a genuinely dead stream must still time out after the crawl ends"
        );
        teardown_watchdog_vm(&adapter, "vm-wd-crawl").await;
    }

    /// Issue #469, the marker side of the crawl regime: the boot-complete
    /// marker arrives at the TAIL of a crawling backlog — long after a
    /// full-rate boot would have shown it. The watchdog must wait the
    /// crawl out (no reboot, no pre-fire gates consumed) and accept the
    /// marker when it finally lands; once marker-healthy, however quiet
    /// the console goes, it stays silent.
    #[tokio::test]
    async fn boot_watchdog_waits_out_a_crawling_backlog_until_the_marker_arrives() {
        let dir = tempfile::tempdir_in(std::env::current_dir().unwrap()).unwrap();
        let vm_dir = dir.path().join("vm-wd-crawl-marker");
        let adapter = ProcessCloudHypervisorAdapter::new(dir.path().join("chv"));
        adapter.configure_boot_watchdog(test_watchdog_config());
        let mock = MockChApiHandle::spawn(&vm_dir.join("vm.sock"), 16);
        let log = vm_console_log(&vm_dir);
        let mut console = String::from("Linux version 6.8.0\n[    0.000000] booting\n");
        let _console_peer =
            insert_watchdog_vm(&adapter, "vm-wd-crawl-marker", &vm_dir, &console, 0).await;

        adapter.boot_watchdog_tick().await;

        // Crawl without the marker, each round pushed to the stall edge.
        for round in 0..5u32 {
            console.push_str(&format!("[  {round:>4}.5] crawling kernel log line\n"));
            std::fs::write(&log, &console).unwrap();
            adapter.boot_watchdog_tick().await;
            backdate_watchdog_stall(&adapter, "vm-wd-crawl-marker", 59);
            adapter.boot_watchdog_tick().await;
            assert_eq!(
                mock.reboot_requests(),
                0,
                "the marker wait must extend across the crawl (round {round})"
            );
        }

        // The marker finally lands at the tail of the backlog.
        console.push_str("systemd-logind started\n");
        std::fs::write(&log, &console).unwrap();
        adapter.boot_watchdog_tick().await;
        assert!(
            watchdog_boot_complete(&adapter, "vm-wd-crawl-marker"),
            "the marker arriving at the tail of the crawl must complete the boot"
        );

        // Marker-healthy: even an hour of console silence must not fire,
        // and the pre-fire gates are never reached.
        backdate_watchdog_stall(&adapter, "vm-wd-crawl-marker", 3600);
        adapter.boot_watchdog_tick().await;
        assert_eq!(
            mock.reboot_requests(),
            0,
            "a marker-healthy VM must never be rebooted, however quiet"
        );
        assert_eq!(
            mock.vm_info_requests(),
            0,
            "a healthy VM never reaches the pre-fire gates"
        );
        teardown_watchdog_vm(&adapter, "vm-wd-crawl-marker").await;
    }

    #[tokio::test]
    async fn boot_watchdog_stands_down_after_the_budget() {
        let dir = tempfile::tempdir_in(std::env::current_dir().unwrap()).unwrap();
        let vm_dir = dir.path().join("vm-wd-budget");
        let adapter = ProcessCloudHypervisorAdapter::new(dir.path().join("chv"));
        let mut config = test_watchdog_config();
        config.max_reboots = 1;
        adapter.configure_boot_watchdog(config);
        let mock = MockChApiHandle::spawn(&vm_dir.join("vm.sock"), 16);
        let _console_peer = insert_watchdog_vm(
            &adapter,
            "vm-wd-budget",
            &vm_dir,
            "firmware only, frozen\n",
            0,
        )
        .await;

        adapter.boot_watchdog_tick().await;
        // Episode attempt 1: fires.
        backdate_watchdog_stall(&adapter, "vm-wd-budget", 120);
        adapter.boot_watchdog_tick().await;
        // Attempt 2 would exceed the budget: stands down (the pre-fire
        // gates run, the commit declines).
        backdate_watchdog_stall(&adapter, "vm-wd-budget", 120);
        adapter.boot_watchdog_tick().await;
        // And stays down on subsequent passes.
        backdate_watchdog_stall(&adapter, "vm-wd-budget", 120);
        adapter.boot_watchdog_tick().await;

        assert_eq!(
            mock.reboot_requests(),
            1,
            "exactly one reboot before the episode budget stands down"
        );
        teardown_watchdog_vm(&adapter, "vm-wd-budget").await;
    }

    #[tokio::test]
    async fn boot_watchdog_honors_the_drain_latch() {
        let dir = tempfile::tempdir_in(std::env::current_dir().unwrap()).unwrap();
        let vm_dir = dir.path().join("vm-wd-drain");
        let adapter = ProcessCloudHypervisorAdapter::new(dir.path().join("chv"));
        adapter.configure_boot_watchdog(test_watchdog_config());
        let mock = MockChApiHandle::spawn(&vm_dir.join("vm.sock"), 16);
        let _console_peer = insert_watchdog_vm(
            &adapter,
            "vm-wd-drain",
            &vm_dir,
            "firmware only, frozen\n",
            0,
        )
        .await;

        adapter.boot_watchdog_tick().await;
        // Graceful agent shutdown latched: the pass returns before any
        // observation or fire decision.
        adapter
            .console_draining
            .store(true, std::sync::atomic::Ordering::SeqCst);
        backdate_watchdog_stall(&adapter, "vm-wd-drain", 120);
        adapter.boot_watchdog_tick().await;

        assert_eq!(
            mock.reboot_requests(),
            0,
            "the watchdog must not fire while the drain latch is set"
        );
        assert_eq!(mock.requests().len(), 0, "a latched pass touches nothing");
        teardown_watchdog_vm(&adapter, "vm-wd-drain").await;
    }

    #[tokio::test]
    async fn boot_watchdog_never_fires_on_a_capture_gap_or_dead_vmm() {
        let dir = tempfile::tempdir_in(std::env::current_dir().unwrap()).unwrap();
        let vm_dir = dir.path().join("vm-wd-skip");
        let adapter = ProcessCloudHypervisorAdapter::new(dir.path().join("chv"));
        adapter.configure_boot_watchdog(test_watchdog_config());
        let mock = MockChApiHandle::spawn(&vm_dir.join("vm.sock"), 16);
        let _console_peer = insert_watchdog_vm(
            &adapter,
            "vm-wd-skip",
            &vm_dir,
            "firmware only, frozen\n",
            0,
        )
        .await;

        // Dead broadcaster (capture gap): the VM is still observed (its
        // tracking state must survive heal cycles) but never rebooted —
        // missing evidence is the heal path's territory.
        adapter
            .vms
            .write()
            .await
            .get_mut("vm-wd-skip")
            .unwrap()
            .broadcaster_alive
            .store(false, std::sync::atomic::Ordering::SeqCst);
        adapter.boot_watchdog_tick().await;
        assert!(
            watchdog_state_exists(&adapter, "vm-wd-skip"),
            "a capture gap keeps the tracking state (budget survives heal cycles)"
        );
        backdate_watchdog_stall(&adapter, "vm-wd-skip", 120);
        adapter.boot_watchdog_tick().await;
        assert_eq!(
            mock.reboot_requests(),
            0,
            "a capture gap must not be treated as a frozen guest"
        );

        // Broadcaster alive again: still observed… and the stall clock
        // kept running through the gap, so the very next backdated pass
        // WOULD fire — but the VMM child is dead (already reaped): the
        // lifecycle machinery's territory, tracking state dropped.
        {
            let mut map = adapter.vms.write().await;
            let proc = map.get_mut("vm-wd-skip").unwrap();
            proc.broadcaster_alive
                .store(true, std::sync::atomic::Ordering::SeqCst);
            proc.child.kill(&proc.api_socket, None);
            proc.child.wait().await;
        }
        adapter.boot_watchdog_tick().await;
        assert!(
            !watchdog_state_exists(&adapter, "vm-wd-skip"),
            "a dead VMM's tracking state must be dropped"
        );
        assert_eq!(
            mock.reboot_requests(),
            0,
            "a dead VMM must never be rebooted by the watchdog"
        );
    }

    /// HIGH-1 regression: the console writer wraps at 10 MiB by
    /// truncating to zero — a shrink must never look like a new boot,
    /// and a wrapped healthy VM must never look frozen.
    #[tokio::test]
    async fn boot_watchdog_tolerates_console_wraparound() {
        let dir = tempfile::tempdir_in(std::env::current_dir().unwrap()).unwrap();
        let vm_dir = dir.path().join("vm-wd-wrap");
        let adapter = ProcessCloudHypervisorAdapter::new(dir.path().join("chv"));
        adapter.configure_boot_watchdog(test_watchdog_config());
        let mock = MockChApiHandle::spawn(&vm_dir.join("vm.sock"), 16);
        let log = vm_console_log(&vm_dir);
        let _console_peer = insert_watchdog_vm(
            &adapter,
            "vm-wd-wrap",
            &vm_dir,
            "Linux version 6.8.0\nsystemd-logind started\n",
            0,
        )
        .await;

        // Boot complete.
        adapter.boot_watchdog_tick().await;
        // The writer wraps: the file truncates and new runtime output
        // (no banner, no marker) arrives.
        std::fs::write(&log, "periodic runtime log line\n").unwrap();
        adapter.boot_watchdog_tick().await;
        // ... and then the console goes quiet. A wrapped, healthy VM
        // must not be rebooted.
        backdate_watchdog_stall(&adapter, "vm-wd-wrap", 3600);
        adapter.boot_watchdog_tick().await;
        assert_eq!(
            mock.reboot_requests(),
            0,
            "a wrapped healthy VM must never look frozen"
        );

        // A NEW boot after the wrap still announces itself with a fresh
        // banner and gets full watchdog coverage.
        std::fs::write(
            &log,
            "periodic runtime log line\nLinux version 6.8.0\npartial\n",
        )
        .unwrap();
        adapter.boot_watchdog_tick().await;
        backdate_watchdog_stall(&adapter, "vm-wd-wrap", 120);
        adapter.boot_watchdog_tick().await;
        assert_eq!(
            mock.reboot_requests(),
            1,
            "a new boot after a wrap must still be watched"
        );
        teardown_watchdog_vm(&adapter, "vm-wd-wrap").await;
    }

    /// HIGH-2 regression: a VM whose vm.info does not report Running
    /// (Created — stopped before its first boot; Shutdown; paused) is
    /// not mid-boot and must not be rebooted — and the decline consumes
    /// no episode budget.
    #[tokio::test]
    async fn boot_watchdog_requires_running_state() {
        let dir = tempfile::tempdir_in(std::env::current_dir().unwrap()).unwrap();
        let vm_dir = dir.path().join("vm-wd-state");
        let adapter = ProcessCloudHypervisorAdapter::new(dir.path().join("chv"));
        adapter.configure_boot_watchdog(test_watchdog_config());
        let mock = MockChApiHandle::spawn(&vm_dir.join("vm.sock"), 16);
        let _console_peer = insert_watchdog_vm(
            &adapter,
            "vm-wd-state",
            &vm_dir,
            "firmware only, frozen\n",
            0,
        )
        .await;

        adapter.boot_watchdog_tick().await;
        mock.set_vm_info_state("Created");
        backdate_watchdog_stall(&adapter, "vm-wd-state", 120);
        adapter.boot_watchdog_tick().await;
        assert_eq!(
            mock.vm_info_requests(),
            1,
            "the candidate reached the state gate"
        );
        assert_eq!(
            mock.reboot_requests(),
            0,
            "a non-Running VM must not be rebooted"
        );

        // The decline consumed no budget: once the VM reports Running
        // again, the same episode still has its full budget.
        mock.set_vm_info_state("Running");
        backdate_watchdog_stall(&adapter, "vm-wd-state", 120);
        adapter.boot_watchdog_tick().await;
        assert_eq!(mock.reboot_requests(), 1, "the decline consumed no budget");
        teardown_watchdog_vm(&adapter, "vm-wd-state").await;
    }

    /// MEDIUM-3 regression: a re-spawned VMM appends to the same
    /// console.log — the OLD boot's banner+marker sit before the boot
    /// watermark and must not mask a frozen (or healthy) new boot.
    #[tokio::test]
    async fn boot_watchdog_honors_the_boot_watermark() {
        let dir = tempfile::tempdir_in(std::env::current_dir().unwrap()).unwrap();
        let adapter = ProcessCloudHypervisorAdapter::new(dir.path().join("chv"));
        adapter.configure_boot_watchdog(test_watchdog_config());
        let old_boot = "Linux version 6.8.0\nsystemd-logind started\nprompt\n";
        let watermark = old_boot.len() as u64;

        // The frozen variant: the new boot emits firmware only (run 9's
        // boot 3, on a re-spawned VMM whose log carries a completed
        // previous boot).
        let frozen_dir = dir.path().join("vm-wd-mask-frozen");
        let mock_frozen = MockChApiHandle::spawn(&frozen_dir.join("vm.sock"), 16);
        let _peer_frozen = insert_watchdog_vm(
            &adapter,
            "vm-wd-mask-frozen",
            &frozen_dir,
            &format!("{old_boot}[INFO] Booting with PVH Boot Protocol\n"),
            watermark,
        )
        .await;
        adapter.boot_watchdog_tick().await;
        backdate_watchdog_stall(&adapter, "vm-wd-mask-frozen", 120);
        adapter.boot_watchdog_tick().await;
        assert_eq!(
            mock_frozen.reboot_requests(),
            1,
            "the old boot's marker must not mask a frozen new boot"
        );

        // The healthy variant: the new boot's banner+marker arrive after
        // the watermark.
        let healthy_dir = dir.path().join("vm-wd-mask-healthy");
        let mock_healthy = MockChApiHandle::spawn(&healthy_dir.join("vm.sock"), 16);
        let _peer_healthy = insert_watchdog_vm(
            &adapter,
            "vm-wd-mask-healthy",
            &healthy_dir,
            &format!("{old_boot}Linux version 6.8.0\nsystemd-logind started\n"),
            watermark,
        )
        .await;
        adapter.boot_watchdog_tick().await;
        backdate_watchdog_stall(&adapter, "vm-wd-mask-healthy", 3600);
        adapter.boot_watchdog_tick().await;
        assert_eq!(
            mock_healthy.reboot_requests(),
            0,
            "a new boot completing after the watermark is healthy"
        );

        teardown_watchdog_vm(&adapter, "vm-wd-mask-frozen").await;
        teardown_watchdog_vm(&adapter, "vm-wd-mask-healthy").await;
    }

    /// A marker split across scan boundaries is found through the
    /// overlap tail — a missed split marker would fire the watchdog on
    /// a healthy boot.
    #[tokio::test]
    async fn boot_watchdog_finds_markers_split_across_scans() {
        let dir = tempfile::tempdir_in(std::env::current_dir().unwrap()).unwrap();
        let vm_dir = dir.path().join("vm-wd-split");
        let adapter = ProcessCloudHypervisorAdapter::new(dir.path().join("chv"));
        adapter.configure_boot_watchdog(test_watchdog_config());
        let mock = MockChApiHandle::spawn(&vm_dir.join("vm.sock"), 16);
        let log = vm_console_log(&vm_dir);
        let _console_peer =
            insert_watchdog_vm(&adapter, "vm-wd-split", &vm_dir, "Linux version 6.8.0\n", 0).await;

        // Mid-boot, banner printed, marker pending.
        adapter.boot_watchdog_tick().await;
        // The marker arrives in two pieces across two passes.
        std::fs::write(&log, "Linux version 6.8.0\nsystemd-lo").unwrap();
        adapter.boot_watchdog_tick().await;
        // Stall the clock past the window before the second half
        // arrives: if the split marker were missed, this pass fires.
        backdate_watchdog_stall(&adapter, "vm-wd-split", 120);
        std::fs::write(&log, "Linux version 6.8.0\nsystemd-logind started\n").unwrap();
        adapter.boot_watchdog_tick().await;
        // The growth alone would keep the watchdog silent (last_change
        // resets on any growth), so assert the EVIDENCE, not just the
        // absence of a reboot: the split marker must have completed the
        // boot.
        assert!(
            watchdog_boot_complete(&adapter, "vm-wd-split"),
            "a marker split across scans must complete the boot"
        );
        assert_eq!(
            mock.reboot_requests(),
            0,
            "a marker split across scans must complete the boot"
        );
        teardown_watchdog_vm(&adapter, "vm-wd-split").await;
    }

    /// NEW-1 regression: the tracking state is anchored to the VMM
    /// generation (pid) and the boot watermark. A re-spawn or a
    /// `reboot_vm` that completes between passes must re-derive the
    /// evidence — otherwise the previous generation's completed boot
    /// masks a new boot frozen before its kernel banner, silently and
    /// forever.
    #[tokio::test]
    async fn boot_watchdog_rederives_when_the_generation_changes() {
        let dir = tempfile::tempdir_in(std::env::current_dir().unwrap()).unwrap();
        let vm_dir = dir.path().join("vm-wd-gen");
        let adapter = ProcessCloudHypervisorAdapter::new(dir.path().join("chv"));
        adapter.configure_boot_watchdog(test_watchdog_config());
        let mock = MockChApiHandle::spawn(&vm_dir.join("vm.sock"), 16);
        let log = vm_console_log(&vm_dir);

        // Shape 1 — re-spawn over a TRUNCATED log (the graceful-stop
        // shape): the new entry's watermark is 0, same as the old
        // state's, so the pid is the ONLY stale signal — this pins the
        // pid anchor specifically. The previous boot completed (evidence
        // true); the new VMM's boot writes firmware only and freezes.
        let old_boot = "Linux version 6.8.0\nsystemd-logind started\n";
        let _console_peer = insert_watchdog_vm(&adapter, "vm-wd-gen", &vm_dir, old_boot, 0).await;
        adapter.boot_watchdog_tick().await;
        assert!(
            watchdog_boot_complete(&adapter, "vm-wd-gen"),
            "precondition: the first generation's boot completed"
        );
        // The re-spawn: the log is truncated (graceful stop) and the new
        // boot's frozen-at-firmware output replaces it; the entry is
        // replaced by a new VMM with a fresh (zero) watermark.
        let firmware = "[INFO] Booting with PVH Boot Protocol\n";
        std::fs::write(&log, firmware).unwrap();
        {
            let mut map = adapter.vms.write().await;
            if let Some(mut old) = map.remove("vm-wd-gen") {
                old.child.kill(&old.api_socket, None);
                old.child.wait().await;
            }
            let (proc, peer) = watchdog_vm_process(&vm_dir, 0);
            map.insert("vm-wd-gen".to_string(), proc);
            drop(peer);
        }
        adapter.boot_watchdog_tick().await;
        assert!(
            !watchdog_boot_complete(&adapter, "vm-wd-gen"),
            "the re-spawned generation must not inherit the old boot's evidence"
        );
        backdate_watchdog_stall(&adapter, "vm-wd-gen", 120);
        adapter.boot_watchdog_tick().await;
        assert_eq!(
            mock.reboot_requests(),
            1,
            "a new boot frozen before its banner after a re-spawn must be caught"
        );

        // Shape 2 — same VMM, `reboot_vm` bumps the watermark: the
        // post-reboot boot freezes at firmware and must be caught even
        // though the pid is unchanged. To pin the WATERMARK anchor
        // specifically, the state must enter this shape with complete
        // evidence — otherwise (entering incomplete, as after shape 1)
        // the freeze fires even with the watermark clause deleted, and
        // the test asserts nothing about the anchor. So: recover to a
        // completed boot first, then reboot and freeze.
        let recovered = format!("{firmware}{old_boot}");
        std::fs::write(&log, &recovered).unwrap();
        adapter.boot_watchdog_tick().await;
        assert!(
            watchdog_boot_complete(&adapter, "vm-wd-gen"),
            "precondition: the recovered boot completed (marker after its banner)"
        );
        // The reboot: watermark bumps to the file size at reboot time,
        // and the new boot's frozen-at-firmware output follows it.
        std::fs::write(&log, format!("{recovered}{firmware}")).unwrap();
        {
            let mut map = adapter.vms.write().await;
            let proc = map.get_mut("vm-wd-gen").unwrap();
            proc.boot_watermark
                .store(recovered.len() as u64, std::sync::atomic::Ordering::SeqCst);
        }
        adapter.boot_watchdog_tick().await;
        assert!(
            !watchdog_boot_complete(&adapter, "vm-wd-gen"),
            "a rebooted boot must not inherit the pre-reboot evidence"
        );
        backdate_watchdog_stall(&adapter, "vm-wd-gen", 120);
        adapter.boot_watchdog_tick().await;
        assert_eq!(
            mock.reboot_requests(),
            2,
            "a new boot frozen before its banner after a reboot must be caught"
        );
        teardown_watchdog_vm(&adapter, "vm-wd-gen").await;
    }

    #[tokio::test]
    async fn boot_watchdog_resets_budget_after_sustained_health() {
        let dir = tempfile::tempdir_in(std::env::current_dir().unwrap()).unwrap();
        let vm_dir = dir.path().join("vm-wd-reset");
        let adapter = ProcessCloudHypervisorAdapter::new(dir.path().join("chv"));
        let mut config = test_watchdog_config();
        config.max_reboots = 1;
        adapter.configure_boot_watchdog(config);
        let mock = MockChApiHandle::spawn(&vm_dir.join("vm.sock"), 16);
        let log = vm_console_log(&vm_dir);
        let _console_peer = insert_watchdog_vm(
            &adapter,
            "vm-wd-reset",
            &vm_dir,
            "firmware only, frozen\n",
            0,
        )
        .await;

        // Episode 1: fires once, then the budget is exhausted.
        adapter.boot_watchdog_tick().await;
        backdate_watchdog_stall(&adapter, "vm-wd-reset", 120);
        adapter.boot_watchdog_tick().await;
        assert_eq!(mock.reboot_requests(), 1);

        // The VM recovers and stays marker-healthy long enough to reset
        // the budget.
        std::fs::write(
            &log,
            "firmware only, frozen\nLinux version 6.8.0\nsystemd-logind\n",
        )
        .unwrap();
        adapter.boot_watchdog_tick().await;
        backdate_watchdog_health(&adapter, "vm-wd-reset", 900);
        adapter.boot_watchdog_tick().await;

        // A NEW unhealthy episode gets a fresh budget.
        std::fs::write(
            &log,
            "firmware only, frozen\nLinux version 6.8.0\nsystemd-logind\nLinux version 6.8.1\npartial\n",
        )
        .unwrap();
        adapter.boot_watchdog_tick().await;
        backdate_watchdog_stall(&adapter, "vm-wd-reset", 120);
        adapter.boot_watchdog_tick().await;
        assert_eq!(
            mock.reboot_requests(),
            2,
            "sustained health resets the episode budget"
        );
        teardown_watchdog_vm(&adapter, "vm-wd-reset").await;
    }

    #[tokio::test]
    async fn boot_watchdog_skips_pty_transport() {
        let dir = tempfile::tempdir_in(std::env::current_dir().unwrap()).unwrap();
        let vm_dir = dir.path().join("vm-wd-pty");
        let adapter = ProcessCloudHypervisorAdapter::new(dir.path().join("chv"));
        adapter.configure_boot_watchdog(test_watchdog_config());
        let mock = MockChApiHandle::spawn(&vm_dir.join("vm.sock"), 16);
        std::fs::create_dir_all(&vm_dir).unwrap();
        std::fs::write(vm_console_log(&vm_dir), "firmware only\n").unwrap();
        let (console_peer, console_agent_end) = std::os::unix::net::UnixStream::pair().unwrap();
        let child = tokio::process::Command::new("sleep")
            .arg("60")
            .spawn()
            .unwrap();
        let (pty_tx, _) = tokio::sync::broadcast::channel::<Vec<u8>>(16);
        adapter.vms.write().await.insert(
            "vm-wd-pty".to_string(),
            VmProcess {
                api_socket: vm_dir.join("vm.sock"),
                child: VmmChild::Owned(child),
                console_io: OwnedFd::from(console_agent_end),
                serial_transport: SerialTransport::Pty,
                pty_tx,
                pty_scrollback: Arc::new(std::sync::RwLock::new(Vec::new())),
                broadcaster_alive: Arc::new(AtomicBool::new(true)),
                boot_watermark: AtomicU64::new(0),
                last_cpu_seconds: 0.0,
                last_cpu_at: None,
            },
        );
        drop(console_peer);

        adapter.boot_watchdog_tick().await;
        adapter.boot_watchdog_tick().await;
        assert!(
            !watchdog_state_exists(&adapter, "vm-wd-pty"),
            "Pty-transport VMs are not watchdog candidates (rotation is Socket-only)"
        );
        assert_eq!(mock.reboot_requests(), 0);
        teardown_watchdog_vm(&adapter, "vm-wd-pty").await;
    }

    /// LOW-6 regression: the pre-fire identity re-check — a candidate
    /// decided against one VMM generation must not reboot a different
    /// (e.g. freshly re-spawned) one. The mock's vm.info pause holds the
    /// pass mid-flight while the test swaps the entry.
    #[tokio::test]
    async fn boot_watchdog_rechecks_target_identity_before_firing() {
        let dir = tempfile::tempdir_in(std::env::current_dir().unwrap()).unwrap();
        let vm_dir = dir.path().join("vm-wd-toctou");
        let adapter = Arc::new(ProcessCloudHypervisorAdapter::new(dir.path().join("chv")));
        adapter.configure_boot_watchdog(test_watchdog_config());
        let mock = MockChApiHandle::spawn(&vm_dir.join("vm.sock"), 16);
        let _console_peer = insert_watchdog_vm(
            &adapter,
            "vm-wd-toctou",
            &vm_dir,
            "firmware only, frozen\n",
            0,
        )
        .await;

        adapter.boot_watchdog_tick().await;
        backdate_watchdog_stall(&adapter, "vm-wd-toctou", 120);
        // Hold the pass inside the vm.info gate.
        mock.pause();
        let tick_adapter = Arc::clone(&adapter);
        let tick = tokio::spawn(async move { tick_adapter.boot_watchdog_tick().await });
        mock.wait_for_vm_info_request().await;
        // The VMM is re-spawned under the pass (a new generation with a
        // different pid) — exactly the accidental-reboot window.
        {
            let mut map = adapter.vms.write().await;
            if let Some(mut old) = map.remove("vm-wd-toctou") {
                old.child.kill(&old.api_socket, None);
                old.child.wait().await;
            }
            let (proc, peer) = watchdog_vm_process(&vm_dir, 0);
            map.insert("vm-wd-toctou".to_string(), proc);
            drop(peer);
        }
        mock.resume();
        tick.await.unwrap();

        assert_eq!(
            mock.reboot_requests(),
            0,
            "a decision made about one VMM generation must not reboot another"
        );
        teardown_watchdog_vm(&adapter, "vm-wd-toctou").await;
    }

    /// LOW-7 regression: the drain latch is re-checked immediately
    /// before firing, not just at pass entry.
    #[tokio::test]
    async fn boot_watchdog_rechecks_drain_latch_before_firing() {
        let dir = tempfile::tempdir_in(std::env::current_dir().unwrap()).unwrap();
        let vm_dir = dir.path().join("vm-wd-drain2");
        let adapter = Arc::new(ProcessCloudHypervisorAdapter::new(dir.path().join("chv")));
        adapter.configure_boot_watchdog(test_watchdog_config());
        let mock = MockChApiHandle::spawn(&vm_dir.join("vm.sock"), 16);
        let _console_peer = insert_watchdog_vm(
            &adapter,
            "vm-wd-drain2",
            &vm_dir,
            "firmware only, frozen\n",
            0,
        )
        .await;

        adapter.boot_watchdog_tick().await;
        backdate_watchdog_stall(&adapter, "vm-wd-drain2", 120);
        // Hold the pass inside the vm.info gate, then latch the drain —
        // graceful shutdown began mid-pass.
        mock.pause();
        let tick_adapter = Arc::clone(&adapter);
        let tick = tokio::spawn(async move { tick_adapter.boot_watchdog_tick().await });
        mock.wait_for_vm_info_request().await;
        adapter
            .console_draining
            .store(true, std::sync::atomic::Ordering::SeqCst);
        mock.resume();
        tick.await.unwrap();

        assert_eq!(
            mock.reboot_requests(),
            0,
            "a reboot must not fire after the drain latch is set mid-pass"
        );
        teardown_watchdog_vm(&adapter, "vm-wd-drain2").await;
    }

    /// The crash-window residual: a LIVE VMM whose map entry is gone
    /// (agent died between spawn and pidfile write, or adoption was
    /// skipped). A later start must adopt it honestly — never fork a
    /// second VMM onto one disk.
    #[tokio::test]
    async fn start_adopts_live_untracked_vmm_instead_of_forking() {
        use super::{pid_exists, pid_is_cloud_hypervisor};

        let dir = tempfile::tempdir_in(std::env::current_dir().unwrap()).unwrap();
        let runtime_root = dir.path().join("runtime");
        let vm_dir = runtime_root.join("vms").join("vm-cw");
        std::fs::create_dir_all(&vm_dir).unwrap();
        std::fs::write(vm_dir.join("vm-config.json"), r#"{"cpus":1}"#).unwrap();
        let api_socket = vm_dir.join("vm.sock");

        // Stand in for a live cloud-hypervisor: file name, /proc exe link
        // and cmdline all match the adapter's identity checks (see
        // `write_vmm_standin_binary` / `spawn_vmm_standin`).
        let fake_bin = write_vmm_standin_binary(dir.path());
        // RAII: the guard killpg+reaps the whole group on drop, so a
        // mid-test panic cannot leak the shell and its sleep child.
        let fake = StandinVmm(spawn_vmm_standin(&fake_bin, &api_socket));

        let adapter = ProcessCloudHypervisorAdapter::new(&fake_bin);
        adapter.adopt_running_vms(&runtime_root).await.unwrap();

        let count_vmm = || {
            std::fs::read_dir("/proc")
                .unwrap()
                .flatten()
                .filter_map(|e| e.file_name().to_string_lossy().parse::<u32>().ok())
                .filter(|&pid| {
                    pid != std::process::id()
                        && pid_is_cloud_hypervisor(
                            pid,
                            &api_socket,
                            Some(std::ffi::OsStr::new("cloud-hypervisor")),
                        )
                })
                .count()
        };
        // spawn() returns before exec(): wait until the stand-in is
        // actually observable with its final cmdline before asserting
        // anything about /proc.
        let setup_deadline = std::time::Instant::now() + std::time::Duration::from_secs(5);
        while count_vmm() == 0 && std::time::Instant::now() < setup_deadline {
            std::thread::sleep(std::time::Duration::from_millis(25));
        }
        assert_eq!(count_vmm(), 1, "test setup: the stand-in must be found");

        // The start must not fork: it adopts the live VMM and boots
        // against its api socket, which the stand-in never bound — an
        // error, but never a second process.
        let _ = adapter.start_vm("vm-cw", None).await.unwrap_err();
        assert_eq!(
            count_vmm(),
            1,
            "start must never spawn a second VMM over a live one"
        );
        assert!(pid_exists(fake.pid()), "the live VMM must be untouched");
        {
            let map = adapter.vms.read().await;
            let proc = map.get("vm-cw").expect("the entry must be re-derived");
            assert!(
                matches!(&proc.child, VmmChild::Adopted(pid) if *pid == fake.pid()),
                "the live untracked VMM must be adopted by pid"
            );
        }

        // (group teardown is the guard's Drop)
    }

    /// The delete liveness gate (M2.5 finding): "no map entry" is not
    /// proof of "no VMM" — an agent crash in the create window or a
    /// skipped adoption leaves the runtime dir owned by a live VMM this
    /// agent never tracked. The adapter's delete must reap it (under
    /// the per-VM lifecycle lock, like every lifecycle op) and then
    /// remove the artifacts — never claim success while the guest runs
    /// untracked.
    #[tokio::test]
    async fn delete_after_force_stop_reaps_live_untracked_vmm() {
        use super::{vm_config_file, vm_pid_file};

        let dir = tempfile::tempdir_in(std::env::current_dir().unwrap()).unwrap();
        let runtime_root = dir.path().join("runtime");
        // Stand in for a live cloud-hypervisor (see the helpers): the
        // exe-strict kill authorization must match its name.
        let fake_bin = write_vmm_standin_binary(dir.path());
        let adapter = ProcessCloudHypervisorAdapter::new(&fake_bin);
        // Startup FIRST (nothing to adopt yet): the residual happens at
        // RUNTIME, like the force-stop flow.
        adapter.adopt_running_vms(&runtime_root).await.unwrap();

        let vm_dir = runtime_root.join("vms").join("vm-orphan");
        std::fs::create_dir_all(&vm_dir).unwrap();
        std::fs::write(vm_config_file(&vm_dir), r#"{"cpus":1}"#).unwrap();
        let api_socket = vm_dir.join("vm.sock");

        // RAII (see `StandinVmm`): the guard reaps the whole group on
        // drop even if an assertion below panics.
        let mut fake = StandinVmm(spawn_vmm_standin(&fake_bin, &api_socket));
        // Wait out the spawn-before-exec /proc race before running the
        // delete.
        wait_for_standin_argv(fake.pid());

        adapter.delete_vm("vm-orphan", None).await.unwrap();
        assert!(
            fake.try_wait().unwrap().is_some(),
            "the untracked VMM must have been reaped"
        );
        assert!(
            !vm_config_file(&vm_dir).exists(),
            "persisted config must be removed after the reap"
        );
        assert!(
            !vm_pid_file(&vm_dir).exists(),
            "pid file must be removed after the reap"
        );
        assert!(!api_socket.exists(), "api socket must be removed");

        // (group teardown is the guard's Drop — it also reaps the sleep
        // child orphaned when the adapter reaped only the shell)

        // Misroute rule: a VM that never ran on this node stays NotFound.
        let err = adapter.delete_vm("vm-never", None).await.unwrap_err();
        assert!(matches!(err, ChvError::NotFound { .. }), "got {err:?}");
    }

    /// delete_vm removes the adapter-owned runtime artifacts (api socket,
    /// ch.pid, vm-config.json) alongside the VMM process.
    #[tokio::test]
    async fn delete_vm_removes_runtime_artifacts() {
        let dir = tempfile::tempdir_in(std::env::current_dir().unwrap()).unwrap();
        let vm_dir = dir.path().join("vm-del");
        std::fs::create_dir_all(&vm_dir).unwrap();
        let api_socket = vm_dir.join("vm.sock");
        std::fs::write(&api_socket, b"").unwrap();
        std::fs::write(vm_dir.join("ch.pid"), "12345").unwrap();
        std::fs::write(vm_dir.join("vm-config.json"), "{}").unwrap();

        let adapter = ProcessCloudHypervisorAdapter::new(dir.path().join("chv"));
        let (pty_tx, _) = tokio::sync::broadcast::channel::<Vec<u8>>(4096);
        let mut child = tokio::process::Command::new("true").spawn().unwrap();
        let _ = child.wait().await;
        {
            let mut map = adapter.vms.write().await;
            map.insert(
                "vm-del".to_string(),
                VmProcess {
                    api_socket: api_socket.clone(),
                    child: VmmChild::Owned(child),
                    console_io: std::fs::File::open("/dev/null").unwrap().into(),
                    serial_transport: SerialTransport::Socket(vm_dir.join("serial.sock")),
                    pty_tx,
                    pty_scrollback: Arc::new(std::sync::RwLock::new(Vec::new())),
                    broadcaster_alive: Arc::new(AtomicBool::new(false)),
                    last_cpu_seconds: 0.0,
                    last_cpu_at: None,
                    boot_watermark: AtomicU64::new(0),
                },
            );
        }

        adapter.delete_vm("vm-del", None).await.unwrap();
        assert!(!api_socket.exists(), "api socket must be removed");
        assert!(!vm_dir.join("ch.pid").exists(), "pidfile must be removed");
        assert!(
            !vm_dir.join("vm-config.json").exists(),
            "persisted config must be removed"
        );
        assert!(!adapter.vms.read().await.contains_key("vm-del"));
    }

    /// Lifecycle operations serialize per VM: with the per-VM mutex held
    /// by an external holder, a lifecycle op on the same VM must block
    /// instead of running concurrently (two concurrent starts over an
    /// exited VMM would otherwise both re-spawn a process for it). An op
    /// on a DIFFERENT VM must not be blocked by the first holder.
    #[tokio::test]
    async fn lifecycle_ops_serialize_per_vm() {
        let dir = tempfile::tempdir_in(std::env::current_dir().unwrap()).unwrap();
        let adapter = ProcessCloudHypervisorAdapter::new(dir.path().join("chv"));

        let held = adapter.vm_op_lock("vm-a");
        let _guard = held.lock_owned().await;

        // Same VM: must block — without serialization it would complete
        // immediately with NotFound (the map is empty).
        let start_a = adapter.start_vm("vm-a", None);
        match tokio::time::timeout(std::time::Duration::from_millis(200), start_a).await {
            Err(_elapsed) => {} // still blocked — serialization holds
            Ok(res) => panic!("start on vm-a ran while its lifecycle lock was held: {res:?}"),
        }

        // Different VM: must not be blocked by vm-a's holder (it fails
        // fast with NotFound instead).
        let start_b = adapter.start_vm("vm-b", None);
        match tokio::time::timeout(std::time::Duration::from_millis(200), start_b).await {
            Ok(Err(ChvError::NotFound { .. })) => {}
            other => panic!("start on vm-b should fail fast with NotFound, got {other:?}"),
        }
    }

    /// create refuses to run a second VMM for a VM whose runtime dir
    /// already hosts a live one — by pidfile identity, and by its api
    /// socket answering — while a dead pid and a stale (non-listening)
    /// socket file do not block a create.
    #[tokio::test]
    async fn create_refuses_over_live_vmm() {
        use std::io::Write as _;

        let dir = tempfile::tempdir_in(std::env::current_dir().unwrap()).unwrap();

        // --- Case 1: live VMM identified by pidfile + cmdline + exe. ---
        let live_dir = dir.path().join("vms").join("vm-live");
        std::fs::create_dir_all(&live_dir).unwrap();
        let live_api_socket = live_dir.join("vm.sock");
        let mut orphan = tokio::process::Command::new("sh")
            .arg("-c")
            .arg("sleep 5; true")
            .arg("--api-socket")
            .arg(&live_api_socket)
            .spawn()
            .unwrap();
        let orphan_pid = orphan.id().expect("freshly spawned child has a pid");
        wait_for_cmdline_containing(orphan_pid, &live_api_socket.to_string_lossy()).await;
        std::fs::write(live_dir.join("ch.pid"), format!("{orphan_pid}")).unwrap();
        let orphan_exe = std::fs::read_link(format!("/proc/{orphan_pid}/exe")).unwrap();

        let adapter = ProcessCloudHypervisorAdapter::new(orphan_exe.clone());
        let cfg = VmConfig {
            vm_id: "vm-live".to_string(),
            cpus: 1,
            memory_bytes: 512 * 1024 * 1024,
            kernel_path: dir.path().join("kernel"), // unused by the guard
            firmware_path: None,
            disks: vec![],
            nics: vec![],
            api_socket_path: live_api_socket.clone(),
            cloud_init_userdata: None,
            hypervisor_overrides: None,
        };
        let err = adapter.ensure_no_live_vmm(&cfg).await.unwrap_err();
        match &err {
            ChvError::Internal { reason } => {
                assert!(
                    reason.contains("already running"),
                    "unexpected error: {reason}"
                );
            }
            other => panic!("expected Internal, got {other:?}"),
        }

        let _ = orphan.start_kill();
        let _ = orphan.wait().await;

        // --- Case 2: dead pid + stale non-listening socket: no refusal. ---
        std::fs::write(&live_api_socket, b"").unwrap(); // stale file
        adapter.ensure_no_live_vmm(&cfg).await.unwrap();

        // --- Case 3: no pidfile, but the api socket answers: refusal. ---
        let anon_dir = dir.path().join("vms").join("vm-anon");
        std::fs::create_dir_all(&anon_dir).unwrap();
        let anon_api_socket = anon_dir.join("vm.sock");
        let responder = std::os::unix::net::UnixListener::bind(&anon_api_socket).unwrap();
        let server = std::thread::spawn(move || {
            if let Ok((mut conn, _)) = responder.accept() {
                let _ = conn.write_all(b"HTTP/1.1 200 OK\r\nContent-Length: 0\r\n\r\n");
                // Hold the connection open until the test ends.
                std::thread::sleep(std::time::Duration::from_millis(2500));
            }
        });
        let cfg_anon = VmConfig {
            vm_id: "vm-anon".to_string(),
            cpus: 1,
            memory_bytes: 512 * 1024 * 1024,
            kernel_path: dir.path().join("kernel"),
            firmware_path: None,
            disks: vec![],
            nics: vec![],
            api_socket_path: anon_api_socket.clone(),
            cloud_init_userdata: None,
            hypervisor_overrides: None,
        };
        let err = adapter.ensure_no_live_vmm(&cfg_anon).await.unwrap_err();
        match &err {
            ChvError::Internal { reason } => {
                assert!(
                    reason.contains("answered by a running cloud-hypervisor"),
                    "unexpected error: {reason}"
                );
            }
            other => panic!("expected Internal, got {other:?}"),
        }
        server.join().expect("responder thread");
    }

    #[test]
    fn validate_vm_config_rejects_missing_kernel() {
        let dir = tempfile::tempdir_in(std::env::current_dir().unwrap()).unwrap();
        let chv_bin = dir.path().join("cloud-hypervisor");
        std::fs::write(&chv_bin, b"#!/bin/true").unwrap();
        let adapter = ProcessCloudHypervisorAdapter::new(chv_bin);
        let cfg = VmConfig {
            vm_id: "vm-1".to_string(),
            cpus: 1,
            memory_bytes: 512 * 1024 * 1024,
            kernel_path: dir.path().join("missing-kernel"),
            firmware_path: None,
            disks: vec![],
            nics: vec![],
            api_socket_path: PathBuf::from("/tmp/chv/vms/vm-1/vm.sock"),
            cloud_init_userdata: None,
            hypervisor_overrides: None,
        };
        let err = adapter.validate_vm_config(&cfg).unwrap_err();
        assert!(matches!(err, ChvError::InvalidArgument { field, .. } if field == "kernel_path"));
    }

    #[test]
    fn validate_vm_config_accepts_existing_paths() {
        let dir = tempfile::tempdir_in(std::env::current_dir().unwrap()).unwrap();
        let chv_bin = dir.path().join("cloud-hypervisor");
        let kernel = dir.path().join("vmlinux");
        let disk = dir.path().join("root.img");
        std::fs::write(&chv_bin, b"#!/bin/true").unwrap();
        std::fs::write(&kernel, b"kernel").unwrap();
        std::fs::write(&disk, b"disk").unwrap();
        let adapter = ProcessCloudHypervisorAdapter::new(chv_bin);
        let cfg = VmConfig {
            vm_id: "vm-1".to_string(),
            cpus: 1,
            memory_bytes: 512 * 1024 * 1024,
            kernel_path: kernel,
            firmware_path: None,
            disks: vec![VmDiskConfig {
                path: disk,
                read_only: false,
                id: None,
            }],
            nics: vec![],
            api_socket_path: PathBuf::from("/tmp/chv/vms/vm-1/vm.sock"),
            cloud_init_userdata: None,
            hypervisor_overrides: None,
        };
        adapter.validate_vm_config(&cfg).unwrap();
    }

    #[test]
    fn nested_cpu_config_includes_complete_topology_for_cloud_hypervisor_v51() {
        let cfg = VmConfig {
            vm_id: "vm-1".to_string(),
            cpus: 2,
            memory_bytes: 512 * 1024 * 1024,
            kernel_path: PathBuf::from("/tmp/kernel"),
            firmware_path: None,
            disks: vec![],
            nics: vec![],
            api_socket_path: PathBuf::from("/tmp/chv/vms/vm-1/vm.sock"),
            cloud_init_userdata: None,
            hypervisor_overrides: Some(HypervisorOverrides {
                cpu_nested: Some(true),
                ..Default::default()
            }),
        };

        let cpus = build_cpus_config(&cfg);

        assert_eq!(cpus["boot_vcpus"], 2);
        assert_eq!(cpus["max_vcpus"], 2);
        assert_eq!(cpus["topology"]["threads_per_core"], 1);
        assert_eq!(cpus["topology"]["cores_per_die"], 2);
        assert_eq!(cpus["topology"]["dies_per_package"], 1);
        assert_eq!(cpus["topology"]["packages"], 1);
    }

    #[tokio::test]
    async fn stop_vm_force_clears_console_cache() {
        let dir = tempfile::tempdir_in(std::env::current_dir().unwrap()).unwrap();
        let vm_dir = dir.path().join("vm-test");
        std::fs::create_dir_all(&vm_dir).unwrap();

        // Create a dummy console.log with some content.
        let console_log = vm_dir.join("console.log");
        std::fs::write(&console_log, b"boot log line 1\nboot log line 2\n").unwrap();

        // Spawn a short-lived child process that we can kill.
        let child = tokio::process::Command::new("sleep")
            .arg("60")
            .spawn()
            .unwrap();

        // Create a fake VmProcess directly in the adapter's map.
        let adapter = ProcessCloudHypervisorAdapter::new(dir.path().join("chv"));
        let (pty_tx, _) = tokio::sync::broadcast::channel::<Vec<u8>>(4096);
        let pty_scrollback = Arc::new(std::sync::RwLock::new(Vec::from(b"scrollback data")));
        let console_io = std::fs::File::open("/dev/null").unwrap().into();

        {
            let mut map = adapter.vms.write().await;
            map.insert(
                "vm-test".to_string(),
                VmProcess {
                    api_socket: vm_dir.join("vm.sock"),
                    child: VmmChild::Owned(child),
                    console_io,
                    serial_transport: SerialTransport::Pty,
                    pty_tx: pty_tx.clone(),
                    pty_scrollback: pty_scrollback.clone(),
                    broadcaster_alive: Arc::new(AtomicBool::new(false)),
                    last_cpu_seconds: 0.0,
                    last_cpu_at: None,
                    boot_watermark: AtomicU64::new(0),
                },
            );
        }

        // Pre-stop assertions.
        assert_eq!(
            adapter.pty_scrollback("vm-test").await.unwrap(),
            b"scrollback data"
        );
        assert!(console_log.exists());

        // Force stop should clear scrollback and remove console.log.
        adapter
            .stop_vm("vm-test", true, Some("op-test"))
            .await
            .unwrap();

        // Post-stop assertions: the entry and its scrollback are gone,
        // and the console evidence is ROTATED one generation back, not
        // deleted (the M2.5 freeze investigation depended on it).
        assert!(adapter.pty_scrollback("vm-test").await.is_none());
        assert!(
            !console_log.exists(),
            "console.log should be rotated away on force stop"
        );
        assert_eq!(
            std::fs::read(vm_dir.join("console.log.last")).unwrap(),
            b"boot log line 1\nboot log line 2\n",
            "the previous generation's console evidence must survive the force stop"
        );
    }

    #[tokio::test]
    async fn stop_vm_graceful_clears_console_cache() {
        let dir = tempfile::tempdir_in(std::env::current_dir().unwrap()).unwrap();
        let vm_dir = dir.path().join("vm-test");
        std::fs::create_dir_all(&vm_dir).unwrap();

        // Create a dummy console.log with some content.
        let console_log = vm_dir.join("console.log");
        std::fs::write(&console_log, b"boot log line 1\nboot log line 2\n").unwrap();

        // For graceful stop we need a real CHV process or we skip the API part.
        // Since we can't spawn real CHV, we test the cache-clear path by
        // simulating what happens after the API shutdown succeeds: the VmProcess
        // stays in the map and we clear its scrollback and truncate the log.
        // We test this by manually exercising the internal logic via the adapter.
        let adapter = ProcessCloudHypervisorAdapter::new(dir.path().join("chv"));
        let (pty_tx, _) = tokio::sync::broadcast::channel::<Vec<u8>>(4096);
        let pty_scrollback = Arc::new(std::sync::RwLock::new(Vec::from(b"scrollback data")));
        let console_io = std::fs::File::open("/dev/null").unwrap().into();

        // Spawn a child that exits immediately so the graceful shutdown loop
        // breaks early (CH process disappeared).
        let mut child = tokio::process::Command::new("true").spawn().unwrap();
        let _ = child.wait().await;

        {
            let mut map = adapter.vms.write().await;
            map.insert(
                "vm-test".to_string(),
                VmProcess {
                    api_socket: vm_dir.join("vm.sock"),
                    child: VmmChild::Owned(child),
                    console_io,
                    serial_transport: SerialTransport::Pty,
                    pty_tx: pty_tx.clone(),
                    pty_scrollback: pty_scrollback.clone(),
                    broadcaster_alive: Arc::new(AtomicBool::new(false)),
                    last_cpu_seconds: 0.0,
                    last_cpu_at: None,
                    boot_watermark: AtomicU64::new(0),
                },
            );
        }

        // Pre-stop assertions.
        assert_eq!(
            adapter.pty_scrollback("vm-test").await.unwrap(),
            b"scrollback data"
        );
        assert!(console_log.exists());
        let pre_size = std::fs::metadata(&console_log).unwrap().len();
        assert!(pre_size > 0);

        // Graceful stop: the CH API calls will fail (no real socket), so the
        // loop breaks with "CH process disappeared" and then clears caches.
        adapter
            .stop_vm("vm-test", false, Some("op-test"))
            .await
            .unwrap();

        // Post-stop assertions: scrollback cleared, log truncated.
        assert_eq!(adapter.pty_scrollback("vm-test").await.unwrap(), b"");
        assert!(
            console_log.exists(),
            "console.log should still exist after graceful stop"
        );
        let post_size = std::fs::metadata(&console_log).unwrap().len();
        assert_eq!(
            post_size, 0,
            "console.log should be truncated on graceful stop"
        );
    }

    #[tokio::test]
    async fn stop_vm_graceful_reaps_exited_child() {
        // Regression test for the zombie left by the graceful stop path:
        // the child HAS exited when the stop loop ends (guest down, CH
        // exits with it), but nothing reaped it until the next
        // `vm.start` ran `prove_exited` — a VM stopped and never
        // restarted leaked a zombie for the agent's lifetime. The stop
        // must now reap the child and mark the surviving entry `Dead`.
        let dir = tempfile::tempdir_in(std::env::current_dir().unwrap()).unwrap();
        let vm_dir = dir.path().join("vm-test");
        std::fs::create_dir_all(&vm_dir).unwrap();
        std::fs::write(vm_dir.join("console.log"), b"boot log\n").unwrap();

        let adapter = ProcessCloudHypervisorAdapter::new(dir.path().join("chv"));
        let (pty_tx, _) = tokio::sync::broadcast::channel::<Vec<u8>>(4096);
        let pty_scrollback = Arc::new(std::sync::RwLock::new(Vec::new()));
        let console_io = std::fs::File::open("/dev/null").unwrap().into();

        // Spawn a child that exits immediately and DO NOT wait for it:
        // by the time stop_vm runs it is an unreaped zombie — exactly
        // the leaked state the fix addresses.
        let child = tokio::process::Command::new("true").spawn().unwrap();
        let zombie_pid = child.id().expect("child pid before exit");
        {
            let mut map = adapter.vms.write().await;
            map.insert(
                "vm-test".to_string(),
                VmProcess {
                    api_socket: vm_dir.join("vm.sock"),
                    child: VmmChild::Owned(child),
                    console_io,
                    serial_transport: SerialTransport::Pty,
                    pty_tx: pty_tx.clone(),
                    pty_scrollback: pty_scrollback.clone(),
                    broadcaster_alive: Arc::new(AtomicBool::new(false)),
                    last_cpu_seconds: 0.0,
                    last_cpu_at: None,
                    boot_watermark: AtomicU64::new(0),
                },
            );
        }

        // Graceful stop: no real CH socket, so the loop breaks via the
        // "CH process disappeared" branch and takes the post-loop
        // graceful path.
        adapter
            .stop_vm("vm-test", false, Some("op-test"))
            .await
            .unwrap();

        // The surviving entry's child is now `Dead` (the truthful state
        // for an exited VMM), not an unreaped `Owned` handle.
        {
            let vms = adapter.vms.read().await;
            let proc = vms.get("vm-test").expect("entry survives graceful stop");
            assert!(
                matches!(proc.child, VmmChild::Dead),
                "graceful stop must mark the exited child Dead"
            );
        }

        // And the zombie is actually reaped: /proc/<pid> disappears
        // once the detached reaper's wait() completes.
        let deadline = std::time::Instant::now() + std::time::Duration::from_secs(5);
        while std::path::Path::new(&format!("/proc/{zombie_pid}")).exists() {
            assert!(
                std::time::Instant::now() < deadline,
                "zombie pid {zombie_pid} was not reaped within 5s of the graceful stop"
            );
            tokio::time::sleep(std::time::Duration::from_millis(50)).await;
        }
    }

    #[tokio::test]
    async fn stop_vm_graceful_kills_live_child_after_dead_socket_loop() {
        // Regression test for the M4.3 run-5 wedge (issue #345): the
        // graceful loop's dead-socket branch treats an unreachable API
        // as "CH process disappeared" — but the process can still be
        // alive (wedged control loop: guest powered down, API dead,
        // SIGTERM ineffective). The stop must verify liveness after the
        // loop and SIGKILL the survivor instead of reporting success
        // over a live VMM that holds the VM's runtime dir and disk and
        // blocks the next start (re-spawn refused on Alive).
        let dir = tempfile::tempdir_in(std::env::current_dir().unwrap()).unwrap();
        let vm_dir = dir.path().join("vm-wedge");
        std::fs::create_dir_all(&vm_dir).unwrap();
        std::fs::write(vm_dir.join("console.log"), b"boot log\n").unwrap();

        let adapter = ProcessCloudHypervisorAdapter::new(dir.path().join("chv"));
        let (pty_tx, _) = tokio::sync::broadcast::channel::<Vec<u8>>(4096);
        let pty_scrollback = Arc::new(std::sync::RwLock::new(Vec::new()));
        let console_io = std::fs::File::open("/dev/null").unwrap().into();

        // A child that will NOT exit on its own: the loop below ends on
        // the dead-socket premise while this process is still alive —
        // exactly the wedged state.
        let child = tokio::process::Command::new("sleep")
            .arg("300")
            .spawn()
            .unwrap();
        let wedged_pid = child.id().expect("child pid");
        {
            let mut map = adapter.vms.write().await;
            map.insert(
                "vm-wedge".to_string(),
                VmProcess {
                    api_socket: vm_dir.join("vm.sock"),
                    child: VmmChild::Owned(child),
                    console_io,
                    serial_transport: SerialTransport::Pty,
                    pty_tx: pty_tx.clone(),
                    pty_scrollback: pty_scrollback.clone(),
                    broadcaster_alive: Arc::new(AtomicBool::new(false)),
                    last_cpu_seconds: 0.0,
                    last_cpu_at: None,
                    boot_watermark: AtomicU64::new(0),
                },
            );
        }

        // Graceful stop: no real CH socket, so the loop breaks via the
        // dead-socket branch — over a process that is still alive.
        adapter
            .stop_vm("vm-wedge", false, Some("op-test"))
            .await
            .unwrap();

        // The wedge path kills and waits SYNCHRONOUSLY inside the stop,
        // so by the time it reports success the survivor must be gone
        // from /proc (killed AND reaped).
        assert!(
            !std::path::Path::new(&format!("/proc/{wedged_pid}")).exists(),
            "a live VMM must not outlive a successful graceful stop"
        );

        // The surviving entry's child is the truthful `Dead`.
        {
            let vms = adapter.vms.read().await;
            let proc = vms.get("vm-wedge").expect("entry survives graceful stop");
            assert!(
                matches!(proc.child, VmmChild::Dead),
                "graceful stop must mark the killed child Dead"
            );
        }
    }

    #[tokio::test]
    async fn stop_vm_graceful_fails_loudly_when_kill_is_refused() {
        // Companion to stop_vm_graceful_kills_live_child_after_dead_socket_loop:
        // when the post-loop SIGKILL is REFUSED — an adopted pid whose
        // identity cannot be re-proven (here: the stand-in's executable
        // is not the adapter's VMM binary, as happens when the binary
        // is replaced on disk while the VMM runs) — the stop must NOT
        // report success over the live process, and the surviving entry
        // must keep the truthful Adopted handle so a later start
        // re-validates instead of forking a second VMM onto the disk
        // the live process still holds.
        let dir = tempfile::tempdir_in(std::env::current_dir().unwrap()).unwrap();
        let vm_dir = dir.path().join("vm-refused");
        std::fs::create_dir_all(&vm_dir).unwrap();
        std::fs::write(vm_dir.join("console.log"), b"boot log\n").unwrap();

        let adapter = ProcessCloudHypervisorAdapter::new(dir.path().join("chv"));
        let (pty_tx, _) = tokio::sync::broadcast::channel::<Vec<u8>>(4096);
        let pty_scrollback = Arc::new(std::sync::RwLock::new(Vec::new()));
        let console_io = std::fs::File::open("/dev/null").unwrap().into();

        // `sh -c "sleep 30; true"` never execs (compound command), so
        // the process keeps its argv — including the api-socket flag
        // and path — for its lifetime: a perfect argv match for an
        // adopted VMM. Its executable is `sh`, not the adapter's `chv`,
        // so the exe cross-check refuses the SIGKILL authorization.
        let mut stand_in = tokio::process::Command::new("sh")
            .arg("-c")
            .arg("sleep 30; true")
            .arg("--api-socket")
            .arg(vm_dir.join("vm.sock"))
            .spawn()
            .unwrap();
        let stand_in_pid = stand_in.id().expect("stand-in pid");
        wait_for_cmdline_containing(stand_in_pid, &vm_dir.join("vm.sock").to_string_lossy()).await;
        assert!(
            super::pid_is_cloud_hypervisor(stand_in_pid, &vm_dir.join("vm.sock"), None),
            "stand-in must match the loose (argv-only) identity check"
        );
        assert!(
            !super::pid_is_cloud_hypervisor(
                stand_in_pid,
                &vm_dir.join("vm.sock"),
                Some(std::ffi::OsStr::new("chv"))
            ),
            "stand-in must fail the exe-strict identity check"
        );

        {
            let mut map = adapter.vms.write().await;
            map.insert(
                "vm-refused".to_string(),
                VmProcess {
                    api_socket: vm_dir.join("vm.sock"),
                    child: VmmChild::Adopted(stand_in_pid),
                    console_io,
                    serial_transport: SerialTransport::Pty,
                    pty_tx: pty_tx.clone(),
                    pty_scrollback: pty_scrollback.clone(),
                    broadcaster_alive: Arc::new(AtomicBool::new(false)),
                    last_cpu_seconds: 0.0,
                    last_cpu_at: None,
                    boot_watermark: AtomicU64::new(0),
                },
            );
        }

        // Graceful stop over a dead socket ends the loop while the
        // process lives; the remediation SIGKILL is refused (exe
        // mismatch) → the stop must fail loudly, not report success.
        let err = adapter
            .stop_vm("vm-refused", false, Some("op-test"))
            .await
            .unwrap_err();
        assert!(
            matches!(err, ChvError::Internal { .. }),
            "refused kill must fail the stop, got: {err:?}"
        );

        // The stand-in survived the refused kill.
        assert!(
            super::pid_exists(stand_in_pid),
            "the refused kill must not have signalled the stand-in"
        );

        // The entry keeps the truthful Adopted handle (not Dead): a
        // later start must re-validate liveness and refuse to re-spawn.
        {
            let vms = adapter.vms.read().await;
            let proc = vms.get("vm-refused").expect("entry survives failed stop");
            assert!(
                matches!(proc.child, VmmChild::Adopted(pid) if pid == stand_in_pid),
                "a live VMM must keep its Adopted handle after a failed stop"
            );
        }

        let _ = stand_in.start_kill();
        let _ = stand_in.wait().await;
    }

    /// #351: delete_vm must not report success over a live VMM when the
    /// force kill is REFUSED — the delete counterpart of
    /// `stop_vm_graceful_fails_loudly_when_kill_is_refused`. An adopted
    /// stand-in with matching argv but a non-VMM executable (as when the
    /// binary is replaced on disk while the VMM runs) refuses the
    /// SIGKILL authorization: the delete must fail loudly, leave the
    /// runtime artifacts in place (the live VMM still holds them), and
    /// restore the entry so the VM's state stays truthful.
    #[tokio::test]
    async fn delete_vm_fails_loudly_when_kill_is_refused() {
        let dir = tempfile::tempdir_in(std::env::current_dir().unwrap()).unwrap();
        let vm_dir = dir.path().join("vm-del-refused");
        std::fs::create_dir_all(&vm_dir).unwrap();
        let api_socket = vm_dir.join("vm.sock");
        std::fs::write(&api_socket, b"").unwrap();
        std::fs::write(vm_dir.join("ch.pid"), "12345").unwrap();
        std::fs::write(vm_dir.join("vm-config.json"), "{}").unwrap();

        let adapter = ProcessCloudHypervisorAdapter::new(dir.path().join("chv"));
        let (pty_tx, _) = tokio::sync::broadcast::channel::<Vec<u8>>(4096);
        let pty_scrollback = Arc::new(std::sync::RwLock::new(Vec::new()));
        let console_io = std::fs::File::open("/dev/null").unwrap().into();

        // `sh -c "sleep 30; true"` keeps its argv (including the
        // api-socket flag and path) for its lifetime — a perfect argv
        // match for an adopted VMM — while its executable (`sh`) fails
        // the exe cross-check, so the SIGKILL authorization is refused.
        let mut stand_in = tokio::process::Command::new("sh")
            .arg("-c")
            .arg("sleep 30; true")
            .arg("--api-socket")
            .arg(&api_socket)
            .spawn()
            .unwrap();
        let stand_in_pid = stand_in.id().expect("stand-in pid");
        wait_for_cmdline_containing(stand_in_pid, &api_socket.to_string_lossy()).await;
        assert!(
            super::pid_is_cloud_hypervisor(stand_in_pid, &api_socket, None),
            "stand-in must match the loose (argv-only) identity check"
        );
        assert!(
            !super::pid_is_cloud_hypervisor(
                stand_in_pid,
                &api_socket,
                Some(std::ffi::OsStr::new("chv"))
            ),
            "stand-in must fail the exe-strict identity check"
        );

        {
            let mut map = adapter.vms.write().await;
            map.insert(
                "vm-del-refused".to_string(),
                VmProcess {
                    api_socket: api_socket.clone(),
                    child: VmmChild::Adopted(stand_in_pid),
                    console_io,
                    serial_transport: SerialTransport::Pty,
                    pty_tx: pty_tx.clone(),
                    pty_scrollback: pty_scrollback.clone(),
                    broadcaster_alive: Arc::new(AtomicBool::new(false)),
                    last_cpu_seconds: 0.0,
                    last_cpu_at: None,
                    boot_watermark: AtomicU64::new(0),
                },
            );
        }

        // The delete must fail, not report success over the live VMM.
        let err = adapter
            .delete_vm("vm-del-refused", Some("op-test"))
            .await
            .unwrap_err();
        assert!(
            matches!(err, ChvError::Internal { .. }),
            "refused kill must fail the delete, got: {err:?}"
        );

        // The stand-in survived the refused kill.
        assert!(
            super::pid_exists(stand_in_pid),
            "the refused kill must not have signalled the stand-in"
        );

        // The runtime artifacts stay: the live VMM still holds the
        // runtime dir, and the delete's cleanup must not unlink
        // evidence out from under it.
        assert!(
            api_socket.exists(),
            "api socket must survive a failed delete"
        );
        assert!(
            vm_dir.join("ch.pid").exists(),
            "pidfile must survive a failed delete"
        );
        assert!(
            vm_dir.join("vm-config.json").exists(),
            "persisted config must survive a failed delete"
        );

        // The entry is restored with the truthful Adopted handle: a
        // retry re-validates liveness instead of the delete having
        // silently orphaned a live VMM.
        {
            let vms = adapter.vms.read().await;
            let proc = vms
                .get("vm-del-refused")
                .expect("entry survives failed delete");
            assert!(
                matches!(proc.child, VmmChild::Adopted(pid) if pid == stand_in_pid),
                "a live VMM must keep its Adopted handle after a failed delete"
            );
        }

        let _ = stand_in.start_kill();
        let _ = stand_in.wait().await;
    }

    /// #351's idempotency invariant: a REFUSED kill on a DEAD adopted
    /// VMM must still delete successfully. The kill refuses because the
    /// pid no longer proves identity (it left /proc), but the death
    /// confirmation sees it gone — only a refused or ineffective kill
    /// on a LIVE VMM may fail the delete.
    #[tokio::test]
    async fn delete_vm_succeeds_when_adopted_vmm_already_exited() {
        let dir = tempfile::tempdir_in(std::env::current_dir().unwrap()).unwrap();
        let vm_dir = dir.path().join("vm-del-dead");
        std::fs::create_dir_all(&vm_dir).unwrap();
        let api_socket = vm_dir.join("vm.sock");
        std::fs::write(&api_socket, b"").unwrap();
        std::fs::write(vm_dir.join("ch.pid"), "12345").unwrap();
        std::fs::write(vm_dir.join("vm-config.json"), "{}").unwrap();

        let adapter = ProcessCloudHypervisorAdapter::new(dir.path().join("chv"));
        let (pty_tx, _) = tokio::sync::broadcast::channel::<Vec<u8>>(4096);
        let pty_scrollback = Arc::new(std::sync::RwLock::new(Vec::new()));
        let console_io = std::fs::File::open("/dev/null").unwrap().into();

        // A process that already exited: cloud-hypervisor v43 exits
        // with the guest, so a stopped VM's adopted pid is normally in
        // exactly this state when the delete arrives.
        let mut dead = tokio::process::Command::new("true").spawn().unwrap();
        let dead_pid = dead.id().expect("dead stand-in pid");
        let _ = dead.wait().await;
        assert!(
            !super::pid_exists(dead_pid),
            "precondition: the stand-in must have left /proc"
        );

        {
            let mut map = adapter.vms.write().await;
            map.insert(
                "vm-del-dead".to_string(),
                VmProcess {
                    api_socket: api_socket.clone(),
                    child: VmmChild::Adopted(dead_pid),
                    console_io,
                    serial_transport: SerialTransport::Pty,
                    pty_tx,
                    pty_scrollback,
                    broadcaster_alive: Arc::new(AtomicBool::new(false)),
                    last_cpu_seconds: 0.0,
                    last_cpu_at: None,
                    boot_watermark: AtomicU64::new(0),
                },
            );
        }

        adapter.delete_vm("vm-del-dead", None).await.unwrap();
        assert!(!api_socket.exists(), "api socket must be removed");
        assert!(!vm_dir.join("ch.pid").exists(), "pidfile must be removed");
        assert!(
            !vm_dir.join("vm-config.json").exists(),
            "persisted config must be removed"
        );
        assert!(!adapter.vms.read().await.contains_key("vm-del-dead"));
    }

    /// #351's idempotency invariant, `Dead`-handle arm: a VM whose
    /// graceful stop already marked the entry `Dead` (the truthful
    /// post-stop state) must delete successfully — there is nothing to
    /// signal, and the death confirmation sees the handle as gone.
    #[tokio::test]
    async fn delete_vm_succeeds_for_dead_handle() {
        let dir = tempfile::tempdir_in(std::env::current_dir().unwrap()).unwrap();
        let vm_dir = dir.path().join("vm-del-dead-handle");
        std::fs::create_dir_all(&vm_dir).unwrap();
        let api_socket = vm_dir.join("vm.sock");
        std::fs::write(&api_socket, b"").unwrap();
        std::fs::write(vm_dir.join("ch.pid"), "12345").unwrap();
        std::fs::write(vm_dir.join("vm-config.json"), "{}").unwrap();

        let adapter = ProcessCloudHypervisorAdapter::new(dir.path().join("chv"));
        let (pty_tx, _) = tokio::sync::broadcast::channel::<Vec<u8>>(4096);
        let pty_scrollback = Arc::new(std::sync::RwLock::new(Vec::new()));
        let console_io = std::fs::File::open("/dev/null").unwrap().into();

        {
            let mut map = adapter.vms.write().await;
            map.insert(
                "vm-del-dead-handle".to_string(),
                VmProcess {
                    api_socket: api_socket.clone(),
                    child: VmmChild::Dead,
                    console_io,
                    serial_transport: SerialTransport::Pty,
                    pty_tx,
                    pty_scrollback,
                    broadcaster_alive: Arc::new(AtomicBool::new(false)),
                    last_cpu_seconds: 0.0,
                    last_cpu_at: None,
                    boot_watermark: AtomicU64::new(0),
                },
            );
        }

        adapter.delete_vm("vm-del-dead-handle", None).await.unwrap();
        assert!(!api_socket.exists(), "api socket must be removed");
        assert!(!vm_dir.join("ch.pid").exists(), "pidfile must be removed");
        assert!(
            !vm_dir.join("vm-config.json").exists(),
            "persisted config must be removed"
        );
        assert!(
            !adapter.vms.read().await.contains_key("vm-del-dead-handle"),
            "entry must be removed by the successful delete"
        );
    }

    /// #351: stop_vm's force branch must not report success over a live
    /// VMM when the kill is REFUSED — the force-stop counterpart of
    /// `stop_vm_graceful_fails_loudly_when_kill_is_refused` (which pins
    /// the graceful-completion remediation). Same stand-in: argv
    /// matches, executable does not.
    #[tokio::test]
    async fn stop_vm_force_fails_loudly_when_kill_is_refused() {
        let dir = tempfile::tempdir_in(std::env::current_dir().unwrap()).unwrap();
        let vm_dir = dir.path().join("vm-force-refused");
        std::fs::create_dir_all(&vm_dir).unwrap();
        std::fs::write(vm_dir.join("console.log"), b"boot log\n").unwrap();
        let api_socket = vm_dir.join("vm.sock");

        let adapter = ProcessCloudHypervisorAdapter::new(dir.path().join("chv"));
        let (pty_tx, _) = tokio::sync::broadcast::channel::<Vec<u8>>(4096);
        let pty_scrollback = Arc::new(std::sync::RwLock::new(Vec::new()));
        let console_io = std::fs::File::open("/dev/null").unwrap().into();

        let mut stand_in = tokio::process::Command::new("sh")
            .arg("-c")
            .arg("sleep 30; true")
            .arg("--api-socket")
            .arg(&api_socket)
            .spawn()
            .unwrap();
        let stand_in_pid = stand_in.id().expect("stand-in pid");
        wait_for_cmdline_containing(stand_in_pid, &api_socket.to_string_lossy()).await;
        assert!(
            super::pid_is_cloud_hypervisor(stand_in_pid, &api_socket, None),
            "stand-in must match the loose (argv-only) identity check"
        );
        assert!(
            !super::pid_is_cloud_hypervisor(
                stand_in_pid,
                &api_socket,
                Some(std::ffi::OsStr::new("chv"))
            ),
            "stand-in must fail the exe-strict identity check"
        );

        {
            let mut map = adapter.vms.write().await;
            map.insert(
                "vm-force-refused".to_string(),
                VmProcess {
                    api_socket: api_socket.clone(),
                    child: VmmChild::Adopted(stand_in_pid),
                    console_io,
                    serial_transport: SerialTransport::Pty,
                    pty_tx: pty_tx.clone(),
                    pty_scrollback: pty_scrollback.clone(),
                    broadcaster_alive: Arc::new(AtomicBool::new(false)),
                    last_cpu_seconds: 0.0,
                    last_cpu_at: None,
                    boot_watermark: AtomicU64::new(0),
                },
            );
        }

        // Force stop over a refused kill: must fail, not report success
        // over the live process.
        let err = adapter
            .stop_vm("vm-force-refused", true, Some("op-test"))
            .await
            .unwrap_err();
        assert!(
            matches!(err, ChvError::Internal { .. }),
            "refused kill must fail the force stop, got: {err:?}"
        );

        // The stand-in survived the refused kill.
        assert!(
            super::pid_exists(stand_in_pid),
            "the refused kill must not have signalled the stand-in"
        );

        // The entry is restored with the truthful Adopted handle: a
        // retry stop or a later start re-validates liveness instead of
        // assuming the VMM is gone.
        {
            let vms = adapter.vms.read().await;
            let proc = vms
                .get("vm-force-refused")
                .expect("entry survives failed force stop");
            assert!(
                matches!(proc.child, VmmChild::Adopted(pid) if pid == stand_in_pid),
                "a live VMM must keep its Adopted handle after a failed force stop"
            );
        }

        // The console evidence is not rotated out from under the live
        // VMM (rotation only runs on the force path's success leg).
        assert!(
            vm_dir.join("console.log").exists(),
            "console.log must survive a failed force stop"
        );
        assert!(
            !vm_dir.join("console.log.last").exists(),
            "console.log must not be rotated by a failed force stop"
        );

        let _ = stand_in.start_kill();
        let _ = stand_in.wait().await;
    }

    #[test]
    fn adopted_vm_handle_revalidates_successfully() {
        use super::AdoptedVmHandle;
        use std::fs;

        let temp = tempfile::tempdir_in(std::env::current_dir().unwrap()).unwrap();
        let proc_path = temp.path().join("proc");
        fs::create_dir(&proc_path).unwrap();

        let pid = 1234;
        let pid_path = proc_path.join(pid.to_string());
        fs::create_dir(&pid_path).unwrap();

        fs::write(pid_path.join("stat"), b"1234 (bash) S 1 1 1 0 -1 4210944 1 0 0 0 0 0 0 0 20 0 1 0 12345 0 0 18446744073709551615 0 0 0 0 0 0 0 2147483647 0 0 0 0 17 0 0 0 0 0 0 0 0 0 0 0 0 0 0").unwrap();

        fs::write(
            pid_path.join("status"),
            b"Uid:\t1000\t1000\t1000\t1000\nGid:\t1000\t1000\t1000\t1000\n",
        )
        .unwrap();
        fs::write(pid_path.join("cgroup"), b"0::/test\n").unwrap();

        let sys_kernel_random = proc_path.join("sys").join("kernel").join("random");
        fs::create_dir_all(&sys_kernel_random).unwrap();
        fs::write(
            sys_kernel_random.join("boot_id"),
            b"00000000-0000-4000-8000-000000000001\n",
        )
        .unwrap();

        let fake_exe = temp.path().join("fake_exe");
        fs::write(&fake_exe, b"").unwrap();
        std::os::unix::fs::symlink(&fake_exe, pid_path.join("exe")).unwrap();

        use std::os::unix::fs::MetadataExt;
        let exe_meta = fs::metadata(&fake_exe).unwrap();
        let identity = cellhv_core_runtime_ownership::ProcessIdentity {
            pid,
            start_ticks: 12345,
            boot_id: "00000000-0000-4000-8000-000000000001".to_string(),
            executable: cellhv_core_runtime_ownership::FileIdentity {
                device: exe_meta.dev(),
                inode: exe_meta.ino(),
            },
            uid: 1000,
            gid: 1000,
            cgroup_fingerprint: "/test".to_string(),
        };

        let handle = AdoptedVmHandle::new(
            "vm-test".to_string(),
            temp.path().join("vm.sock"),
            identity.clone(),
        )
        .with_proc_path(proc_path.clone())
        .with_runtime_root(temp.path().to_path_buf());

        let r = handle.revalidate();
        assert!(r.is_ok());

        fs::write(pid_path.join("stat"), b"1234 (bash) S 1 1 1 0 -1 4210944 1 0 0 0 0 0 0 0 20 0 1 0 99999 0 0 18446744073709551615 0 0 0 0 0 0 0 2147483647 0 0 0 0 17 0 0 0 0 0 0 0 0 0 0 0 0 0 0").unwrap();
        assert!(handle.revalidate().is_err());
    }

    #[test]
    fn start_vm_action_paused_is_already_running() {
        assert!(matches!(
            super::start_vm_action("Paused"),
            super::StartVmAction::AlreadyRunning
        ));
    }

    #[test]
    fn start_vm_action_running_is_already_running() {
        assert!(matches!(
            super::start_vm_action("Running"),
            super::StartVmAction::AlreadyRunning
        ));
    }

    #[test]
    fn start_vm_action_other_states_map_to_boot() {
        for state in ["", "Created", "Booted", "Failed", "garbage"] {
            assert!(
                matches!(super::start_vm_action(state), super::StartVmAction::Boot),
                "state {state:?} should map to Boot"
            );
        }
    }

    /// Linux process state from /proc/<pid>/stat ('S' = sleeping, 'Z' = zombie
    /// i.e. terminated-but-not-yet-reaped, None = fully gone).
    fn proc_state(pid: u32) -> Option<char> {
        let stat = std::fs::read_to_string(format!("/proc/{pid}/stat")).ok()?;
        // Format: `pid (comm) state ...`. comm can contain spaces/parens, so
        // the state is the token immediately after the last ')'.
        let close = stat.rfind(')')?;
        stat.as_bytes().get(close + 2).copied().map(char::from)
    }

    /// Empty spawn helper mirroring the CH spawn shape (null stdio, long sleep).
    fn spawn_sleep_child() -> (tokio::process::Child, u32) {
        let child = tokio::process::Command::new("sleep")
            .arg("300")
            .stdout(std::process::Stdio::null())
            .stderr(std::process::Stdio::null())
            .spawn()
            .unwrap();
        let pid = child.id().unwrap();
        (child, pid)
    }

    /// Proves the orphan-window guard in the CH spawn path: while a CH child
    /// is spawned but not yet registered in the vm process map, dropping an
    /// *armed* `ChildGuard` must terminate the VMM — otherwise an aborted
    /// create (e.g. a bounded-drain cancellation) leaves an unaccounted live
    /// process.
    #[tokio::test]
    async fn child_guard_armed_drop_terminates_child() {
        let (child, pid) = spawn_sleep_child();
        assert!(
            proc_state(pid).is_some(),
            "child should be alive before drop"
        );
        drop(super::ChildGuard::new(child));
        let deadline = tokio::time::Instant::now() + std::time::Duration::from_secs(5);
        loop {
            if matches!(proc_state(pid), None | Some('Z')) {
                break;
            }
            assert!(
                tokio::time::Instant::now() < deadline,
                "child was not terminated by armed ChildGuard drop"
            );
            tokio::time::sleep(std::time::Duration::from_millis(20)).await;
        }
    }

    /// Proves the counterpart: after registration the vm process map owns the
    /// child, so `disarm()` must return a live child whose ordinary drop does
    /// NOT kill the VMM (lifecycle is explicit via start_kill on stop/delete).
    #[tokio::test]
    async fn child_guard_disarm_keeps_child_alive() {
        let (child, pid) = spawn_sleep_child();
        let mut child = super::ChildGuard::new(child).disarm();
        assert!(
            !matches!(proc_state(pid), None | Some('Z')),
            "child must remain running after disarm"
        );
        // Clean up and reap this test's child so it does not linger on the host.
        child.start_kill().unwrap();
        child.wait().await.unwrap();
    }
}
