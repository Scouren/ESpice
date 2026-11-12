//! The `auto` backend's price of a GPU query. In: the circuit's batches, a
//! host probe of their eval time, the caller's eval estimate, the machine's
//! calibrated constants (`machine.zig`) and the measurements earlier runs
//! left in the cache directory; under lever `p1`, the census and the
//! file's model rows alone (`../price.zig`). Out: an admit or a
//! decline before the first driver call, the audit that holds an admitted
//! query to its price, and the JIT warmth of the heavy kernel images.
//! Cites #126 and #139 (the measurements behind the constants).
//!
//! Contents:
//! - `pub const Price = struct`
//! - `pub const Audit = struct (`from`, `at`)`
//! - `pub const CostCache = struct (`key`, `read`, `learn`, `write`, `Rec`)`
//! - `pub const heavy_image_bytes: usize`
//! - `pub fn admit(gpa: std.mem.Allocator, host: Host, threads: u32, evals: f64, driver_up: bool, m: *const Machine) !Price`
//! - `pub fn quote(gpa: std.mem.Allocator, host: Host, threads: u32, c: *const Constants) !price.Cost`
//! - `pub fn recommend(host: Host, m: ?*const Machine) bool`
//! - `pub fn imageOf(kernel: []const u8) ?[:0]const u8`
//! - `pub fn imageKey(kernel: []const u8) u64`
//! - `pub fn unpriced(m: *const Machine, b: device_ir.Batch) bool`
//! - `pub fn imageWarm(image: []const u8, knobs: Knobs) bool`
//! - `pub fn markWarm(image: []const u8, knobs: Knobs) void`

const std = @import("std");
const assert = std.debug.assert;
const gompute = @import("gompute");
const drv = @import("driver.zig");
const artifacts = @import("gompute_kernels");
const device_ir = @import("device").abi;
const Knobs = @import("../Circuit.zig").Knobs;
const devices = @import("devices.zig");
const context = @import("context.zig");
const ctx_scatter = @import("context_scatter.zig");
const price = @import("price.zig");
const placement = @import("../price.zig");
const machine = @import("../machine.zig");
const Machine = machine.Machine;
const Constants = machine.Constants;
const Planes = device_ir.Planes;
const backend = devices.backend;
const Host = context.Host;
const Error = context.Error;
const nowNs = context.nowNs;

/// The host's price per eval in microseconds, and the circuit's
/// `CostCache` key.
pub const Price = struct { cpu_us: f64, key: u64 };

/// The device path's measured price under `auto`: wall time
/// inside the entry points that evaluate (eval, the limit pass with its
/// prefetch, the charge passes) per device eval, from eval `from` to
/// eval `at`, against the host price per eval `Cost.admit` measured.
/// Checked once; past it the query stays where it is.
pub const Audit = struct {
    cpu_us: f64,
    spent_ns: u64 = 0,
    done: bool = false,
    /// Where the verdict is kept for the next run (`CostCache`).
    key: u64,
    knobs: Knobs,
    /// False under an explicit `cuda`/`hip`: the audit only measures, for a
    /// circuit `auto` declined on its probe (`CostCache.learn`).
    demote: bool = true,

    /// The first evals pay cold caches and the module's first launches.
    pub const from: u64 = 10;
    pub const at: u64 = 40;
};

