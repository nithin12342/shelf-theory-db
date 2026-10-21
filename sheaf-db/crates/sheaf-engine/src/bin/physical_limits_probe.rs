// crates/sheaf-engine/src/bin/physical_limits_probe.rs
// REQ-057 / SPEC-057 / METHOD-052 — von Neumann physical-limits probe.
//
// Purpose: measure the machine's ACTUAL memory-hierarchy and storage limits,
// and print the DERIVED physical floors side by side, so the comparison in
// VON_NEUMANN_LIMITS.md is measured-vs-derived (never claimed).
//
// Sections:
//   A: latency ladder  — dependent pointer chase over growing working sets
//                         (L1 -> L2 -> L3 -> DRAM), ns per dependent load.
//   B: read bandwidth  — streaming read, 1..N threads (true READ bytes/s).
//   C: compute rate    — scalar / AVX2 / AVX-512 f32 FMA, FLOP/s, cache-resident.
//   D: storage         — NVMe random-read latency, sequential read
//                         throughput, fsync floor, write-only floor.
//   E: derived floors  — Landauer, Si propagation, DRAM timing floor,
//                         bandwidth-delay product, machine balance.
//   F: gates           — physics-invariant ordering assertions.
//
// Every perf number is measured on this host at run time (no hardcoded perf
// values; published constants are labelled `const`). Output is machine-
// readable: `key=value` per line. Section E consumes this run's A/B/C
// measurements, so the derived comparison can never drift from the data.

#[path = "shared/phys_derive.rs"]
mod phys_derive;
#[path = "shared/phys_mem.rs"]
mod phys_mem;
#[path = "shared/phys_store.rs"]
mod phys_store;

use phys_mem::{chase_latency_ns, chase_latency_page_spread_ns, read_bandwidth_gbs};
use std::time::Instant;

// ---------------------------------------------------------------------------
// A. Latency ladder
// ---------------------------------------------------------------------------

fn section_a() {
    // The CACHE-TIER latencies are measured in ns, but ns is not a stable
    // quantity here: an L1 hit costs a fixed number of CYCLES, so its
    // nanosecond value tracks the core clock, and this box's clock swings
    // with thermal state and background load. The clock is therefore
    // measured immediately BEFORE and AFTER the sweep, and the ladder is
    // reported in BOTH ns and cycles (cycles = ns x clock). The cycle
    // figure is the stable one; the ns figure is what a latency-sensitive
    // caller actually experiences.
    let (clock_before, _, _) = phys_mem::measure_clock_ghz();

    // Fine sweep across the L1/L2/L3 knees. Each 1 MiB of dense working set
    // adds 256 distinct 4 KiB pages, so the sweep walks the page-table
    // coverage as it walks the cache capacities.
    let sets: [(usize, u64); 22] = [
        (4 << 10, 20_000_000),
        (16 << 10, 20_000_000),
        (32 << 10, 20_000_000),
        (64 << 10, 20_000_000),
        (128 << 10, 20_000_000),
        (256 << 10, 20_000_000),
        (512 << 10, 20_000_000),
        (1 << 20, 20_000_000),
        (2 << 20, 15_000_000),
        (3 << 20, 12_000_000),
        (4 << 20, 10_000_000),
        (5 << 20, 10_000_000),
        (6 << 20, 10_000_000),
        (7 << 20, 10_000_000),
        (8 << 20, 10_000_000),
        (10 << 20, 8_000_000),
        (12 << 20, 8_000_000),
        (16 << 20, 8_000_000),
        (24 << 20, 6_000_000),
        (32 << 20, 5_000_000),
        (64 << 20, 5_000_000),
        (128 << 20, 5_000_000),
    ];
    for (bytes, iters) in sets {
        let ns = chase_latency_ns(bytes, iters);
        println!(
            "A_latency_ns set_kb={} pages_4k={} ns={:.2} cycles={:.2}",
            bytes >> 10,
            bytes / 4096,
            ns,
            ns * clock_before
        );
    }

    let (clock_after, _, _) = phys_mem::measure_clock_ghz();
    println!(
        "A_clock_GHz_before={:.3} A_clock_GHz_after={:.3}",
        clock_before, clock_after
    );

    // TLB penalty, isolated by holding the CACHE footprint constant and
    // varying only the number of distinct 4 KiB pages:
    //   few_pages  -> data packed into few pages  -> TLB resident
    //   many_pages -> same data over many pages    -> TLB missing
    // Same bytes, same dependent-load count, same cache behaviour: the
    // difference IS the page-walk penalty.
    const DATA: usize = 4 << 20; // 4 MiB of data (fits L3, exceeds L2)
    let few = best_of(3, || chase_latency_page_spread_ns(128 << 20, DATA, 64, 3_000_000));
    let many = best_of(3, || chase_latency_page_spread_ns(128 << 20, DATA, 16384, 3_000_000));
    println!(
        "A_tlb_few_pages_64_ns={:.2} A_tlb_many_pages_16384_ns={:.2} A_tlb_penalty_ns={:.2}",
        few,
        many,
        many - few
    );
}

