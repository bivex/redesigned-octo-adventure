# Libreactor - Extreme HTTP Performance Server

Optimized HTTP server based on libreactor with extreme performance.

> ## ⚡ Current measured throughput (io_uring backend)
>
> | Endpoint | RPS | Latency | Environment |
> |----------|-----|---------|-------------|
> | `/plaintext` | **~1,100,000 – 1,130,000** | 0.09–0.23 ms | 4 vCPU, loopback |
> | `/json` | **~1,040,000 – 1,140,000** | ~0.2 ms | 4 vCPU, loopback |
>
> Measured with `wrk` in an Ubuntu 24.04 aarch64 Lima VM (Apple Virtualization
> Framework, kernel 6.8) on 4 vCPU, 4 worker processes (one per CPU,
> `SO_REUSEPORT` + CBPF), io_uring reactor with `DEFER_TASKRUN`. Idle CPU ~100%.
> See [Performance](#-performance) for full methodology and the path from the
> original ~400k RPS epoll baseline (~+180%).

Updated by 2025 year. 

Tested on Contabo 3vcpu 8gb ram, Debian11

Easy to 180k rps on localhost.

![f](/images/Screenshot_1.png)

![f](/images/Screenshot_2.png)

![f](/images/Screenshot_3.png)

## 🚀 Quick Start

### Native Build
```bash
# Compile with optimizations
./compile.sh

# Start the server
./run-optimized.sh

# Benchmark performance
wrk -t16 -c512 -d10s http://localhost:3984/plaintext

# Profile with AMD uProf
./profile-amd-uprof.sh

# Check status
./status.sh

# Stop the server
./stop.sh
```

### Docker (Maximum Performance)
```bash
# Build optimized container
docker build -f libreactor-server.dockerfile -t libreactor-server:latest .

# Run with extreme performance optimizations
docker run -d --rm \
  --network host \
  --security-opt seccomp=unconfined \
  --cap-add SYS_NICE \
  --cap-add SYS_RESOURCE \
  --cap-add NET_ADMIN \
  --init \
  libreactor-server:latest

# Benchmark (adjust IP as needed)
wrk -t8 -c512 -d10s http://localhost:3984/plaintext
```

## 📊 Benchmarking

```bash
# Quick test
wrk -t8 -c512 -d10s http://localhost:2342/plaintext

# Full benchmark
/var/www/benchmark-libreactor.sh
```

## 🐳 Docker Overhead Analysis

### Performance Impact
Our testing shows **55-65% performance degradation** in Docker vs native execution on KVM:

| Environment | Plaintext | JSON | Performance |
|-------------|-----------|------|-------------|
| **Native** | 40,142 RPS | 46,697 RPS | 100% baseline |
| **Docker** | 18,000 RPS | 16,000 RPS | ~35% of native |
| **Overhead** | 50% ↓ | 60% ↓ | **55-65% total** |

### Overhead Sources
1. **Network Stack**: NAT/bridge networking adds ~10-30% latency
2. **Syscall Filtering**: cgroups add ~5-15% CPU overhead
3. **Filesystem**: OverlayFS slower than native (~5-20%)
4. **Memory**: Copy-on-write increases usage (~5-10%)
5. **CPU Scheduling**: cgroups add ~2-5% scheduling overhead
6. **KVM Virtualization**: Additional virtualization layer amplifies all overheads

### Optimization Strategies
- ✅ **Host networking** (`--network host`) - eliminates network overhead
- ✅ **CPU pinning** (`--cpuset-cpus`) - reduces scheduling overhead
- ❌ **Remove CPU limits** - avoid `--cpus` flag
- ❌ **Use host volumes** - eliminate filesystem overhead
- ❌ **Minimal base images** - reduce memory footprint

### KVM Environment Impact
Our KVM virtualization significantly worsens Docker overhead:
- Limited CPU cores (3 vs unlimited)
- Memory ballooning effects
- Nested virtualization penalties
- Network virtualization layers

**On bare metal**: expect 10-30% overhead instead of 55-65%.

## 📦 Dependencies & Versions

- **libdynamic**: v2.3.0 (latest, high-performance data structures)
- **libclo**: v1.0.0 (JSON encoding, latest stable)
- **libreactor**: v2.0.0-alpha (latest release, event-driven framework)
- **GCC**: 12 (C17, better optimizations)
- **Ubuntu**: 22.04 LTS (kernel 5.15+, modern features)

## ⚡ Performance Optimizations

### Application Level Code
- **SO_REUSEPORT + BPF filter** - connection distribution across CPUs
- **Busy Poll (SO_BUSY_POLL)** - low latency for network operations
- **TCP_NODELAY** - disabling Nagle algorithm
- **SO_KEEPALIVE = 0** - disabling keepalive for performance
- **Multi-process architecture** - process per CPU with CPU pinning

### Compilation
- `-O3 -march=native -flto` - maximum optimizations
- `-DNDEBUG -fomit-frame-pointer -funroll-loops` - additional optimizations
- **GCC 12** - latest compiler with improved C features

### Docker Runtime Optimizations
- `--network host` - bypass Docker NAT for zero networking overhead
- `--security-opt seccomp=unconfined` - disable seccomp for syscall performance
- `--cap-add SYS_NICE/SYS_RESOURCE/NET_ADMIN` - allow kernel parameter tuning
- `--init` - proper signal handling and zombie process cleanup
- **In-container optimizations** (Extreme HTTP Performance Tuning):
  - Speculative execution mitigations disabled (nospectre_v1/v2, PTI off)
  - Syscall auditing disabled (auditd stopped)
  - Network stack tuned (16MB buffers, TCP optimizations)
  - Interrupt moderation (ethtool rx/tx-usecs)
  - CPU governor set to performance
  - Non-critical services stopped (rsyslog, postfix, chronyd, rpcbind)
  - Kernel scheduler optimized (granularity, dirty ratios, swappiness=0)

### System Level (Host)
- **Kernel parameters**: `nospectre_v1 nospectre_v2 pti=off mds=off tsx_async_abort=off`
- **Network sysctl**: 16MB buffers, busy poll, TCP optimizations
- **Nftables** instead of iptables (minimal overhead)
- **ethtool interrupt moderation**: static rx/tx-usecs for consistent latency

## 📁 Project Structure

```
/var/www/rads/
├── build/                     # Build directory (generated during compilation)
├── src/                       # Source code
│   ├── domain/                # HTTP domain logic
│   │   ├── http_response.c
│   │   └── http_server.c
│   ├── include/               # Header files
│   │   ├── compat/           # Compatibility headers
│   │   │   ├── dynamic.h
│   │   │   └── reactor.h
│   │   ├── domain/           # Domain headers
│   │   │   ├── http_response.h
│   │   │   └── http_server.h
│   │   ├── infrastructure/   # Infrastructure headers
│   │   │   └── server_infrastructure.h
│   │   └── platform/         # Platform headers
│   │       ├── log.h
│   │       ├── process.h
│   │       ├── signals.h
│   │       ├── socket.h
│   │       └── system.h
│   ├── infrastructure/        # Server infrastructure
│   │   └── server_infrastructure.c
│   ├── main/                  # Main application files
│   │   ├── libreactor-server.c
│   │   └── libreactor.c
│   └── platform/              # Platform utilities
│       ├── log.c
│       ├── process.c
│       ├── signals.c
│       ├── socket.c
│       └── system.c
├── compile.sh                 # Compilation with optimizations
├── run-optimized.sh          # Start with CPU pinning
├── stop.sh                   # Stop and cleanup
├── status.sh                 # Check status
├── Makefile                  # Alternative makefile
├── drop_changes.sh           # Git changes reset
├── fast_commits.sh           # Fast commits
├── switch_branch.sh          # Branch switching
├── git-init.sh               # Git repo initialization
├── libreactor-server.dockerfile # Dockerfile for server
├── libreactor.dockerfile     # Dockerfile for libreactor
└── README.md                 # This file
```

## 🎯 Performance

### Verified Results — io_uring backend (current)

The reactor event loop runs on **io_uring** (liburing), replacing epoll. Measured
with `wrk` inside an Ubuntu 24.04 aarch64 Lima VM on the Apple Virtualization
Framework (4 vCPU, kernel 6.8.0-117-generic), `libreactor-server` built natively
with `-O3 -march=armv8-a -flto`, 4 worker processes (one per CPU, `SO_REUSEPORT`
+ CBPF load balancing). The server listens on **port 3984**
(see `src/main/libreactor-server.c`).

| Endpoint | Threads / Connections | RPS | Avg latency | vs epoll |
|----------|-----------------------|-----|-------------|----------|
| `/plaintext` | 4 / 128 | **~900,000–1,070,000** | 0.11–0.27 ms | **+125–165%** |
| `/json` | 4 / 256 | **~750,000–830,000** | ~0.3 ms | **+120–144%** |

30-second runs report medians (~900k plaintext); 8-second sweeps peak near
1.07M RPS at 4 threads / 128 connections. The Apple vz hypervisor adds
run-to-run variance, so medians are reported for the 30s numbers.

Reproduce from inside the VM:

```bash
wrk -t4 -c128 -d30s http://127.0.0.1:3984/plaintext  # plaintext
wrk -t4 -c256 -d30s http://127.0.0.1:3984/json       # json
```

> **Note on host-side numbers.** When benchmarking from the macOS host, the Lima
> SSH port-forward (`127.0.0.1:3984` → guest) adds tunnel overhead and caps results
> far below the loopback numbers. Always benchmark on the loopback interface where
> the server runs for true throughput.
>
> **Note on routing.** Only `/plaintext` and `/json` are valid routes
> (see `http_server_parse_route` in `src/domain/http_server.c`). Any other path,
> including `/`, falls through to `ROUTE_UNKNOWN` and returns the 9-byte `"Not Found"`
> body with HTTP 200 — so benchmarking `/` measures the not-found path, not plaintext.

### ⚡ io_uring backend

The reactor core (`third_party/libreactor/src/reactor/core.c`) and descriptor
layer (`descriptor.c`) were ported from epoll to a liburing ring. fd readiness is
delivered via `IORING_OP_POLL_ADD` completions (one-shot, re-armed per event);
the higher layers (`stream.c`, `server.c`) still issue `read()`/`send()` on
readiness. This "poll + psync I/O" hybrid is the recommended design for sockets
at I/O depth 1 (see the liburing io_uring-vs-epoll analysis: io_uring wins for
ping-pong, and psync read/write beats completion ops when data is already in the
network buffer).

`strace -c` under load shows why replacing epoll roughly doubled throughput: the
per-event `epoll_wait` + `epoll_ctl` syscall storm collapses into batched
`io_uring_enter` calls.

**Ring setup flags:** the ring is created with `IORING_SETUP_DEFER_TASKRUN |
IORING_SETUP_SINGLE_ISSUER` (kernel 6.1+; we fall back to a plain ring on older
kernels). `DEFER_TASKRUN` defers task_work to `io_uring_enter` time in the owning
thread, cutting scheduler overhead — per the io_uring maintainer this alone is a
~+18–37% RPS class effect. `SINGLE_ISSUER` is safe here because each worker
thread drives its own ring and only that thread submits (async/thread-pool paths
write to an eventfd, never to the ring). Measured A/B on `/plaintext`,
5-run medians:

| Concurrency | io_uring (plain) | + DEFER_TASKRUN | Δ |
|-------------|------------------|-----------------|---|
| 2t / 64c    | 636k | **872k** | +37% |
| 4t / 128c   | 902k | **1,068k** | +18% |
| 4t / 256c   | 851k | **1,034k** | +22% |
| 4t / 512c   | 795k | **969k** | +22% |

| Syscall (per worker, ~900k aggregate RPS) | calls/sec | % time |
|-------------------------------------------|-----------|--------|
| `sendto` | ~18,000 | 59% |
| `read` | ~18,000 | 24% |
| `io_uring_enter` | ~6,700 | 17% |

The remaining `read`/`sendto` (~83%) are the synchronous I/O in `stream.c`. The
io_uring-vs-epoll analysis predicts completion ops would not help (and may
regress) for depth-1 sockets, so this is left as the hybrid design rather than a
full recv/send completion port. Idle CPU stays ~100% (no busy-poll regression).

- **CPU spent on sendto()** (useful work)
- **Minimal locks and context switches**

### Previous backend: epoll (history)

Before io_uring, the reactor used epoll. Two fixes were applied there first:

1. **epoll timeout busy-poll → blocking** — the loop previously used a 1 ms
   `epoll_wait` timeout (intentional "run-to-completion"), which pinned workers
   at ~0% idle / ~70% sys CPU with zero load. Switched to `-1` (block until
   event): ~100% idle at rest, +73% RPS at low concurrency. The
   `reactor_set_timeout(ms)` API is retained for callers wanting busy-poll.
2. That epoll backend peaked at **~400k RPS** (`/plaintext`), ~340k (`/json`).

### Historical Results (Docker, 3 CPUs, KVM)
- **18k+ req/sec** on plaintext (port 3984)
- **16k+ req/sec** on JSON responses (port 3984)

### Expected with Full Optimizations (4+ CPUs, bare metal)
Based on [Extreme HTTP Performance Tuning](https://talawah.io/blog/extreme-http-performance-tuning-one-point-two-million/):
- **1.2M req/sec** on plaintext (target from article)
- **Latency**: sub-millisecond p99
- **CPU utilization**: 100% on useful work
- **Scaling**: linear with CPU cores

### Why kerneldev MCP is not used here
The `kerneldev-mcp` tool builds and boots a *custom* kernel in a separate
virtme-ng/QEMU VM; it cannot reconfigure the kernel of an already-running Apple vz
Lima instance (no `/dev/kvm`, no cpufreq governor, no control over the guest kernel
command line). The single change that moved the needle in this environment was the
in-process epoll-timeout fix above, not kernel tuning.

### 🖥️ System tuning (Ubuntu guest)
Out of the box Ubuntu ships with small socket buffers and backlogs that cap
high-concurrency throughput. `tune_system.sh` applies the validated sysctl set
(run as root inside the VM, or copy to `/etc/sysctl.d/99-libreactor.conf`):

- Socket buffers: `rmem_max`/`wmem_max` 16 MB, `tcp_rmem`/`tcp_wmem` up to 16 MB
- Listen backlog: `somaxconn=32768` (the server calls `listen(fd, INT_MAX)`,
  the kernel clamps to this), `tcp_max_syn_backlog=32768`, `netdev_max_backlog=250000`
- `tcp_fastopen=3` (client + server), `tcp_tw_reuse=2`

A/B-measured effect on `/plaintext` (loopback, 4 vCPU):

| Concurrency | default Ubuntu | + sysctl tuning | Δ |
|-------------|----------------|-----------------|---|
| 2t / 64c    | 859k | 861k | ~0% |
| 4t / 128c   | 1,016k | 1,015k | ~0% |
| 4t / 256c   | 1,032k | **1,089k** | **+5.5%** |
| 4t / 512c   | 1,012k | **1,088k** | **+7.5%** |

The win is concentrated at high concurrency (256+ connections), where the larger
buffers/backlog stop being the limit. At low concurrency the workload is
syscall-bound, not buffer-bound, so sysctl changes are in the noise.

> **Conntrack bypass (NOTRACK for lo) — do NOT apply here.** Bypassing
> connection tracking for the loopback interface is a commonly recommended
> tuning, but A/B on this setup *regressed hard* at high concurrency (4t/256c:
> 1089k → 528k RPS with high variance). It is intentionally excluded from
> `tune_system.sh`. Loopback-specific quirks in the Apple vz net stack are the
> likely cause.

### 🧪 TechEmpower-equivalent methodology (self-reported)

The official [TechEmpower Framework Benchmarks](https://www.techempower.com/benchmarks/)
were **archived in March 2026** (Round 23 was the final round, on dedicated
40 Gb enterprise hardware). New submissions are no longer accepted, so this is
**not an official TechEmpower result** — it is the same methodology run locally,
self-reported, for comparison only.

The responses are byte-exact to the TechEmpower spec — verified:

| Endpoint | Body | Bytes | Content-Type |
|----------|------|-------|--------------|
| `/plaintext` | `Hello, World!` | 13 | `text/plain` |
| `/json` | `{"message":"Hello, World!"}` | 27 | `application/json` |

Using the TechEmpower parameters (512 connections, 15 s runs, plaintext at
pipeline depth 16, JSON unpipelined) on the 4-vCPU Lima vz VM:

| Test | TechEmpower params | Median RPS | min–max (7 runs) |
|------|--------------------|-----------|------------------|
| **plaintext** (pipeline=16) | `-c 512 -d 15`, 16-deep pipeline | **~7,700,000** | 6.59M – 7.79M |
| **json** (unpipelined) | `-c 512 -d 15` | **~1,045,000** | 904k – 1.12M |

Reproduce:

```bash
# plaintext (pipeline depth 16, TechEmpower-style)
wrk -s bench/techempower_plaintext_pipeline16.lua -c 512 -t 4 -d 15 \
    http://127.0.0.1:3984/plaintext

# json (unpipelined)
wrk -c 512 -t 4 -d 15 -H "Accept: application/json" http://127.0.0.1:3984/json
```

> **Hardware caveat — not apples-to-apples with Round 23.** Round 23's top
> C/C++ frameworks (ulib, drogon, h2o) score 7–9M plaintext RPS on 40 Gb NICs
> with fiber and many-core enterprise CPUs. These numbers are measured on a
> 4-vCPU Apple Virtualization Framework VM over **loopback**, so they reflect
> the in-process event loop and TCP loopback stack, not real-network throughput.
> They place libreactor in the same *performance class* as the top of the
> Round 23 table, but a direct numeric comparison would be misleading. The
> non-pipelined json number (~1.05M) is the more honest measure of per-request
> cost; the 7.7M plaintext number is dominated by pipeline amplification.

### 🎮 Binary protocol benchmark (raw vs MessagePack)

For comparison with the kind of binary wire format used in game servers (vs the
HTTP/JSON workload above), the repo includes an **isolated** binary server
(`libreactor-binary-server`) built on the same io_uring reactor but bypassing the
HTTP path entirely. It uses libreactor's transport-agnostic `stream`/`descriptor`
API directly — no HTTP parsing, no headers, no `server_*`.

**Protocol** (length-prefixed, one packet per request, one reply):
```
[u16 len BE][payload of len bytes]
payload[0] = type tag:
  0x01 = raw fixed-struct {u8 type, u16 x, u16 y, u8 hp}  (6 bytes)
  0x02 = MessagePack map {x:u16, y:u16, hp:u8}
```
The server mutates state per packet (`x+1, y+1, hp-1 floored at 0`) and echoes
the mutated state back in the same codec — so the only delta between raw and
MessagePack is the codec cost.

**Measured** (loopback, 4-vCPU Lima vz VM, `binary-loadgen`, 3-run medians,
8 threads × 256 connections, depth-1 ping-pong, 8s runs):

| Workload | Codec | Per-request bytes | Throughput |
|----------|-------|-------------------|------------|
| HTTP `/json` (wrk) | text JSON | ~200 (headers+body) | ~1,050,000 req/s |
| **raw fixed-struct** (binary) | packed struct | 6 payload + 2 framing | **~343,000 pkt/s** |
| **MessagePack** (binary) | msgpack map | ~9 payload + 2 framing | **~272,000 pkt/s** |

`strace -c` of a binary worker under peak load: `sendto` 54%, `recvfrom` 34%,
`io_uring_enter` 12% — same shape as the HTTP path, **codec cost is not the
bottleneck**. The server saturates at ~69% kernel (sys 42% + softirq 27%) on
recv/send syscalls, 0% idle — the reactor and codecs are not the limit.

> **Caveat — this is NOT "binary is slower than HTTP".** The two numbers are
> generated by **different load tools** and measure different things:
> - HTTP/json uses **wrk** (io_uring-internal client, full HTTP pipeline, many
>   requests in flight per connection) → it keeps the server fed at all times.
> - binary uses **`binary-loadgen`** (pthread + blocking sockets, depth-1
>   ping-pong: send one, read one reply, repeat) → each connection has at most
>   one packet in flight, so throughput is capped by RTT × connection-count, not
>   by server capacity. The raw-vs-msgpack comparison (same loadgen) is the
>   honest delta: raw is ~26% faster because the packed struct skips msgpack's
>   per-field tag/length encoding.
> - A fair apples-to-apples comparison would need an io_uring binary load
>   generator (the binary analogue of wrk). That is intentionally out of scope
>   here — the goal was to measure the **codec delta** (raw vs msgpack), not to
>   claim a binary vs HTTP winner.

**Build & run:**
```bash
make libreactor-binary-server binary-loadgen
./libreactor-binary-server --port 3985          # 4 workers, pinned to CPUs
./binary-loadgen --proto raw --threads 8 --conns 256 --duration 8 --port 3985
./binary-loadgen --proto msgpack --threads 8 --conns 256 --duration 8 --port 3985
```

**Protocol design notes:**
- The raw fixed-struct uses **network byte order** (`htobe16`/`be16toh`) so a
  macOS/ARM client and a Linux/ARM server agree regardless of endianness.
- The binary server uses `SO_REUSEPORT` across workers (kernel load-balances
  accepts), exactly like the HTTP server.
- The same io_uring reactor backend (DEFER_TASKRUN + O(1) slot table + recv)
  powers both servers — only the application framing differs.

## 🔧 API

### Endpoints
- `GET /plaintext` - returns "Hello, World!"
- `GET /json` - returns `{"message":"Hello, World!"}`

### Example Request
```bash
curl http://localhost:3984/plaintext
# Hello, World!

curl http://localhost:3984/json
# {"message":"Hello, World!"}
```

## 🛠️ Development

### Recompilation
```bash
make clean
make CFLAGS="-O3 -march=native -flto -DNDEBUG" libreactor-server
```

### Debug Build
```bash
make CFLAGS="-O0 -g" libreactor-server
```

## 📈 Monitoring

### CPU Profiling
```bash
perf record -F 99 -g -p $(pgrep libreactor-server | head -1) -o perf.data -- sleep 10
perf report -i perf.data
```

### System Calls
```bash
bpftrace -e 'tracepoint:syscalls:sys_enter_sendto { @[comm] = count(); } interval:s:1 { print(@); clear(@); }'
```

## 🔗 Links

- [Libreactor](https://github.com/fredrikwidlund/libreactor)
- [Extreme HTTP Performance Tuning](https://talawah.io/blog/extreme-http-performance-tuning-one-point-two-million/)
- [SO_REUSEPORT](https://lwn.net/Articles/542629/)