/// The prices `Audit` measured for one circuit on this card,
/// kept beside the JIT markers in `<cache>/espice/gpu-cost/<key>` as the
/// host and device microseconds per eval. `Cost.admit` prices from them
/// instead of probing, and declines a circuit the device lost before
/// without starting the driver. The key covers the machine's cards (read
/// without the driver: `Identity.cardsKey`), the circuit's
/// shape and models, the kernel images, the host threads and the query's
/// expected evals (an OP and a transient of one circuit price apart), so a
/// rebuild, another card or another thread count measures again.
pub const CostCache = struct {
    pub const Rec = struct { cpu_us: f64, gpu_us: f64 };

    pub fn key(host: Host, threads: u32, evals: f64) u64 {
        var h = std.hash.Wyhash.init(0x5e1ce);
        const cards: u64 = if (machine.vendor) |v| machine.identity("", v).cardsKey() else 0;
        h.update(std.mem.asBytes(&cards));
        for ([_]u64{ host.n, host.planes.g_vals.len, @intFromBool(host.has_charge), threads, @bitCast(evals) }) |v| h.update(std.mem.asBytes(&v));
        for (host.batches) |b| {
            const get = b.hooks.gpu_payload orelse continue;
            const p = get(b.ctx);
            h.update(b.type_name);
            h.update(std.mem.asBytes(&p.count));
            // A runtime `.hdl` image would start the driver: its kernel's
            // name stands in.
            const image = imageOf(p.kernel) orelse p.kernel;
            const ih = std.hash.Wyhash.hash(0, image);
            h.update(std.mem.asBytes(&ih));
        }
        return h.final();
    }

    pub fn read(k: u64, knobs: Knobs) ?Rec {
        var buf: [512]u8 = undefined;
        const p = machine.cachePath(&buf, "gpu-cost", k, "", knobs) orelse return null;
        const fd = std.c.open(p, .{ .ACCMODE = .RDONLY }, @as(c_uint, 0));
        if (fd < 0) return null;
        defer _ = std.c.close(fd);
        var rec: [2]f64 = undefined;
        if (std.c.read(fd, @ptrCast(&rec), @sizeOf([2]f64)) != @sizeOf([2]f64)) return null;
        // gpu_us 0: `auto` declined on the probe; nothing measured the device.
        if (!(rec[0] > 0) or !(rec[1] >= 0)) return null;
        return .{ .cpu_us = rec[0], .gpu_us = rec[1] };
    }

    /// The measuring audit for an explicit `cuda`/`hip` query of a circuit
    /// `auto` priced before (a record exists): it books the device's cost
    /// per eval beside the host's, so the next `auto` run decides from both
    /// measurements instead of the estimate that declined it. Null for a
    /// circuit with no record.
    pub fn learn(host: Host, threads: u32, evals: f64, knobs: Knobs) ?Audit {
        if (evals < 20) return null;
        const k = key(host, threads, evals);
        const rec = read(k, knobs) orelse return null;
        return .{ .cpu_us = rec.cpu_us, .key = k, .knobs = knobs, .demote = false };
    }

    /// Best effort, as `markWarm`: a missing record only means the next
    /// run probes.
    pub fn write(k: u64, knobs: Knobs, rec: Rec) void {
        var buf: [512]u8 = undefined;
        const p = machine.cachePath(&buf, "gpu-cost", k, "", knobs) orelse return;
        if (!machine.makeParents(&buf, p)) return;
        const fd = std.c.open(p, .{ .ACCMODE = .WRONLY, .CREAT = true, .TRUNC = true }, @as(c_uint, 0o644));
        if (fd < 0) return;
        defer _ = std.c.close(fd);
        const v = [2]f64{ rec.cpu_us, rec.gpu_us };
        _ = std.c.write(fd, @ptrCast(&v), @sizeOf([2]f64));
    }
};

/// Kernel images larger than this JIT for seconds to minutes on first use
/// (bsim4va 3.6 MB of PTX in 15 s, psp103 7.8 MB in 35 s, hisimhv_va
/// 29.3 MB in 1001 s), so `auto` only runs them once a `--backend cuda` run
/// has compiled them into the driver cache.
pub const heavy_image_bytes: usize = 1 << 20;

// TESTHELPER
/// A batch for `Cost.admit` that busy-waits `spin_ns` per eval and counts
/// its evals.
const StubBatch = struct {
    spin_ns: u64,
    count: u32 = 1,
    /// `GpuPayload.instances`: `count` instances' bytes.
    held: []const u8 = &.{},
    /// `GpuPayload.kernel`: no image in a test build, so its name keys
    /// the model row (`imageKey`).
    kernel: []const u8 = "",
    evals: u32 = 0,

    fn eval(ctx: *anyopaque, _: *const Planes, _: u32, _: u32, _: []const f64, _: f64) void {
        const self: *StubBatch = @ptrCast(@alignCast(ctx));
        self.evals += 1;
        const t0 = nowNs();
        while (nowNs() - t0 < self.spin_ns) {}
    }

    fn payload(ctx: *anyopaque) device_ir.GpuPayload {
        const self: *StubBatch = @ptrCast(@alignCast(ctx));
        return .{
            .kernel = self.kernel,
            .count = self.count,
            .n_u = 2,
            .models = &.{},
            .model_of = &.{},
            .instances = self.held,
            .gath = &.{},
            .rhs_idx = &.{},
            .slots = &.{ 0, 1 },
            .lim_kernel = "",
            .ctl_kernel = "",
            .reduce_kernel = "",
            .lim_x = &.{},
            .states = &.{},
            .lim_active = false,
        };
    }

    fn batch(self: *StubBatch, hooks: *const device_ir.Hooks) device_ir.Batch {
        return .{ .ctx = self, .eval = eval, .eval_newton = eval, .count = self.count, .n_u = 2, .has_charge = false, .has_const_jacobian = false, .type_name = "stub", .hooks = hooks };
    }
};