/// Best-of-N helper: the minimum over `reps` measurements is the least
/// contended estimate on a shared box.
fn best_of(reps: usize, mut f: impl FnMut() -> f64) -> f64 {
    let mut best = f64::INFINITY;
    for _ in 0..reps.max(1) {
        let v = f();
        if v < best {
            best = v;
        }
    }
    best
}

// ---------------------------------------------------------------------------
// B. Read bandwidth
// ---------------------------------------------------------------------------

/// Returns (mean 1-thread GB/s, best multi-thread GB/s).
fn section_b() -> (f64, f64) {
    let n = 64 << 20; // 64 Mi elements u64 = 512 MiB
    let buf: Vec<u64> = (0..n).map(|i| i ^ 0x9E37_79B9).collect();

    // 1-thread figure: BEST-of-3 (the machine-balance input must be the
    // least contended single-core number, not an average that the box's
    // background load drags down).
    let one = best_of(3, || {
        let g = read_bandwidth_gbs(&buf, 1);
        println!("B_read_GBps threads=1 gbs={:.2}", g);
        g
    });
    println!("B_read_1t_mean_GBps={:.2}", one);

    let mut best = 0.0f64;
    for t in [2usize, 4, 8] {
        let gbs = best_of(3, || read_bandwidth_gbs(&buf, t));
        println!("B_read_GBps threads={} gbs={:.2}", t, gbs);
        if gbs > best {
            best = gbs;
        }
    }
    (one, best)
}

// ---------------------------------------------------------------------------
// C. Compute rate (cache-resident, so this is the ALUs, not memory)
// ---------------------------------------------------------------------------