/// Admits the device for `host`'s query, or declines it with
/// `NotEnoughGpuWork`, from the machine's calibrated constants (`m.c`):
/// the GPU must beat the CPU by `min_ratio` per eval and by `margin` over
/// the whole query, the driver's `start_ms` included unless `driver_up`.
/// Under lever `p1` it prices from `m`'s model rows and the census alone
/// (`placement.place`): no probe, no record, `driver_up` unread.
pub fn admit(gpa: std.mem.Allocator, host: Host, threads: u32, evals: f64, driver_up: bool, m: *const Machine) !Price {
    if (host.knobs.perf.p1) return admitPriced(gpa, host, threads, evals, m);
    const c = &m.c;
    const stats = host.knobs.gpu_stats != .off;
    const init_us: f64 = if (driver_up) 0 else c.start_ms * 1e3;
    // The probe costs three host evals; a query with few more than
    // that cannot repay the setup.
    if (evals < 20) return decline(stats, 0, 0, "too few evals");
    const key = CostCache.key(host, threads, evals);
    if (CostCache.read(key, host.knobs)) |rec| if (rec.gpu_us > 0) {
        if (!measuredWins(c, rec, evals, init_us)) return decline(stats, rec.cpu_us, rec.gpu_us, "measured on this card");
        if (stats) std.debug.print(
            "gpu-stats: cost per eval cpu={d:.0} us gpu={d:.0} us (measured on this card), {d:.0} evals, setup {d:.0} ms: GPU\n",
            .{ rec.cpu_us, rec.gpu_us, evals, init_us * 1e-3 },
        );
        return .{ .cpu_us = rec.cpu_us, .key = key };
    };
    const q = try quote(gpa, host, threads, c);
    const cpu_us = q.cpu_us;
    const gpu_us = q.gpu_us;
    if (!gpuWins(c, cpu_us, gpu_us, evals, init_us)) {
        // The host's price, for an explicit device run to set beside
        // its measured one (`CostCache.learn`).
        CostCache.write(key, host.knobs, .{ .cpu_us = cpu_us, .gpu_us = 0 });
        return decline(stats, cpu_us, gpu_us, "the CPU is priced faster");
    }
    if (stats) std.debug.print(
        "gpu-stats: cost per eval cpu={d:.0} us gpu={d:.0} us, {d:.0} evals, setup {d:.0} ms: GPU\n",
        .{ cpu_us, gpu_us, evals, init_us * 1e-3 },
    );
    return .{ .cpu_us = cpu_us, .key = key };
}

/// Both sides' price per eval of `host`'s GPU-eligible batches (`price`),
/// from one host probe of each: three evals on scratch planes at a spread
/// x, the fastest kept.
pub fn quote(gpa: std.mem.Allocator, host: Host, threads: u32, c: *const Constants) !price.Cost {
    var slots: u64 = 0;
    var n_rows: usize = 0;
    for (host.batches) |b| {
        const get = b.hooks.gpu_payload orelse continue;
        const p = get(b.ctx);
        // A constant batch's g/c stamps sit in the baseline.
        if (!b.has_const_jacobian) slots += p.slots.len;
        n_rows += 1;
    }
    const rows = try gpa.alloc(price.Row, n_rows);
    defer gpa.free(rows);
    // Scratch planes: the probe must not disturb a linearization a
    // prerequisite query left behind.
    const ng = host.planes.g_vals.len;
    const nr = host.planes.rhs.len;
    const g = try gpa.alloc(f64, 2 * ng + 2 * nr);
    defer gpa.free(g);
    @memset(g, 0);
    const pl = ctx_scatter.scratchPlanes(g, ng, nr);
    // Spread, not zero: at x = 0 every MOSFET sits in cutoff, which
    // evaluates in half the time of the operating mix (mos1: 197 us
    // against ~400 us per eval on parallel_inverters_2000).
    const x = try gpa.alloc(f64, host.n + 1);
    defer gpa.free(x);
    for (x, 0..) |*xi, i| xi.* = @as(f64, @floatFromInt(i % 7)) * 0.3;
    var i: usize = 0;
    for (host.batches) |b| {
        const get = b.hooks.gpu_payload orelse continue;
        const p = get(b.ctx);
        var host_ns: u64 = std.math.maxInt(u64);
        for (0..3) |_| {
            const t0 = nowNs();
            b.eval(b.ctx, &pl, 0, b.count, x, 0);
            host_ns = @min(host_ns, nowNs() - t0);
        }
        const held: f64 = @floatFromInt((p.instances.len + p.states.len) / @max(p.count, 1));
        rows[i] = .{ .count = @max(p.count, 1), .host_us = @as(f64, @floatFromInt(host_ns)) * 1e-3, .held_bytes = held };
        // placement.tsv's `rows` column, recorded from these lines.
        if (host.knobs.gpu_stats != .off) std.debug.print("gpu-stats: price row {s} {d}:{d:.3}:{d:.0}\n", .{ b.type_name, rows[i].count, rows[i].host_us, held });
        i += 1;
    }
    assert(i == n_rows);

    const n_planes: usize = if (host.has_charge) 4 else 2;
    const bus_bytes: f64 = @floatFromInt((n_planes * (ng + nr) / 2 + 2 * host.n) * @sizeOf(f64));
    const stage_bytes: f64 = @floatFromInt(slots * n_planes / 2 * @sizeOf(f64));
    const fixed_us = c.eval_fixed_us + bus_bytes / c.bus_b_per_us + stage_bytes / c.stage_b_per_us;
    const lanes = 1.0 + c.host_lane_gain * @as(f64, @floatFromInt(@max(1, threads) - 1));
    if (host.knobs.gpu_stats != .off) std.debug.print("gpu-stats: price fixed_us={d:.1} lanes={d:.2}\n", .{ fixed_us, lanes });
    return price.ofQuery(c, rows, fixed_us, lanes);
}

/// Under an explicit device backend, one stderr line when the history walk
/// alone (`price.ofHistory`: counts and held bytes, no probe, so the same
/// text on every run) loses on the device by far. Advice only; every
/// eligible batch still runs where it was asked to. Silent without a
/// calibrated machine `m`, whose constants price the walk. True when it
/// printed.
pub fn recommend(host: Host, m: ?*const Machine) bool {
    const c = &(m orelse return false).c;
    var hist: price.Cost = .{ .cpu_us = 0, .gpu_us = 0 };
    var n_lines: usize = 0;
    var n_rows: usize = 0;
    for (host.batches) |b| {
        const get = b.hooks.gpu_payload orelse continue;
        const p = get(b.ctx);
        n_rows += 1;
        const held: f64 = @floatFromInt((p.instances.len + p.states.len) / @max(p.count, 1));
        if (held <= c.hist_floor_bytes) continue;
        n_lines += 1;
        const line = price.ofHistory(c, &.{.{ .count = @max(p.count, 1), .host_us = 0, .held_bytes = held }});
        hist.cpu_us += line.cpu_us;
        hist.gpu_us += line.gpu_us;
    }
    if (!price.historyLoses(c, hist)) return false;
    std.debug.print(
        "note: {d} of {d} GPU-eligible device types hold a waveform history that one GPU thread per instance walks serially, priced at {d:.0} us per iteration against {d:.0} us on the CPU; `--backend auto` or `cpu` runs this circuit faster\n",
        .{ n_lines, n_rows, hist.gpu_us, hist.cpu_us },
    );
    return true;
}

/// The embedded image that exports `kernel`, or null.
pub fn imageOf(kernel: []const u8) ?[:0]const u8 {
    if (comptime backend == null) return null;
    const idx = if (comptime backend == .cuda) artifacts.cuda_index else artifacts.hip_index;
    const images = if (comptime backend == .cuda) artifacts.cuda_images else artifacts.hip_images;
    const e = idx.get(kernel) orelse return null;
    return images[e.blob];
}

/// The key of `kernel`'s `machine.Model` row: the Wyhash of its embedded
/// image, or of the kernel's name when this build has none (a runtime
/// `.hdl` image, which calibrate never measures, so it has no row).
pub fn imageKey(kernel: []const u8) u64 {
    return std.hash.Wyhash.hash(0, imageOf(kernel) orelse kernel);
}

/// Under lever `p1`, whether eligible batch `b` stays on the host: `m`
/// holds no model row for its image (08-placement.md sec. 2). False for a
/// batch without a GPU payload, which never leaves the host anyway.
pub fn unpriced(m: *const Machine, b: device_ir.Batch) bool {
    const get = b.hooks.gpu_payload orelse return false;
    return placement.rowOf(m, imageKey(get(b.ctx).kernel)) == null;
}

pub fn imageWarm(image: []const u8, knobs: Knobs) bool {
    return sassFits() or markedWarm(image, knobs);
}

/// Records `image` as compiled. Best effort: a missing marker only means the
/// next `auto` run keeps that batch on the CPU.
pub fn markWarm(image: []const u8, knobs: Knobs) void {
    var buf: [512]u8 = undefined;
    const path = markerPath(&buf, image, knobs) orelse return;
    if (!machine.makeParents(&buf, path)) return;
    const fd = std.c.open(path, .{ .ACCMODE = .WRONLY, .CREAT = true }, @as(c_uint, 0o644));
    if (fd >= 0) _ = std.c.close(fd);
}

// ---- private ----

/// `admit` under lever `p1`: the census of `host`'s eligible batches
/// (image keys and widths, the bytes `quote` prices) at `threads` lanes
/// and `evals` evals, placed by `placement.place`. Evaluates nothing.
fn admitPriced(gpa: std.mem.Allocator, host: Host, threads: u32, evals: f64, m: *const Machine) !Price {
    const stats = host.knobs.gpu_stats != .off;
    var slots: u64 = 0;
    var n_rows: usize = 0;
    for (host.batches) |b| {
        const get = b.hooks.gpu_payload orelse continue;
        if (!b.has_const_jacobian) slots += get(b.ctx).slots.len;
        n_rows += 1;
    }
    const rows = try gpa.alloc(placement.Batch, n_rows);
    defer gpa.free(rows);
    var i: usize = 0;
    for (host.batches) |b| {
        const get = b.hooks.gpu_payload orelse continue;
        const p = get(b.ctx);
        rows[i] = .{ .image = imageKey(p.kernel), .count = @max(p.count, 1) };
        i += 1;
    }
    assert(i == n_rows);
    const n_planes: usize = if (host.has_charge) 4 else 2;
    const ng = host.planes.g_vals.len;
    const nr = host.planes.rhs.len;
    const census: placement.Census = .{
        .batches = rows,
        .evals = evals,
        .bus_bytes = @floatFromInt((n_planes * (ng + nr) / 2 + 2 * host.n) * @sizeOf(f64)),
        .stage_bytes = @floatFromInt(slots * n_planes / 2 * @sizeOf(f64)),
        .lanes = @max(threads, 1),
    };
    const v = placement.place(m, &census);
    if (!v.device) return decline(stats, v.cpu_us, v.gpu_us, "priced from the calibration's rows");
    if (stats) std.debug.print(
        "gpu-stats: cost per eval cpu={d:.0} us gpu={d:.0} us ({d} of {d} batches priced), {d:.0} evals: GPU\n",
        .{ v.cpu_us, v.gpu_us, v.priced, n_rows, evals },
    );
    return .{ .cpu_us = v.cpu_us, .key = CostCache.key(host, threads, evals) };
}