/// Returns (best 1-thread GFLOP/s, all-threads GFLOP/s).
fn section_c() -> (f64, f64) {
    // 16 KiB of f32 per operand => L1-resident, so we measure the FMA pipes.
    let n = 4 << 10;
    let a: Vec<f32> = (0..n).map(|i| (i % 17) as f32 * 0.01).collect();
    let b: Vec<f32> = (0..n).map(|i| (i % 13) as f32 * 0.02).collect();
    let c: Vec<f32> = (0..n).map(|i| (i % 11) as f32 * 0.03).collect();
    let iters = 400_000;

    // The clock probe returns (clock_GHz, add_ratio, imul_ratio) and
    // already aggregates its own 15 inner reps by median. The outer loop
    // runs it 3 more times: the CLOCK is taken as the best of the three
    // (the least-contended estimate), but the RATIOS are aggregated by
    // median across the three, because a consistency check should be
    // judged by its typical behaviour, not by the single luckiest run.
    let mut clock_ghz = 0.0f64;
    let mut add_ratios: Vec<f64> = Vec::new();
    let mut imul_ratios: Vec<f64> = Vec::new();
    for _ in 0..3 {
        let (c, r, i) = phys_mem::measure_clock_ghz();
        if c > clock_ghz {
            clock_ghz = c;
        }
        add_ratios.push(r);
        imul_ratios.push(i);
    }
    let median = |mut v: Vec<f64>| -> f64 {
        v.sort_by(|a, b| a.partial_cmp(b).unwrap());
        v[v.len() / 2]
    };
    let implied_ratio = median(add_ratios);
    let imul_ratio = median(imul_ratios);

    println!("C_clock_GHz={:.3}", clock_ghz);
    // Cross-check 1: the long chain runs 8 dependent adds per iteration
    // and the short chain 4, so their cycle ratio must be exactly 2.0.
    println!(
        "C_clock_crosscheck_add_ratio={:.3} (const expected=2.000)",
        implied_ratio
    );
    // Cross-check 2 (validates the ABSOLUTE cycle count): the chain uses
    // `imul r64, r64, imm32`, which has 3-cycle latency on this core
    // class, so 4 of them cost 12 cycles against the add chain's 4 =>
    // the expected ratio is 3.0. (An early version of this probe read
    // ~4.0 because the chain set was measured across a drifting clock;
    // the adjacent-pair median fixed the measurement, and the
    // expectation was then confirmed rather than assumed.)
    println!(
        "C_clock_crosscheck_imul_ratio={:.3} (const expected=3.000)",
        imul_ratio
    );
    println!(
        "C_clock_crosscheck_ok={}",
        if (implied_ratio - 2.0).abs() < 0.20 && (imul_ratio - 3.0).abs() < 0.30 {
            "PASS"
        } else {
            "FAIL"
        }
    );

    let mut best = 0.0f64;
    let mut best_label = "scalar";

    {
        let g = best_of(3, || {
            let t0 = Instant::now();
            let fl = phys_mem::flops_scalar(&a, &b, &c, iters);
            fl / t0.elapsed().as_secs_f64() / 1e9
        });
        println!("C_flops scalar gflops={:.2}", g);
        if g > best {
            best = g;
            best_label = "scalar";
        }
    }

    #[cfg(target_arch = "x86_64")]
    {
        if is_x86_feature_detected!("avx2") {
            let g = best_of(3, || {
                let t0 = Instant::now();
                let fl = unsafe { phys_mem::simd::flops_avx2(&a, &b, &c, iters) };
                fl / t0.elapsed().as_secs_f64() / 1e9
            });
            println!("C_flops avx2 gflops={:.2}", g);
            if g > best {
                best = g;
                best_label = "avx2";
            }
        }
        if is_x86_feature_detected!("avx512f") {
            let g = best_of(3, || {
                let t0 = Instant::now();
                let fl = unsafe { phys_mem::simd::flops_avx512(&a, &b, &c, iters) };
                fl / t0.elapsed().as_secs_f64() / 1e9
            });
            println!("C_flops avx512 gflops={:.2}", g);
            if g > best {
                best = g;
                best_label = "avx512";
            }
        }
    }
    println!(
        "C_avx512f_present={}",
        cfg!(target_arch = "x86_64") && is_x86_feature_detected!("avx512f")
    );
    println!("C_best_path={}", best_label);

    // Theoretical FMA peak for the winning path, at the measured clock.
    // avx512: 16 lanes x 2 FMA units x 2 flops = 64 flops/cycle/core.
    // avx2:    8 lanes x 2 FMA units x 2 flops = 32 flops/cycle/core.
    let flops_per_cycle = match best_label {
        "avx512" => 64.0,
        "avx2" => 32.0,
        _ => 4.0, // scalar SSE: 4 lanes x 1 mul + 1 add = 4 flops/cycle
    };
    println!(
        "C_theoretical_1core_gflops={:.2} (const flops_per_cycle={} x clock_GHz={:.3})",
        flops_per_cycle * clock_ghz,
        flops_per_cycle,
        clock_ghz
    );

    // All-threads: replicate the winning single-thread path per physical core.
    let cores = 4usize; // physical cores on this host
    let all_gflops = best_of(3, || {
        let a2 = a.clone();
        let b2 = b.clone();
        let c2 = c.clone();
        let t0 = Instant::now();
        let parts: Vec<f64> = std::thread::scope(|s| {
            let mut handles = Vec::with_capacity(cores);
            for _ in 0..cores {
                let a3 = a2.clone();
                let b3 = b2.clone();
                let c3 = c2.clone();
                handles.push(s.spawn(move || match best_label {
                    "avx512" => unsafe { phys_mem::simd::flops_avx512(&a3, &b3, &c3, iters / 8) },
                    "avx2" => unsafe { phys_mem::simd::flops_avx2(&a3, &b3, &c3, iters / 8) },
                    _ => phys_mem::flops_scalar(&a3, &b3, &c3, iters / 8),
                }));
            }
            handles
                .into_iter()
                .map(|h| h.join().unwrap_or(0.0))
                .collect()
        });
        let total: f64 = parts.iter().sum();
        total / t0.elapsed().as_secs_f64() / 1e9
    });
    println!(
        "C_flops_allthreads gflops={:.2} threads={}",
        all_gflops, cores
    );
    (best, all_gflops)
}