/// `gpuWins` for prices `Audit` measured: no per-eval safety ratio
/// (the audit demotes at 1), the query margin and the setup kept.
fn measuredWins(c: *const Constants, rec: CostCache.Rec, evals: f64, init_us: f64) bool {
    return rec.cpu_us > rec.gpu_us and c.margin * (init_us + evals * rec.gpu_us) < evals * rec.cpu_us;
}

/// The GPU must beat the CPU by `min_ratio` per eval and by `margin` over
/// the whole query, setup included. Any NaN input prices the CPU.
fn gpuWins(c: *const Constants, cpu_us: f64, gpu_us: f64, evals: f64, init_us: f64) bool {
    return cpu_us >= c.min_ratio * gpu_us and c.margin * (init_us + evals * gpu_us) < evals * cpu_us;
}

fn decline(stats: bool, cpu_us: f64, gpu_us: f64, why: []const u8) Error {
    if (stats) std.debug.print("gpu-stats: cost per eval cpu={d:.0} us gpu={d:.0} us: CPU ({s})\n", .{ cpu_us, gpu_us, why });
    return Error.NotEnoughGpuWork;
}

/// The images carry SASS for this card (`-Dcuda-sass`), so loading them
/// needs no JIT. Asked once per process; any failure answers false.
fn sassFits() bool {
    if (comptime backend != .cuda) return false;
    const want: u32 = comptime if (artifacts.cuda_sass) |arch| std.fmt.parseInt(u32, arch["sm_".len..], 10) catch 0 else 0;
    if (want == 0) return false;
    const Cache = struct {
        var state: std.atomic.Value(u8) = .init(0); // 0 unknown, 1 fits, 2 not
    };
    switch (Cache.state.load(.acquire)) {
        1 => return true,
        2 => return false,
        else => {},
    }
    const fits = blk: {
        var compute = drv.compute(null) catch break :blk false;
        defer compute.deinit();
        break :blk (compute.computeCapability() catch break :blk false) == want;
    };
    Cache.state.store(if (fits) 1 else 2, .release);
    return fits;
}

/// The marker file that records `image` as compiled into the driver cache:
/// `$XDG_CACHE_HOME/espice/gpu-jit/<hash>` or `$HOME/.cache/...`. The hash
/// covers the image bytes, so a rebuild that changes the kernel starts cold.
/// ponytail: the driver cache also keys on the driver version, so an upgrade
/// leaves stale markers and `auto` pays one cold JIT; key on the version too
/// if that ever matters.
fn markerPath(buf: []u8, image: []const u8, knobs: Knobs) ?[:0]const u8 {
    return machine.cachePath(buf, "gpu-jit", std.hash.Wyhash.hash(0, image), "", knobs);
}

/// Whether `markWarm` recorded `image` under `knobs`' cache root.
fn markedWarm(image: []const u8, knobs: Knobs) bool {
    var buf: [512]u8 = undefined;
    const path = markerPath(&buf, image, knobs) orelse return false;
    return std.c.access(path, 0) == 0;
}

/// The constants the tests price with: the placement fixture's.
fn fixture() !Constants {
    var arena: std.heap.ArenaAllocator = .init(std.testing.allocator);
    defer arena.deinit();
    return (try machine.parse(arena.allocator(), machine.test_hooks.fixture)).c;
}

test "cardsKey:procfs gives the key the driver's own card uuids give" {
    // Oracle: the driver (`cuDeviceGetUuid` per ordinal), which the key
    // read before stage 1. Without images or a CUDA driver both sides are 0.
    var want: u64 = 0;
    if (comptime backend == .cuda) if (drv.deviceCount(.cuda)) |count| {
        for (0..count) |o| {
            var c = try drv.computeOn(.cuda, @intCast(o));
            defer c.deinit();
            want +%= std.hash.Wyhash.hash(0, &(try c.info()).uuid);
        }
    } else |_| {};
    // ponytail: no AMD card here to check kfd ids against.
    if (comptime backend == .hip) return;
    const got = if (machine.vendor) |v| machine.identity("", v).cardsKey() else 0;
    try std.testing.expectEqual(want, got);
}

test "CostCache: a record reads back under its key and nowhere else" {
    var tmp = std.testing.tmpDir(.{});
    defer tmp.cleanup();
    var root: [64]u8 = undefined;
    const knobs: Knobs = .{ .xdg_cache_home = try std.fmt.bufPrint(&root, ".zig-cache/tmp/{s}", .{&tmp.sub_path}) };
    try std.testing.expect(CostCache.read(42, knobs) == null);
    CostCache.write(42, knobs, .{ .cpu_us = 120, .gpu_us = 30 });
    const rec = CostCache.read(42, knobs) orelse return error.TestUnexpectedResult;
    try std.testing.expectEqual(@as(f64, 120), rec.cpu_us);
    try std.testing.expectEqual(@as(f64, 30), rec.gpu_us);
    try std.testing.expect(CostCache.read(43, knobs) == null);
    // A declined probe books the host's price alone; it reads back for
    // `learn`, with no device price to admit on.
    CostCache.write(44, knobs, .{ .cpu_us = 120, .gpu_us = 0 });
    try std.testing.expectEqual(@as(f64, 0), (CostCache.read(44, knobs) orelse return error.TestUnexpectedResult).gpu_us);
    const c = try fixture();
    try std.testing.expect(measuredWins(&c, rec, 1000, 0));
    try std.testing.expect(!measuredWins(&c, .{ .cpu_us = 30, .gpu_us = 120 }, 1000, 0));
}

test "Cost.gpuWins needs both margins and refuses NaN" {
    const c = try fixture();
    // 10x per eval, cheap setup: the GPU.
    try std.testing.expect(gpuWins(&c, 1000, 100, 1000, 0));
    // Under the per-eval ratio, however many evals.
    try std.testing.expect(!gpuWins(&c, 199, 100, 1e9, 0));
    // Fast per eval, but setup outweighs the query.
    try std.testing.expect(!gpuWins(&c, 1000, 100, 10, c.start_ms * 1e3));
    try std.testing.expect(!gpuWins(&c, std.math.nan(f64), 100, 1000, 0));
    try std.testing.expect(!gpuWins(&c, 1000, std.math.nan(f64), 1000, 0));
}

test "Cost.gpuWins at its bars and on infinities" {
    const c = try fixture();
    // `min_ratio` exactly passes.
    try std.testing.expect(gpuWins(&c, c.min_ratio * 100, 100, 1e6, 0));
    // Setup: 1.3 * (init + 1e5) < 1e6 holds below init = 669,230.8 us.
    try std.testing.expect(gpuWins(&c, 1000, 100, 1000, 669_000));
    try std.testing.expect(!gpuWins(&c, 1000, 100, 1000, 670_000));
    try std.testing.expect(!gpuWins(&c, 1000, std.math.inf(f64), 1000, 0));
    // Unbounded evals: inf < inf is false, so the CPU.
    try std.testing.expect(!gpuWins(&c, 1000, 100, std.math.inf(f64), 0));
}

test "Cost.admit prices a measured host eval and leaves the planes alone" {
    const gpa = std.testing.allocator;
    const m: Machine = .{ .id = .{ .threads = 1 }, .c = try fixture() };
    // `admit` reads only `gpu_payload` off the hooks.
    var gpu_hooks: device_ir.Hooks = undefined;
    gpu_hooks.gpu_payload = StubBatch.payload;
    var host_hooks: device_ir.Hooks = undefined;
    host_hooks.gpu_payload = null;
    var vals: [8]f64 = @splat(7);
    const planes: Planes = .{ .g_vals = vals[0..2], .c_vals = vals[2..4], .rhs = vals[4..6], .q_vec = vals[6..8] };
    const Case = struct { spin_ns: u64, count: u32 = 2000, evals: f64, driver_up: bool, admitted: bool, probed: bool };
    const cases = [_]Case{
        // Too few evals: declined before the probe.
        .{ .spin_ns = 2_000_000, .evals = 19, .driver_up = true, .admitted = false, .probed = false },
        // A free host eval never repays the 40 us launch floor.
        .{ .spin_ns = 0, .evals = 1e6, .driver_up = true, .admitted = false, .probed = true },
        // >= 2 ms against <= 0.28 ms + 0.12 of it on the device.
        .{ .spin_ns = 2_000_000, .evals = 1e6, .driver_up = true, .admitted = true, .probed = true },
        // The same eval in one instance: one device thread, 120x the host.
        .{ .spin_ns = 2_000_000, .count = 1, .evals = 1e6, .driver_up = true, .admitted = false, .probed = true },
        // The same, but 20 evals cannot repay a cold 350 ms driver setup.
        .{ .spin_ns = 2_000_000, .evals = 20, .driver_up = false, .admitted = false, .probed = true },
    };
    for (cases) |c| {
        var dev: StubBatch = .{ .spin_ns = c.spin_ns, .count = c.count };
        var other: StubBatch = .{ .spin_ns = 0 };
        const batches = [_]device_ir.Batch{ other.batch(&host_hooks), dev.batch(&gpu_hooks) };
        const host: Host = .{ .batches = &batches, .planes = planes, .n = 2, .trash_slot = 2, .has_charge = false, .knobs = .{} };
        const got = admit(gpa, host, 1, c.evals, c.driver_up, &m);
        if (c.admitted) try std.testing.expect((try got).cpu_us > 0) else try std.testing.expectError(Error.NotEnoughGpuWork, got);
        try std.testing.expectEqual(@as(u32, if (c.probed) 3 else 0), dev.evals);
        try std.testing.expectEqual(@as(u32, 0), other.evals);
        try std.testing.expectEqualSlices(f64, &@as([8]f64, @splat(7)), &vals);
    }
}