// ---------------------------------------------------------------------------
// F. Physics-invariant gates
// ---------------------------------------------------------------------------

/// These are not performance targets — they are ORDERING and IDENTITY
/// constraints that any machine obeying the von Neumann memory hierarchy
/// must satisfy. If one of them fails, the measurement is wrong (or the
/// machine is not what we think it is), so they are asserted rather than
/// reported.
///
/// G1 L1 < L2 < L3 < DRAM: the hierarchy is strictly ordered in latency.
/// G2 A DRAM access is strictly more expensive than an L3 access.
/// G3 The DRAM access must EXCEED the DDR4-3200 CAS floor
///    (tRCD + tCL + tRP = 41.2 ns), because the real access also pays
///    the row activation, the bus turnaround and the controller queueing.
///    A number BELOW the floor would mean the measurement is not actually
///    reaching DRAM.
/// G4 A page walk must be strictly more expensive than an L3 hit.
/// G5 Read bandwidth must be a meaningful fraction of the DDR4-3200
///    single-channel peak (a stream cannot exceed the bus; a stream
///    reaching <5% would mean we are not measuring the memory system).
/// G6 fsync must be far more expensive than a buffered write of the SAME
///    size (the durability floor exists; if they were equal, sync is a
///    no-op).
fn section_f(
    l1_ns: f64,
    l2_ns: f64,
    l3_ns: f64,
    dram_ns: f64,
    read_gbs: f64,
    write_only_us: f64,
    fsync_us: f64,
) {
    let pass = |b: bool| if b { "PASS" } else { "FAIL" };

    let g1 = l1_ns < l2_ns && l2_ns < l3_ns && l3_ns < dram_ns;
    println!(
        "gate_hierarchy_ordered={} (L1={:.2} L2={:.2} L3={:.2} DRAM={:.2} ns)",
        pass(g1),
        l1_ns,
        l2_ns,
        l3_ns,
        dram_ns
    );

    let g2 = dram_ns > l3_ns;
    println!("gate_dram_slower_than_l3={}", pass(g2));

    let g3 = dram_ns > 41.2;
    println!(
        "gate_dram_above_ddr4_cas_floor={} (measured={:.2} ns > floor=41.20 ns)",
        pass(g3),
        dram_ns
    );

    let g4 = fsync_us > write_only_us * 10.0;
    println!(
        "gate_fsync_floor_exists={} (fsync={:.1} us vs write_only={:.1} us)",
        pass(g4),
        fsync_us,
        write_only_us
    );

    let g5 = read_gbs > 25.6 * 0.05;
    println!(
        "gate_read_bw_significant={} (measured={:.2} GB/s vs 1ch_peak=25.60 GB/s)",
        pass(g5),
        read_gbs
    );

    let g6 = dram_ns > l1_ns;
    println!("gate_dram_slower_than_l1={}", pass(g6));
}