test "Cost.admit under p1: the file's model rows decide, nothing is probed, driver_up is unread" {
    // Oracle: hand arithmetic on rows written here (flat across sizes, so
    // `interp` returns them): `fast` saves 1e6 * (1000 - 3.3 * ~50) us,
    // past the 350 ms start; `slow` loses per eval; `none` has no row. The
    // stub counts its host evals: a probe would make them nonzero.
    const gpa = std.testing.allocator;
    var gpu_hooks: device_ir.Hooks = undefined;
    gpu_hooks.gpu_payload = StubBatch.payload;
    var host_hooks: device_ir.Hooks = undefined;
    host_hooks.gpu_payload = null;
    var vals: [8]f64 = @splat(7);
    const planes: Planes = .{ .g_vals = vals[0..2], .c_vals = vals[2..4], .rhs = vals[4..6], .q_vec = vals[6..8] };
    const models = [_]machine.Model{
        .{ .image = imageKey("fast"), .dev_us = @splat(50), .host_p_us = @splat(1000), .host_e_us = @splat(1000), .jit_ms = 0, .lane_gain = 1 },
        .{ .image = imageKey("slow"), .dev_us = @splat(5000), .host_p_us = @splat(100), .host_e_us = @splat(100), .jit_ms = 0, .lane_gain = 1 },
    };
    const m: Machine = .{ .id = .{ .threads = 1 }, .c = try fixture(), .models = &models };
    const Case = struct { kernel: []const u8, evals: f64, admitted: bool };
    for ([_]Case{
        .{ .kernel = "fast", .evals = 1e6, .admitted = true },
        // 300 evals save ~250 ms: under the start, whether or not the
        // driver is up.
        .{ .kernel = "fast", .evals = 300, .admitted = false },
        .{ .kernel = "slow", .evals = 1e6, .admitted = false },
        .{ .kernel = "none", .evals = 1e6, .admitted = false },
    }) |c| for ([_]bool{ false, true }) |driver_up| {
        var dev: StubBatch = .{ .spin_ns = 0, .kernel = c.kernel };
        const batches = [_]device_ir.Batch{dev.batch(&gpu_hooks)};
        const host: Host = .{ .batches = &batches, .planes = planes, .n = 2, .trash_slot = 2, .has_charge = false, .knobs = .{ .perf = .{ .p1 = true } } };
        const got = admit(gpa, host, 1, c.evals, driver_up, &m);
        if (c.admitted) {
            try std.testing.expectApproxEqRel(@as(f64, 1000), (try got).cpu_us, 1e-12);
        } else try std.testing.expectError(Error.NotEnoughGpuWork, got);
        try std.testing.expectEqual(@as(u32, 0), dev.evals);
        try std.testing.expectEqualSlices(f64, &@as([8]f64, @splat(7)), &vals);
        try std.testing.expectEqual(std.mem.eql(u8, c.kernel, "none"), unpriced(&m, batches[0]));
    };
    // A batch without a GPU payload is never `unpriced`: it is the host's.
    var cpu_only: StubBatch = .{ .spin_ns = 0 };
    try std.testing.expect(!unpriced(&m, cpu_only.batch(&host_hooks)));
}

test "Cost.recommend speaks for one history line, not for a thousand" {
    const m: Machine = .{ .id = .{ .threads = 1 }, .c = try fixture() };
    var gpu_hooks: device_ir.Hooks = undefined;
    gpu_hooks.gpu_payload = StubBatch.payload;
    var vals: [8]f64 = @splat(7);
    const planes: Planes = .{ .g_vals = vals[0..2], .c_vals = vals[2..4], .rhs = vals[4..6], .q_vec = vals[6..8] };
    // ltra.va's history, 320 KB an instance.
    const history = try std.testing.allocator.alloc(u8, 1000 * 5 * 8192 * 8);
    defer std.testing.allocator.free(history);
    for ([_]struct { count: u32, speaks: bool }{ .{ .count = 1, .speaks = true }, .{ .count = 1000, .speaks = false } }) |c| {
        var dev: StubBatch = .{ .spin_ns = 0, .count = c.count, .held = history[0 .. c.count * 5 * 8192 * 8] };
        const batches = [_]device_ir.Batch{dev.batch(&gpu_hooks)};
        const host: Host = .{ .batches = &batches, .planes = planes, .n = 2, .trash_slot = 2, .has_charge = false, .knobs = .{} };
        try std.testing.expectEqual(c.speaks, recommend(host, &m));
        // No calibration: no constants to price the walk with, no advice.
        try std.testing.expect(!recommend(host, null));
        // No probe: the advice is the same on every run.
        try std.testing.expectEqual(@as(u32, 0), dev.evals);
    }
    // A compact model's few bytes: no advice.
    var small: StubBatch = .{ .spin_ns = 0, .held = history[0..256] };
    const batches = [_]device_ir.Batch{small.batch(&gpu_hooks)};
    try std.testing.expect(!recommend(.{ .batches = &batches, .planes = planes, .n = 2, .trash_slot = 2, .has_charge = false, .knobs = .{} }, &m));
}

test "price: each recorded deck lands on its measured winner" {
    // placement.tsv: measured walls and the price's inputs, with provenance;
    // placement.machine.tsv: the machine's constants, measured beside them.
    // The verdict: a deck within `margin` of a tie may go either way;
    // a `known` deck must miss, so a fix that lands it fails until the
    // marker goes. The size: the priced wall ratio (setup included) within
    // `tolerance` of the measured one either way, the oracle's own accuracy
    // (one deck's walls wander 2-5x on the loaded machine that measured them).
    const tolerance: f64 = 10;
    const c = try fixture();
    var rows_buf: [8]price.Row = undefined;
    var lines = std.mem.tokenizeScalar(u8, @embedFile("placement.tsv"), '\n');
    var decks: usize = 0;
    var misses: usize = 0;
    var header = true;
    while (lines.next()) |line| {
        if (line[0] == '#') continue;
        if (header) {
            header = false;
            continue;
        }
        var f = std.mem.splitScalar(u8, line, '\t');
        const deck = f.next().?;
        const evals = try std.fmt.parseFloat(f64, f.next().?);
        const init_us = try std.fmt.parseFloat(f64, f.next().?);
        const fixed_us = try std.fmt.parseFloat(f64, f.next().?);
        var n_rows: usize = 0;
        var cells = std.mem.splitScalar(u8, f.next().?, ',');
        while (cells.next()) |cell| : (n_rows += 1) {
            var v = std.mem.splitScalar(u8, cell, ':');
            rows_buf[n_rows] = .{
                .count = try std.fmt.parseInt(u32, v.next().?, 10),
                .host_us = try std.fmt.parseFloat(f64, v.next().?),
                .held_bytes = try std.fmt.parseFloat(f64, v.next().?),
            };
        }
        const cpu_s = try std.fmt.parseFloat(f64, f.next().?);
        const cuda_s = try std.fmt.parseFloat(f64, f.next().?);
        const known = !std.mem.eql(u8, f.next().?, "-");
        try std.testing.expect(f.next() == null);

        const q = price.ofQuery(&c, rows_buf[0..n_rows], fixed_us, 1);
        const priced = (init_us + evals * q.gpu_us) / (evals * q.cpu_us);
        const measured = cuda_s / cpu_s;
        const on_gpu = gpuWins(&c, q.cpu_us, q.gpu_us, evals, init_us);
        const right = if (on_gpu) c.margin * cpu_s >= cuda_s else c.margin * cuda_s >= cpu_s;
        const sized = priced < tolerance * measured and measured < tolerance * priced;
        if (right == known or !sized) std.debug.print("{s}: priced cpu={d:.1} gpu={d:.1} us per eval, {s}, {d:.1}x; measured cpu {d} s cuda {d} s, {d:.1}x\n", .{ deck, q.cpu_us, q.gpu_us, if (on_gpu) "GPU" else "CPU", priced, cpu_s, cuda_s, measured });
        try std.testing.expect(right != known);
        try std.testing.expect(sized);
        decks += 1;
        misses += @intFromBool(known);
    }
    // An empty capture is a broken capture.
    try std.testing.expect(decks > misses);
}

test markerPath {
    var buf: [64]u8 = undefined;
    const Want = struct { knobs: Knobs, prefix: ?[]const u8 };
    for ([_]Want{
        .{ .knobs = .{ .xdg_cache_home = "/x", .home = "/h" }, .prefix = "/x/espice/gpu-jit/" },
        .{ .knobs = .{ .home = "/h" }, .prefix = "/h/.cache/espice/gpu-jit/" },
        .{ .knobs = .{}, .prefix = null },
        // Past the buffer: no marker, not a truncated one.
        .{ .knobs = .{ .home = "/hhhhhhhhhhhhhhhhhhhhhhhhhhhhhhhhhhhhhhhh" }, .prefix = null },
    }) |w| {
        const got = markerPath(&buf, "image", w.knobs);
        const prefix = w.prefix orelse {
            try std.testing.expect(got == null);
            continue;
        };
        try std.testing.expect(std.mem.startsWith(u8, got.?, prefix));
        const hash = got.?[prefix.len..];
        try std.testing.expectEqual(@as(usize, 16), hash.len);
        for (hash) |ch| try std.testing.expect(std.ascii.isHex(ch));
    }
    // The name is keyed on the image bytes.
    var other: [64]u8 = undefined;
    try std.testing.expect(!std.mem.eql(u8, markerPath(&buf, "image", .{ .home = "/h" }).?, markerPath(&other, "imagf", .{ .home = "/h" }).?));
}

test "markWarm marks that image only" {
    // markedWarm, not imageWarm: a build whose SASS fits this card is warm
    // without a marker.
    var tmp = std.testing.tmpDir(.{});
    defer tmp.cleanup();
    var root: [64]u8 = undefined;
    const knobs: Knobs = .{ .xdg_cache_home = try std.fmt.bufPrint(&root, ".zig-cache/tmp/{s}", .{&tmp.sub_path}) };
    try std.testing.expect(!markedWarm("a", knobs));
    markWarm("a", knobs);
    try std.testing.expect(markedWarm("a", knobs));
    try std.testing.expect(!markedWarm("b", knobs));
    // A second mark, with both directories present, is harmless.
    markWarm("a", knobs);
    try std.testing.expect(markedWarm("a", knobs));
}