/// Section G: the ROOFLINE PAIR, measured in ONE window.
///
/// The machine balance (FLOP/byte) is a ratio of a compute rate to a
/// bandwidth rate. If those two are measured minutes apart on a
/// thermally-governed laptop whose clock swings by 3x, the ratio is
/// meaningless. This section therefore measures BOTH in the same
/// interleaved pass, so the ridge point is a same-window number.
///
/// It also measures the arithmetic intensity of the repo's own kernel
/// shape (a dense d x d matvec per face), which is the number that
/// decides whether the kernel is memory-bound or compute-bound.
fn section_g() {
    let n = 4 << 10;
    let a: Vec<f32> = (0..n).map(|i| (i % 17) as f32 * 0.01).collect();
    let b: Vec<f32> = (0..n).map(|i| (i % 13) as f32 * 0.02).collect();
    let c: Vec<f32> = (0..n).map(|i| (i % 11) as f32 * 0.03).collect();
    let iters = 400_000;

    // 512 MiB read buffer, 64 Mi u64 elements.
    let buf: Vec<u64> = (0..(64 << 20)).map(|i| i ^ 0x9E37_79B9).collect();

    let mut best_flops = 0.0f64;
    let mut best_bw = 0.0f64;

    // INTERLEAVE: each rep measures bandwidth then compute, back to back.
    for _ in 0..3 {
        let bw = phys_mem::read_bandwidth_gbs(&buf, 1);
        if bw > best_bw {
            best_bw = bw;
        }
        let t0 = Instant::now();
        #[cfg(target_arch = "x86_64")]
        let fl = unsafe {
            if is_x86_feature_detected!("avx512f") {
                phys_mem::simd::flops_avx512(&a, &b, &c, iters)
            } else {
                phys_mem::simd::flops_avx2(&a, &b, &c, iters)
            }
        };
        #[cfg(not(target_arch = "x86_64"))]
        let fl = phys_mem::flops_scalar(&a, &b, &c, iters);
        let g = fl / t0.elapsed().as_secs_f64() / 1e9;
        if g > best_flops {
            best_flops = g;
        }
    }

    println!("G_same_window_read_GBps={:.2}", best_bw);
    println!("G_same_window_gflops={:.2}", best_flops);
    println!(
        "G_same_window_machine_balance_flop_per_byte={:.3}",
        best_flops / best_bw
    );

    // Arithmetic intensity of the repo's own kernel shape.
    // A dense d x d matvec reads d*d weights + d inputs and does d*d FMAs
    // (2*d*d flops). With f32 data the intensity is:
    //   2*d*d flops / (4*(d*d + d) bytes)  =  d*d / (2*(d*d + d))
    for d in [2usize, 4, 8, 16] {
        let flops = 2.0 * (d * d) as f64;
        let bytes = 4.0 * ((d * d + d) as f64);
        let intensity = flops / bytes;
        println!(
            "G_kernel_intensity_flop_per_byte d={} intensity={:.3} memory_bound_vs_measured_ridge={}",
            d,
            intensity,
            if intensity < best_flops / best_bw {
                "YES"
            } else {
                "NO"
            }
        );
    }
}

fn main() {
    let arg = std::env::args().nth(1).unwrap_or_default();
    let run = |name: &str| arg.is_empty() || arg == name;

    let mut read_gbs_1t = 0.0f64;
    let mut read_gbs_all = 0.0f64;
    let mut gflops_1t = 0.0f64;
    let mut gflops_all = 0.0f64;
    let mut seq_gbs = 0.0f64;
    let mut rand_us = 0.0f64;
    let mut write_only_us = 0.0f64;
    let mut fsync_us = 0.0f64;

    if run("A") {
        section_a();
    }
    if run("B") {
        let (g1, gall) = section_b();
        read_gbs_1t = g1;
        read_gbs_all = gall;
    }
    if run("C") {
        let (g1, gall) = section_c();
        gflops_1t = g1;
        gflops_all = gall;
    }
    if run("D") {
        let (s, r, w, f) = phys_store::measure_storage();
        seq_gbs = s;
        rand_us = r;
        write_only_us = w;
        fsync_us = f;
    }
    if run("E") {
        // Re-measure the DRAM tier here so E is fed by a value from this run.
        let dram_bytes = 128 << 20;
        let dram_ns = chase_latency_ns(dram_bytes, 5_000_000);
        println!(
            "E_recheck_dram_latency_ns={:.2} set_mb={}",
            dram_ns,
            dram_bytes >> 20
        );
        phys_derive::section_e(
            dram_ns,
            read_gbs_1t,
            read_gbs_all,
            gflops_1t,
            gflops_all,
            seq_gbs,
            rand_us,
        );
    }
    if run("F") {
        // Representative tier latencies for the ordering gates.
        let l1_ns = chase_latency_ns(32 << 10, 20_000_000);
        let l2_ns = chase_latency_ns(128 << 10, 20_000_000);
        let l3_ns = chase_latency_ns(4 << 20, 10_000_000);
        let dram_ns = chase_latency_ns(128 << 20, 5_000_000);
        section_f(
            l1_ns,
            l2_ns,
            l3_ns,
            dram_ns,
            read_gbs_1t,
            write_only_us,
            fsync_us,
        );
    }
    if run("G") {
        section_g();
    }
    println!("PHYSICAL-LIMITS-PROBE: COMPLETE");
}
