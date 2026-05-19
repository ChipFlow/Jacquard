// SPDX-FileCopyrightText: Copyright (c) 2024 NVIDIA CORPORATION & AFFILIATES. All rights reserved.
// SPDX-License-Identifier: Apache-2.0
//! Unified CLI for the Jacquard GPU-accelerated RTL simulator.

use std::path::PathBuf;

use clap::{Parser, Subcommand};
use jacquard::sim::setup::DesignArgs;

/// `--timing-report` / `--timing-summary` plumbing for GPU sim entry
/// points. The report is built whenever either flag is requested; the
/// flags then choose whether to write JSON, print text, or both.
#[cfg(feature = "metal")]
struct TimingReportConfig<'a> {
    json_path: Option<&'a std::path::Path>,
    text_summary: bool,
    /// Per-cycle violations cap. `None` = unbounded, `Some(n)` = cap.
    max_violations: Option<usize>,
    metadata: jacquard::timing_report::RunMetadata,
}

#[cfg(feature = "metal")]
impl TimingReportConfig<'_> {
    fn requested(&self) -> bool {
        self.json_path.is_some() || self.text_summary
    }
}

#[derive(Parser)]
#[command(
    name = "jacquard",
    about = "Jacquard — GPU-accelerated RTL logic simulator"
)]
struct Cli {
    #[command(subcommand)]
    command: Commands,
}

#[derive(Subcommand)]
enum Commands {
    /// Run a GPU simulation with VCD input/output.
    ///
    /// Reads a gate-level netlist, partitions it automatically, processes a VCD
    /// input waveform through the GPU simulator, and writes the output VCD.
    /// Requires building with `--features metal` (macOS), `--features cuda` (Linux/NVIDIA),
    /// or `--features hip` (Linux/AMD).
    Sim(SimArgs),

    /// Run a GPU co-simulation with SPI flash and UART models (Metal only).
    ///
    /// Reads a gate-level netlist and testbench configuration JSON, then runs
    /// a cycle-accurate co-simulation with GPU-side SPI flash and UART models.
    /// Requires building with `--features metal`.
    Cosim(CosimArgs),

    /// Dump AIG critical paths with timing details.
    ///
    /// Analyzes the AIG timing and shows the critical paths from source to sink,
    /// including cell origins (synthesis cells), gate delays, and cumulative arrivals.
    DumpPaths(DumpPathsArgs),
}

#[derive(Parser)]
struct SimArgs {
    /// Gate-level Verilog path synthesized with AIGPDK, SKY130, or GF180MCU.
    netlist_verilog: PathBuf,

    /// VCD input signal path.
    input_vcd: String,

    /// Output VCD path (must be writable).
    output_vcd: String,

    /// Number of GPU blocks to use.
    ///
    /// For CUDA: set to 2x the number of GPU SMs.
    /// For Metal: set to 1.
    num_blocks: usize,

    /// Top module name in the netlist.
    #[clap(long)]
    top_module: Option<String>,

    /// Level split thresholds (must match values used during mapping).
    #[clap(long, value_delimiter = ',')]
    level_split: Vec<usize>,

    /// The scope path of top module in the input VCD.
    #[clap(long)]
    input_vcd_scope: Option<String>,

    /// The scope path of top module in the output VCD.
    #[clap(long)]
    output_vcd_scope: Option<String>,

    /// Verify GPU results against CPU baseline.
    #[clap(long)]
    check_with_cpu: bool,

    /// Limit the number of simulated clock edges. One full clock cycle =
    /// 2 edges (posedge + negedge) for single-domain. Matches chipflow
    /// cxxrtl `num_steps` 1:1.
    #[clap(long)]
    max_clock_edges: Option<usize>,

    /// JSON file path for extracting display format strings.
    #[clap(long)]
    json_path: Option<PathBuf>,

    /// Path to SDF file for per-instance back-annotated delays.
    #[clap(long, conflicts_with = "timing_ir")]
    sdf: Option<PathBuf>,

    /// SDF corner selection: min, typ, or max.
    #[clap(long, default_value = "typ")]
    sdf_corner: String,

    /// Enable SDF debug output.
    #[clap(long)]
    sdf_debug: bool,

    /// Path to a user-supplied Verilog cell library. Repeatable. Each
    /// file is parsed at startup; modules found in it become known to
    /// the netlist reader without vendoring. If a sibling
    /// `<file>.cells.toml` manifest is present, its per-cell `kind`
    /// annotations are loaded automatically. See ADR 0010 and
    /// `docs/plans/declarative-cell-metadata.md`.
    #[clap(long = "cell-library", value_name = "PATH")]
    cell_library: Vec<PathBuf>,

    /// Path to a Jacquard timing-IR (.jtir) file. Generate with the
    /// `opensta-to-ir` preprocessing tool. Mutually exclusive with `--sdf`.
    #[clap(long)]
    timing_ir: Option<PathBuf>,

    /// Enable selective X-propagation.
    ///
    /// Tracks unknown (X) values through DFF and SRAM outputs. Only partitions
    /// containing X-capable signals pay the overhead. X values appear in the
    /// output VCD as 'x'.
    #[clap(long)]
    xprop: bool,

    /// Enable timing analysis after simulation.
    #[clap(long)]
    enable_timing: bool,

    /// Clock period in picoseconds for timing analysis.
    #[clap(long, default_value = "1000")]
    timing_clock_period: u64,

    /// Report all timing violations (not just summary).
    #[clap(long)]
    timing_report_violations: bool,

    /// Path to Liberty library file for timing data.
    #[clap(long)]
    liberty: Option<PathBuf>,

    /// Enable timing-accurate VCD output with per-signal arrival times.
    ///
    /// Requires --sdf. Signal transitions in the output VCD are offset from
    /// clock edges by their computed arrival times rather than placed at the
    /// clock edge.
    #[clap(long)]
    timing_vcd: bool,

    /// Write a structured JSON timing report to <PATH> at end of run.
    /// Schema documented in `src/timing_report.rs` and ADR 0008.
    #[clap(long)]
    timing_report: Option<PathBuf>,

    /// Print a human-readable text summary at end of run. Independent
    /// of `--timing-report`; both may be combined. Format is for human
    /// inspection — not a stable parseable contract; consumers that
    /// need to script against it should use `--timing-report` JSON.
    #[clap(long)]
    timing_summary: bool,

    /// Cap the per-cycle violations list in `--timing-report`. Defaults
    /// to 100k records (~8 MB JSON). Pass `0` for unbounded — risky on
    /// long violation-storm runs. Setup/hold totals and worst-slack
    /// rankings always reflect every observed event regardless of cap.
    #[clap(long)]
    timing_report_max_violations: Option<usize>,

    /// Select a specific PVT corner from the timing IR by name.
    /// Defaults to corner index 0 (first declared) when unset. Required
    /// when the IR carries multiple corners and the first isn't the
    /// intended one.
    #[clap(long)]
    timing_corner: Option<String>,
}

#[derive(Parser)]
struct CosimArgs {
    /// Gate-level Verilog path synthesized with AIGPDK, SKY130, or GF180MCU.
    netlist_verilog: PathBuf,

    /// Testbench configuration JSON file.
    #[clap(long)]
    config: PathBuf,

    /// Top module name in the netlist.
    #[clap(long)]
    top_module: Option<String>,

    /// Level split thresholds (comma-separated).
    #[clap(long, value_delimiter = ',')]
    level_split: Vec<usize>,

    /// Number of GPU threadgroups (blocks).
    #[clap(long, default_value = "64")]
    num_blocks: usize,

    /// Limit the number of simulated clock edges. One full clock cycle =
    /// 2 edges (posedge + negedge) for single-domain. Matches chipflow
    /// cxxrtl `num_steps` 1:1.
    #[clap(long)]
    max_clock_edges: Option<usize>,

    /// Enable verbose flash model debug output.
    #[clap(long)]
    flash_verbose: bool,

    /// Clock period in picoseconds.
    #[clap(long)]
    clock_period: Option<u64>,

    /// Verify GPU results against CPU baseline.
    #[clap(long)]
    check_with_cpu: bool,

    /// Run GPU kernel profiling.
    #[clap(long)]
    gpu_profile: bool,

    /// Path to a Jacquard timing-IR (.jtir) file. Generate with the
    /// `opensta-to-ir` preprocessing tool.
    ///
    /// Cosim does not currently accept raw SDF — pre-convert with
    /// `opensta-to-ir` and pass the IR. Adding a subprocess wrapper to
    /// cosim (matching `jacquard sim --sdf`) is tracked as a follow-up
    /// in `docs/plans/post-phase-0-roadmap.md`; not release-gating.
    #[clap(long)]
    timing_ir: Option<PathBuf>,

    /// Path to write stimulus VCD (all primary inputs driven by cosim).
    /// Forces single-tick mode for accurate per-cycle capture.
    #[clap(long)]
    stimulus_vcd: Option<PathBuf>,

    /// Enable timing-accurate VCD output with per-signal arrival times.
    ///
    /// Requires `--timing-ir`. Signal transitions in the output VCD are
    /// offset from clock edges by their computed arrival times. Forces
    /// single-tick mode.
    #[clap(long)]
    timing_vcd: Option<PathBuf>,

    /// Dump all DFF Q-values per cycle to a text file for debugging.
    /// Forces single-tick mode for the specified number of cycles (default 20).
    #[clap(long)]
    dump_dff: Option<PathBuf>,

    /// Number of cycles to dump DFF states for (used with --dump-dff).
    #[clap(long, default_value = "20")]
    dump_dff_cycles: usize,

    /// Path to a user-supplied Verilog cell library. Repeatable. See
    /// `jacquard sim --help` and ADR 0010 for details.
    #[clap(long = "cell-library", value_name = "PATH")]
    cell_library: Vec<PathBuf>,
}

#[derive(Parser)]
struct DumpPathsArgs {
    /// Gate-level Verilog path synthesized with AIGPDK, SKY130, or GF180MCU.
    netlist_verilog: PathBuf,

    /// Top module name in the netlist.
    #[clap(long)]
    top_module: Option<String>,

    /// Level split thresholds (must match values used during mapping).
    #[clap(long, value_delimiter = ',')]
    level_split: Vec<usize>,

    /// Path to Liberty library file for timing data.
    #[clap(long)]
    liberty: Option<PathBuf>,

    /// Clock period in picoseconds for timing analysis.
    #[clap(long, default_value = "1000")]
    clock_period: u64,

    /// Path to SDF file for per-instance back-annotated delays.
    #[clap(long, conflicts_with = "timing_ir")]
    sdf: Option<PathBuf>,

    /// SDF corner selection: min, typ, or max.
    #[clap(long, default_value = "typ")]
    sdf_corner: String,

    /// Path to a Jacquard timing-IR (.jtir) file. Generate with the
    /// `opensta-to-ir` preprocessing tool. Mutually exclusive with `--sdf`.
    #[clap(long)]
    timing_ir: Option<PathBuf>,

    /// Number of critical paths to dump (default: 5).
    #[clap(long, default_value = "5")]
    limit: usize,
}

#[allow(unused_variables)]
fn cmd_sim(args: SimArgs) {
    use jacquard::sim::setup;
    use jacquard::sim::vcd_io;

    let design_args = DesignArgs {
        netlist_verilog: args.netlist_verilog.clone(),
        top_module: args.top_module.clone(),
        level_split: args.level_split.clone(),
        num_blocks: args.num_blocks,
        json_path: args.json_path.clone(),
        sdf: args.sdf.clone(),
        sdf_corner: args.sdf_corner.clone(),
        sdf_debug: args.sdf_debug,
        clock_period_ps: None,
        xprop: args.xprop,
        liberty: args.liberty.clone(),
        timing_ir: args.timing_ir.clone(),
        timing_corner: args.timing_corner.clone(),
        cell_library: args.cell_library.clone(),
    };

    #[allow(unused_mut)]
    let mut design = setup::load_design(&design_args);

    // Enable timing arrival readback if --timing-vcd is set
    if args.timing_vcd {
        if args.sdf.is_none() && args.liberty.is_none() {
            eprintln!("Error: --timing-vcd requires --sdf or --liberty");
            std::process::exit(1);
        }
        design.script.enable_timing_arrivals();
    }

    let timing_constraints = setup::build_timing_constraints(&design.script);

    // Parse input VCD
    let input_vcd = std::fs::File::open(&args.input_vcd).unwrap();
    let mut bufrd = std::io::BufReader::with_capacity(65536, input_vcd);
    let header = {
        let mut vcd_parser = vcd_ng::Parser::new(&mut bufrd);
        vcd_parser.parse_header().unwrap()
    };
    use std::io::{Seek, SeekFrom};
    let mut vcd_file = bufrd.into_inner();
    vcd_file.seek(SeekFrom::Start(0)).unwrap();
    let mut vcdflow = vcd_ng::FastFlow::new(vcd_file, 65536);

    // Resolve VCD scope
    let top_scope = vcd_io::resolve_vcd_scope(
        &header.items[..],
        args.input_vcd_scope.as_deref(),
        &design.netlistdb,
        args.top_module.as_deref(),
    );

    // Match VCD inputs to netlist ports
    let (vcd2inp, _) = vcd_io::match_vcd_inputs(top_scope, &design.netlistdb);

    // Parse input VCD into state vectors
    let parsed = vcd_io::parse_input_vcd(
        &mut vcdflow,
        &vcd2inp,
        &design.aig,
        &design.script,
        &design.netlistdb,
        args.max_clock_edges,
    );

    // Set up output VCD writer
    let write_buf = std::fs::File::create(&args.output_vcd).unwrap();
    let write_buf = std::io::BufWriter::new(write_buf);
    let mut writer = vcd_ng::Writer::new(write_buf);
    let output_mapping = vcd_io::setup_output_vcd(
        &mut writer,
        &header,
        args.output_vcd_scope.as_deref(),
        &design.netlistdb,
        &design.aig,
        &design.script,
    );

    // GPU dispatch
    let input_states = parsed.input_states;
    let offsets_timestamps = parsed.offsets_timestamps;
    let num_cycles = offsets_timestamps.len();

    #[cfg(not(any(feature = "metal", feature = "cuda", feature = "hip")))]
    {
        eprintln!(
            "jacquard sim requires GPU support. Build with:\n\
             \n  cargo build -r --features metal --bin jacquard   (macOS)\n\
             \n  cargo build -r --features cuda --bin jacquard    (Linux/NVIDIA)\n\
             \n  cargo build -r --features hip --bin jacquard     (Linux/AMD)\n"
        );
        std::process::exit(1);
    }

    #[cfg(feature = "metal")]
    let report_cfg = TimingReportConfig {
        json_path: args.timing_report.as_deref(),
        text_summary: args.timing_summary,
        // Translate the CLI sentinel: unset → use builder default,
        // `Some(0)` → unbounded (None), `Some(n)` → cap at n.
        max_violations: match args.timing_report_max_violations {
            None => Some(jacquard::timing_report::DEFAULT_MAX_VIOLATIONS),
            Some(0) => None,
            Some(n) => Some(n),
        },
        metadata: jacquard::timing_report::RunMetadata {
            design: args
                .netlist_verilog
                .file_name()
                .and_then(|s| s.to_str())
                .map(String::from),
            vector_source: std::path::Path::new(&args.input_vcd)
                .file_name()
                .and_then(|s| s.to_str())
                .map(String::from),
            timing_source: args
                .timing_ir
                .as_deref()
                .or(args.sdf.as_deref())
                .and_then(|p| p.file_name())
                .and_then(|s| s.to_str())
                .map(String::from),
            clock_period_ps: design.script.clock_period_ps,
            cycles_run: 0,
            jacquard_version: env!("CARGO_PKG_VERSION").to_string(),
        },
    };

    #[cfg(feature = "metal")]
    let gpu_states = {
        sim_metal(
            &design,
            &input_states,
            &offsets_timestamps,
            &timing_constraints,
            &report_cfg,
        )
    };

    #[cfg(all(feature = "cuda", not(feature = "metal")))]
    let gpu_states = {
        sim_cuda(
            &design,
            &input_states,
            &offsets_timestamps,
            &timing_constraints,
        )
    };

    #[cfg(all(feature = "hip", not(feature = "metal"), not(feature = "cuda")))]
    let gpu_states = {
        sim_hip(
            &design,
            &input_states,
            &offsets_timestamps,
            &timing_constraints,
        )
    };

    // CPU sanity check
    #[cfg(any(feature = "metal", feature = "cuda", feature = "hip"))]
    if args.check_with_cpu {
        if design.script.xprop_enabled {
            let rio = design.script.reg_io_state_size as usize;
            // When timing arrivals are enabled, effective size is 3*rio instead of 2*rio.
            // Extract values and xmasks manually using the actual effective size.
            let eff = design.script.effective_state_size() as usize;
            let num_snapshots = gpu_states.len() / eff;
            let mut gpu_values_vec = Vec::with_capacity(num_snapshots * rio);
            let mut gpu_xmasks_vec = Vec::with_capacity(num_snapshots * rio);
            for snap_i in 0..num_snapshots {
                let base = snap_i * eff;
                gpu_values_vec.extend_from_slice(&gpu_states[base..base + rio]);
                gpu_xmasks_vec.extend_from_slice(&gpu_states[base + rio..base + 2 * rio]);
            }
            let (gpu_values, gpu_xmasks) = (gpu_values_vec, gpu_xmasks_vec);
            // Build input X-masks: same initial template as expand_states_for_xprop
            let num_input_snaps = input_states.len() / rio;
            let mut xmask_template = vec![0xFFFF_FFFFu32; rio];
            for &pos in design.script.input_map.values() {
                xmask_template[(pos >> 5) as usize] &= !(1u32 << (pos & 31));
            }
            let mut input_xmasks = Vec::with_capacity(num_input_snaps * rio);
            for _ in 0..num_input_snaps {
                input_xmasks.extend_from_slice(&xmask_template);
            }
            jacquard::sim::cpu_reference::sanity_check_cpu_xprop(
                &design.script,
                &input_states,
                &gpu_values,
                &input_xmasks,
                &gpu_xmasks,
                num_cycles,
            );
        } else if design.script.timing_arrivals_enabled {
            // Extract value-only states for CPU comparison
            let rio = design.script.reg_io_state_size as usize;
            let eff = design.script.effective_state_size() as usize;
            let num_snapshots = gpu_states.len() / eff;
            let mut values = Vec::with_capacity(num_snapshots * rio);
            for snap_i in 0..num_snapshots {
                values.extend_from_slice(&gpu_states[snap_i * eff..snap_i * eff + rio]);
            }
            jacquard::sim::cpu_reference::sanity_check_cpu(
                &design.script,
                &input_states,
                &values,
                num_cycles,
            );
        } else {
            jacquard::sim::cpu_reference::sanity_check_cpu(
                &design.script,
                &input_states,
                &gpu_states[..],
                num_cycles,
            );
        }
    }

    // Post-simulation timing analysis
    #[cfg(any(feature = "metal", feature = "cuda", feature = "hip"))]
    if args.enable_timing {
        run_timing_analysis(&mut design.aig, &args);
    }

    // Write output VCD
    #[cfg(any(feature = "metal", feature = "cuda", feature = "hip"))]
    if args.timing_vcd && design.script.timing_arrivals_enabled {
        // Timed VCD: extract arrivals and use timed writer
        let rio = design.script.reg_io_state_size as usize;
        let arrival_states = vcd_io::split_arrival_states(&gpu_states[..], &design.script);
        // Debug: show arrival statistics
        let nonzero_count = arrival_states.iter().filter(|&&v| v != 0).count();
        clilog::info!(
            "Arrival states: {} total, {} non-zero",
            arrival_states.len(),
            nonzero_count
        );
        let xmask_states = if design.script.xprop_enabled {
            let eff = design.script.effective_state_size() as usize;
            let num_snapshots = gpu_states.len() / eff;
            let mut xmasks = Vec::with_capacity(num_snapshots * rio);
            for snap_i in 0..num_snapshots {
                let base = snap_i * eff + rio;
                xmasks.extend_from_slice(&gpu_states[base..base + rio]);
            }
            Some(xmasks)
        } else {
            None
        };
        // Extract value-only states (same as split_xprop but works for any layout)
        let eff = design.script.effective_state_size() as usize;
        let num_snapshots = gpu_states.len() / eff;
        let mut values = Vec::with_capacity(num_snapshots * rio);
        for snap_i in 0..num_snapshots {
            let base = snap_i * eff;
            values.extend_from_slice(&gpu_states[base..base + rio]);
        }
        vcd_io::write_output_vcd_timed(
            &mut writer,
            &output_mapping,
            &offsets_timestamps,
            &values,
            xmask_states.as_deref(),
            &arrival_states,
            header.timescale,
        );
    } else if design.script.xprop_enabled {
        let rio = design.script.reg_io_state_size as usize;
        let (values, xmasks) = vcd_io::split_xprop_states(&gpu_states[..], rio);
        vcd_io::write_output_vcd_xprop(
            &mut writer,
            &output_mapping,
            &offsets_timestamps,
            &values,
            &xmasks,
        );

        // X-propagation report: count X bits at primary outputs
        let eff = design.script.effective_state_size() as usize;
        let num_snapshots = gpu_states.len() / eff;
        let mut first_x_free_cycle: Option<usize> = None;
        for snap_i in 1..num_snapshots {
            let xmask_base = snap_i * eff + rio;
            let mut has_x = false;
            for &(_aigpin, pos, _vid) in &output_mapping.out2vcd {
                if pos == u32::MAX {
                    continue;
                }
                let x = gpu_states[xmask_base + (pos >> 5) as usize] >> (pos & 31) & 1;
                if x != 0 {
                    has_x = true;
                    break;
                }
            }
            if !has_x && first_x_free_cycle.is_none() {
                first_x_free_cycle = Some(snap_i - 1);
            }
        }
        if let Some(cycle) = first_x_free_cycle {
            clilog::info!("All primary outputs X-free at cycle {}", cycle);
        } else if num_snapshots > 1 {
            clilog::warn!(
                "Primary outputs still have X values at final cycle {}",
                num_snapshots - 2
            );
        }
    } else {
        vcd_io::write_output_vcd(
            &mut writer,
            &output_mapping,
            &offsets_timestamps,
            &gpu_states[..],
        );
    }
}

#[cfg(feature = "metal")]
fn sim_metal(
    design: &jacquard::sim::setup::LoadedDesign,
    input_states: &[u32],
    offsets_timestamps: &[(usize, u64)],
    timing_constraints: &Option<Vec<u32>>,
    report_cfg: &TimingReportConfig<'_>,
) -> Vec<u32> {
    use jacquard::aig::SimControlType;
    use jacquard::display::format_display_message;
    use jacquard::event_buffer::{
        process_events, AssertConfig, EventBuffer, EventType, ReportingCtx, SimControl, SimStats,
        MAX_EVENTS,
    };
    use jacquard::timing_report::{ReportBuilder, ReportStats};
    use metal::{Device as MTLDevice, MTLResourceOptions, MTLSize};
    use ulib::{AsUPtr, AsUPtrMut, Device, UVec};

    let script = &design.script;

    // WS-P1.1.a: symbol map for violation messages.
    let word_symbol_map = script.build_word_symbol_map(&design.netlistdb);
    if let Some(ref m) = word_symbol_map {
        clilog::info!(
            "Symbolic violation messages enabled: {} DFF sites across {} state words",
            m.num_sites(),
            m.num_words()
        );
    }

    // Top-N for worst-slack ranking; small constant per ADR 0008 § 4.
    const WORST_SLACK_TOP_N: usize = 10;
    let mut report_builder = report_cfg.requested().then(|| {
        ReportBuilder::new(
            report_cfg.metadata.clone(),
            WORST_SLACK_TOP_N,
            report_cfg.max_violations,
        )
    });

    // Initialize Metal
    let mtl_device = MTLDevice::system_default().expect("No Metal device found");
    clilog::info!("Using Metal device: {}", mtl_device.name());

    let metallib_path = env!("METALLIB_PATH");
    let library = mtl_device
        .new_library_with_file(metallib_path)
        .expect("Failed to load metallib");
    let kernel_function = library
        .get_function("simulate_v1_stage", None)
        .expect("Failed to get kernel function");
    let pipeline_state = mtl_device
        .new_compute_pipeline_state_with_function(&kernel_function)
        .expect("Failed to create pipeline state");
    let command_queue = mtl_device.new_command_queue();

    let device = Device::Metal(0);
    let num_cycles = offsets_timestamps.len();

    // When xprop is enabled, expand the value-only state buffer to include X-mask
    let mut expanded_states = if script.xprop_enabled {
        jacquard::sim::vcd_io::expand_states_for_xprop(input_states, script)
    } else {
        input_states.to_vec()
    };
    // When timing arrivals are enabled, expand further to include arrival section
    if script.timing_arrivals_enabled {
        expanded_states =
            jacquard::sim::vcd_io::expand_states_for_arrivals(&expanded_states, script);
    }
    let mut input_states_uvec: UVec<_> = expanded_states.into();
    input_states_uvec.as_mut_uptr(device);
    let mut sram_storage: UVec<u32> = UVec::new_zeroed(script.sram_storage_size as usize, device);
    // SRAM X-mask shadow: all 0xFFFFFFFF (unknown) initially when xprop enabled
    let sram_xmask_size = if script.xprop_enabled {
        script.sram_storage_size as usize
    } else {
        1 // Metal requires non-zero buffer; kernel checks is_x_capable before reading
    };
    let mut sram_xmask: UVec<u32> = if script.xprop_enabled {
        // Build on CPU then transfer to GPU — UVec::new_filled() doesn't support Metal/CUDA devices
        let v: UVec<u32> = vec![0xFFFF_FFFFu32; sram_xmask_size].into();
        v
    } else {
        UVec::new_zeroed(sram_xmask_size, device)
    };

    // Get Metal buffer pointers
    let blocks_start_ptr = script.blocks_start.as_uptr(device);
    let blocks_data_ptr = script.blocks_data.as_uptr(device);
    let sram_data_ptr = sram_storage.as_mut_uptr(device);
    let sram_xmask_ptr = sram_xmask.as_mut_uptr(device);
    let states_ptr = input_states_uvec.as_mut_uptr(device);

    let blocks_start_buffer = mtl_device.new_buffer_with_bytes_no_copy(
        blocks_start_ptr as *const _,
        (script.blocks_start.len() * std::mem::size_of::<usize>()) as u64,
        MTLResourceOptions::StorageModeShared,
        None,
    );
    let blocks_data_buffer = mtl_device.new_buffer_with_bytes_no_copy(
        blocks_data_ptr as *const _,
        (script.blocks_data.len() * std::mem::size_of::<u32>()) as u64,
        MTLResourceOptions::StorageModeShared,
        None,
    );
    let sram_data_buffer = mtl_device.new_buffer_with_bytes_no_copy(
        sram_data_ptr as *mut _ as *const _,
        (sram_storage.len() * std::mem::size_of::<u32>()) as u64,
        MTLResourceOptions::StorageModeShared,
        None,
    );
    let states_buffer = mtl_device.new_buffer_with_bytes_no_copy(
        states_ptr as *mut _ as *const _,
        (input_states_uvec.len() * std::mem::size_of::<u32>()) as u64,
        MTLResourceOptions::StorageModeShared,
        None,
    );
    let sram_xmask_buffer = mtl_device.new_buffer_with_bytes_no_copy(
        sram_xmask_ptr as *mut _ as *const _,
        (sram_xmask.len() * std::mem::size_of::<u32>()) as u64,
        MTLResourceOptions::StorageModeShared,
        None,
    );

    // Event buffer
    let event_buffer = Box::new(EventBuffer::new());
    let event_buffer_ptr = Box::into_raw(event_buffer);
    let event_buffer_metal = mtl_device.new_buffer_with_bytes_no_copy(
        event_buffer_ptr as *const _,
        std::mem::size_of::<EventBuffer>() as u64,
        MTLResourceOptions::StorageModeShared,
        None,
    );

    // Timing constraint buffer (THE GAP FIX)
    let timing_buffer = timing_constraints.as_ref().map(|buf| {
        mtl_device.new_buffer_with_data(
            buf.as_ptr() as *const _,
            (buf.len() * std::mem::size_of::<u32>()) as u64,
            MTLResourceOptions::StorageModeShared,
        )
    });

    #[repr(C)]
    struct SimParams {
        num_blocks: u64,
        num_major_stages: u64,
        num_cycles: u64,
        state_size: u64,
        current_cycle: u64,
        current_stage: u64,
        arrival_state_offset: u64,
    }

    let assert_config = AssertConfig::default();
    let mut sim_stats = SimStats::default();
    let mut cycles_completed = 0;
    let mut final_control = SimControl::Continue;

    let timer_sim = clilog::stimer!("simulation");

    // Resolver lives across all cycles; capturing word_symbol_map by ref.
    let word_resolver = word_symbol_map
        .as_ref()
        .map(|m| move |word_id: u32| m.describe_word(word_id, 4));

    for cycle_i in 0..num_cycles {
        unsafe {
            (*event_buffer_ptr).reset();
        }

        for stage_i in 0..script.num_major_stages {
            let params = SimParams {
                num_blocks: script.num_blocks as u64,
                num_major_stages: script.num_major_stages as u64,
                num_cycles: num_cycles as u64,
                state_size: script.effective_state_size() as u64,
                current_cycle: cycle_i as u64,
                current_stage: stage_i as u64,
                arrival_state_offset: script.arrival_state_offset as u64,
            };

            let params_buffer = mtl_device.new_buffer_with_data(
                &params as *const SimParams as *const _,
                std::mem::size_of::<SimParams>() as u64,
                MTLResourceOptions::StorageModeShared,
            );

            let command_buffer = command_queue.new_command_buffer();
            let encoder = command_buffer.new_compute_command_encoder();

            encoder.set_compute_pipeline_state(&pipeline_state);
            encoder.set_buffer(0, Some(&blocks_start_buffer), 0);
            encoder.set_buffer(1, Some(&blocks_data_buffer), 0);
            encoder.set_buffer(2, Some(&sram_data_buffer), 0);
            encoder.set_buffer(3, Some(&states_buffer), 0);
            encoder.set_buffer(4, Some(&params_buffer), 0);
            encoder.set_buffer(5, Some(&event_buffer_metal), 0);
            // Buffer slot 6: timing constraints (THE GAP FIX)
            encoder.set_buffer(6, timing_buffer.as_ref().map(|v| &**v), 0);
            // Buffer slot 7: SRAM X-mask shadow
            encoder.set_buffer(7, Some(&sram_xmask_buffer), 0);

            let threads_per_threadgroup = MTLSize::new(256, 1, 1);
            let threadgroups = MTLSize::new(script.num_blocks as u64, 1, 1);

            encoder.dispatch_thread_groups(threadgroups, threads_per_threadgroup);
            encoder.end_encoding();

            command_buffer.commit();
            command_buffer.wait_until_completed();
        }

        // Check assertions
        if !script.assertion_positions.is_empty() {
            let states_slice =
                unsafe { std::slice::from_raw_parts(states_ptr, input_states_uvec.len()) };
            let cycle_output_offset = (cycle_i + 1) * script.effective_state_size() as usize;

            for &(cell_id, pos, message_id, control_type) in &script.assertion_positions {
                let word_idx = (pos >> 5) as usize;
                let bit_idx = pos & 31;
                let abs_word_idx = cycle_output_offset + word_idx;
                if abs_word_idx < states_slice.len() {
                    let condition = (states_slice[abs_word_idx] >> bit_idx) & 1;
                    if condition == 1 {
                        let event_type = match control_type {
                            None => EventType::AssertFail,
                            Some(SimControlType::Stop) => EventType::Stop,
                            Some(SimControlType::Finish) => EventType::Finish,
                        };

                        unsafe {
                            let count = (*event_buffer_ptr)
                                .count
                                .fetch_add(1, std::sync::atomic::Ordering::AcqRel)
                                as usize;
                            if count < MAX_EVENTS {
                                let event = &mut (*event_buffer_ptr).events[count];
                                event.event_type = event_type as u32;
                                event.message_id = message_id;
                                event.cycle = cycle_i as u32;
                            }
                        }

                        clilog::debug!(
                            "[cycle {}] Assertion condition fired: cell={}, pos={}, type={:?}",
                            cycle_i,
                            cell_id,
                            pos,
                            control_type
                        );
                    }
                }
            }
        }

        // Check display conditions
        if !script.display_positions.is_empty() {
            let states_slice =
                unsafe { std::slice::from_raw_parts(states_ptr, input_states_uvec.len()) };
            let cycle_output_offset = (cycle_i + 1) * script.effective_state_size() as usize;

            for (cell_id, enable_pos, format, arg_positions, arg_widths) in
                &script.display_positions
            {
                let word_idx = (*enable_pos >> 5) as usize;
                let bit_idx = *enable_pos & 31;
                let abs_word_idx = cycle_output_offset + word_idx;
                if abs_word_idx < states_slice.len() {
                    let enable = (states_slice[abs_word_idx] >> bit_idx) & 1;
                    if enable == 1 {
                        let mut display_args: Vec<u64> = Vec::new();
                        for &arg_pos in arg_positions {
                            let arg_word_idx = (arg_pos >> 5) as usize;
                            let arg_bit_idx = arg_pos & 31;
                            let abs_arg_idx = cycle_output_offset + arg_word_idx;
                            if abs_arg_idx < states_slice.len() {
                                let val = ((states_slice[abs_arg_idx] >> arg_bit_idx) & 1) as u64;
                                display_args.push(val);
                            }
                        }

                        let message = format_display_message(format, &display_args, arg_widths);
                        print!("{}", message);

                        unsafe {
                            let count = (*event_buffer_ptr)
                                .count
                                .fetch_add(1, std::sync::atomic::Ordering::AcqRel)
                                as usize;
                            if count < MAX_EVENTS {
                                let event = &mut (*event_buffer_ptr).events[count];
                                event.event_type = EventType::Display as u32;
                                event.message_id = *cell_id as u32;
                                event.cycle = cycle_i as u32;
                            }
                        }

                        clilog::debug!(
                            "[cycle {}] Display fired: cell={}, format='{}'",
                            cycle_i,
                            cell_id,
                            format
                        );
                    }
                }
            }
        }

        // Process events
        let mut violation_observer_closure = report_builder
            .as_mut()
            .map(|b| move |v: jacquard::timing_report::ViolationRecord| b.observe(v));
        let reporting = ReportingCtx {
            word_resolver: word_resolver.as_ref().map(|f| f as &dyn Fn(u32) -> String),
            violation_observer: violation_observer_closure
                .as_mut()
                .map(|f| f as &mut dyn FnMut(jacquard::timing_report::ViolationRecord)),
        };
        let control = unsafe {
            process_events(
                &*event_buffer_ptr,
                &assert_config,
                &mut sim_stats,
                reporting,
                |msg_id, cycle, _data| {
                    clilog::debug!("[cycle {}] Event processed: message id={}", cycle, msg_id);
                },
            )
        };

        cycles_completed = cycle_i + 1;

        match control {
            SimControl::Continue => {}
            SimControl::Pause => {
                final_control = SimControl::Pause;
            }
            SimControl::Terminate => {
                final_control = SimControl::Terminate;
                break;
            }
        }
    }

    clilog::finish!(timer_sim);

    // Report simulation result
    match final_control {
        SimControl::Continue => {
            clilog::info!("Simulation completed {} cycles", cycles_completed);
        }
        SimControl::Pause => {
            clilog::info!(
                "Simulation paused at cycle {} ($stop encountered)",
                cycles_completed
            );
        }
        SimControl::Terminate => {
            clilog::info!(
                "Simulation terminated at cycle {} ($finish encountered)",
                cycles_completed
            );
        }
    }

    if sim_stats.assertion_failures > 0 {
        clilog::warn!("Total assertion failures: {}", sim_stats.assertion_failures);
    }

    if let Some(builder) = report_builder {
        let stats = ReportStats {
            setup_violations: sim_stats.setup_violations,
            hold_violations: sim_stats.hold_violations,
            events_dropped: sim_stats.events_dropped,
            // `violations_truncated` is filled in by builder.finalize().
            violations_truncated: 0,
        };
        let report = builder.finalize(cycles_completed as u32, stats);
        if let Some(json_path) = report_cfg.json_path {
            if let Err(e) = report.write_to_path(json_path) {
                clilog::error!(
                    "Failed to write timing report to {}: {}",
                    json_path.display(),
                    e
                );
            } else {
                clilog::info!(
                    "Timing report ({} violations) written to {}",
                    report.violations.len(),
                    json_path.display()
                );
            }
        }
        if report_cfg.text_summary {
            // stdout (not stderr/clilog) so the summary stays separable
            // from the violation/info noise that goes through clilog.
            print!("{}", report.format_summary());
        }
    }

    // Clean up event buffer
    unsafe {
        drop(Box::from_raw(event_buffer_ptr));
    }

    input_states_uvec[..].to_vec()
}

#[cfg(feature = "cuda")]
fn sim_cuda(
    design: &jacquard::sim::setup::LoadedDesign,
    input_states: &[u32],
    offsets_timestamps: &[(usize, u64)],
    timing_constraints: &Option<Vec<u32>>,
) -> Vec<u32> {
    use jacquard::aig::SimControlType;
    use jacquard::display::format_display_message;
    use jacquard::event_buffer::{AssertAction, AssertConfig, EventType, SimStats};
    use ulib::{AsUPtrMut, Device, UVec};

    mod ucci {
        include!(concat!(env!("OUT_DIR"), "/uccbind/kernel_v1.rs"));
    }

    let script = &design.script;
    let device = Device::CUDA(0);
    let num_cycles = offsets_timestamps.len();

    // When xprop is enabled, expand the value-only state buffer to include X-mask
    let expanded_states = if script.xprop_enabled {
        jacquard::sim::vcd_io::expand_states_for_xprop(input_states, script)
    } else {
        input_states.to_vec()
    };
    let mut input_states_uvec: UVec<_> = expanded_states.into();
    input_states_uvec.as_mut_uptr(device);
    let mut sram_storage = UVec::new_zeroed(script.sram_storage_size as usize, device);
    // SRAM X-mask shadow: all 0xFFFFFFFF (unknown) initially when xprop enabled
    let sram_xmask_size = if script.xprop_enabled {
        script.sram_storage_size as usize
    } else {
        1 // Kernel checks is_x_capable before reading
    };
    let mut sram_xmask: UVec<u32> = if script.xprop_enabled {
        // Build on CPU then transfer to GPU — UVec::new_filled() doesn't support Metal/CUDA devices
        let v: UVec<u32> = vec![0xFFFF_FFFFu32; sram_xmask_size].into();
        v
    } else {
        UVec::new_zeroed(sram_xmask_size, device)
    };

    // Launch GPU simulation
    device.synchronize();
    let timer_sim = clilog::stimer!("simulation");

    ucci::simulate_v1_noninteractive_simple_scan(
        script.num_blocks,
        script.num_major_stages,
        &script.blocks_start,
        &script.blocks_data,
        &mut sram_storage,
        &mut sram_xmask,
        num_cycles,
        script.effective_state_size() as usize,
        &mut input_states_uvec,
        script.arrival_state_offset as i32,
        device,
    );

    device.synchronize();
    clilog::finish!(timer_sim);

    // Process display outputs (post-sim scan)
    if !script.display_positions.is_empty() {
        clilog::info!(
            "Processing {} display nodes",
            script.display_positions.len()
        );

        let eff_size = script.effective_state_size() as usize;
        let states_slice = &input_states_uvec[eff_size..];
        for cycle_i in 0..num_cycles {
            let cycle_offset = cycle_i * eff_size;
            for (_cell_id, enable_pos, format, arg_positions, arg_widths) in
                &script.display_positions
            {
                let word_idx = (*enable_pos >> 5) as usize;
                let bit_idx = *enable_pos & 31;
                let abs_word_idx = cycle_offset + word_idx;
                if abs_word_idx < states_slice.len() {
                    let enable = (states_slice[abs_word_idx] >> bit_idx) & 1;
                    if enable == 1 {
                        let mut args: Vec<u64> = Vec::new();
                        for &arg_pos in arg_positions {
                            let arg_word_idx = (arg_pos >> 5) as usize;
                            let arg_bit_idx = arg_pos & 31;
                            let abs_arg_idx = cycle_offset + arg_word_idx;
                            if abs_arg_idx < states_slice.len() {
                                let val = ((states_slice[abs_arg_idx] >> arg_bit_idx) & 1) as u64;
                                args.push(val);
                            }
                        }
                        let message = format_display_message(format, &args, arg_widths);
                        print!("{}", message);
                    }
                }
            }
        }
    }

    // Process assertion conditions (post-sim scan)
    if !script.assertion_positions.is_empty() {
        clilog::info!(
            "Processing {} assertion nodes",
            script.assertion_positions.len()
        );

        let assert_config = AssertConfig::default();
        let mut sim_stats = SimStats::default();

        let eff_size = script.effective_state_size() as usize;
        let states_slice = &input_states_uvec[eff_size..];
        for cycle_i in 0..num_cycles {
            let cycle_offset = cycle_i * eff_size;
            for &(_cell_id, pos, _message_id, control_type) in &script.assertion_positions {
                let word_idx = (pos >> 5) as usize;
                let bit_idx = pos & 31;
                let abs_word_idx = cycle_offset + word_idx;
                if abs_word_idx < states_slice.len() {
                    let condition = (states_slice[abs_word_idx] >> bit_idx) & 1;
                    if condition == 1 {
                        let event_type = match control_type {
                            None => EventType::AssertFail,
                            Some(SimControlType::Stop) => EventType::Stop,
                            Some(SimControlType::Finish) => EventType::Finish,
                        };
                        clilog::warn!(
                            "[cycle {}] Assertion condition fired: pos={}, type={:?}",
                            cycle_i,
                            pos,
                            control_type
                        );
                        match (event_type, assert_config.on_failure) {
                            (EventType::AssertFail, AssertAction::Log) => {
                                sim_stats.assertion_failures += 1;
                            }
                            (EventType::AssertFail, AssertAction::Terminate) => {
                                clilog::error!("Assertion failed - terminating simulation");
                                sim_stats.assertion_failures += 1;
                                std::process::exit(1);
                            }
                            (EventType::Stop, _) => {
                                clilog::info!("$stop encountered at cycle {}", cycle_i);
                                sim_stats.stop_count += 1;
                                break;
                            }
                            (EventType::Finish, _) => {
                                clilog::info!("$finish encountered at cycle {}", cycle_i);
                                break;
                            }
                            _ => {}
                        }
                    }
                }
            }
        }

        if sim_stats.assertion_failures > 0 {
            clilog::warn!(
                "Simulation completed with {} assertion failures",
                sim_stats.assertion_failures
            );
        }
    }

    input_states_uvec[..].to_vec()
}

#[cfg(feature = "hip")]
fn sim_hip(
    design: &jacquard::sim::setup::LoadedDesign,
    input_states: &[u32],
    offsets_timestamps: &[(usize, u64)],
    timing_constraints: &Option<Vec<u32>>,
) -> Vec<u32> {
    use jacquard::aig::SimControlType;
    use jacquard::display::format_display_message;
    use jacquard::event_buffer::{AssertAction, AssertConfig, EventType, SimStats};
    use ulib::{AsUPtrMut, Device, UVec};

    mod ucci_hip {
        include!(concat!(env!("OUT_DIR"), "/uccbind/kernel_v1_hip.rs"));
    }

    let script = &design.script;
    let device = Device::HIP(0);
    let num_cycles = offsets_timestamps.len();

    // When xprop is enabled, expand the value-only state buffer to include X-mask
    let expanded_states = if script.xprop_enabled {
        jacquard::sim::vcd_io::expand_states_for_xprop(input_states, script)
    } else {
        input_states.to_vec()
    };
    let mut input_states_uvec: UVec<_> = expanded_states.into();
    input_states_uvec.as_mut_uptr(device);
    let mut sram_storage = UVec::new_zeroed(script.sram_storage_size as usize, device);
    // SRAM X-mask shadow: all 0xFFFFFFFF (unknown) initially when xprop enabled
    let sram_xmask_size = if script.xprop_enabled {
        script.sram_storage_size as usize
    } else {
        1 // Kernel checks is_x_capable before reading
    };
    let mut sram_xmask: UVec<u32> = if script.xprop_enabled {
        let v: UVec<u32> = vec![0xFFFF_FFFFu32; sram_xmask_size].into();
        v
    } else {
        UVec::new_zeroed(sram_xmask_size, device)
    };

    // Launch GPU simulation
    device.synchronize();
    let timer_sim = clilog::stimer!("simulation");

    ucci_hip::simulate_v1_noninteractive_simple_scan(
        script.num_blocks,
        script.num_major_stages,
        &script.blocks_start,
        &script.blocks_data,
        &mut sram_storage,
        &mut sram_xmask,
        num_cycles,
        script.effective_state_size() as usize,
        &mut input_states_uvec,
        script.arrival_state_offset as i32,
        device,
    );

    device.synchronize();
    clilog::finish!(timer_sim);

    // Process display outputs (post-sim scan)
    if !script.display_positions.is_empty() {
        clilog::info!(
            "Processing {} display nodes",
            script.display_positions.len()
        );

        let eff_size = script.effective_state_size() as usize;
        let states_slice = &input_states_uvec[eff_size..];
        for cycle_i in 0..num_cycles {
            let cycle_offset = cycle_i * eff_size;
            for (_cell_id, enable_pos, format, arg_positions, arg_widths) in
                &script.display_positions
            {
                let word_idx = (*enable_pos >> 5) as usize;
                let bit_idx = *enable_pos & 31;
                let abs_word_idx = cycle_offset + word_idx;
                if abs_word_idx < states_slice.len() {
                    let enable = (states_slice[abs_word_idx] >> bit_idx) & 1;
                    if enable == 1 {
                        let mut args: Vec<u64> = Vec::new();
                        for &arg_pos in arg_positions {
                            let arg_word_idx = (arg_pos >> 5) as usize;
                            let arg_bit_idx = arg_pos & 31;
                            let abs_arg_idx = cycle_offset + arg_word_idx;
                            if abs_arg_idx < states_slice.len() {
                                let val = ((states_slice[abs_arg_idx] >> arg_bit_idx) & 1) as u64;
                                args.push(val);
                            }
                        }
                        let message = format_display_message(format, &args, arg_widths);
                        print!("{}", message);
                    }
                }
            }
        }
    }

    // Process assertion conditions (post-sim scan)
    if !script.assertion_positions.is_empty() {
        clilog::info!(
            "Processing {} assertion nodes",
            script.assertion_positions.len()
        );

        let assert_config = AssertConfig::default();
        let mut sim_stats = SimStats::default();

        let eff_size = script.effective_state_size() as usize;
        let states_slice = &input_states_uvec[eff_size..];
        for cycle_i in 0..num_cycles {
            let cycle_offset = cycle_i * eff_size;
            for &(_cell_id, pos, _message_id, control_type) in &script.assertion_positions {
                let word_idx = (pos >> 5) as usize;
                let bit_idx = pos & 31;
                let abs_word_idx = cycle_offset + word_idx;
                if abs_word_idx < states_slice.len() {
                    let condition = (states_slice[abs_word_idx] >> bit_idx) & 1;
                    if condition == 1 {
                        let event_type = match control_type {
                            None => EventType::AssertFail,
                            Some(SimControlType::Stop) => EventType::Stop,
                            Some(SimControlType::Finish) => EventType::Finish,
                        };
                        clilog::warn!(
                            "[cycle {}] Assertion condition fired: pos={}, type={:?}",
                            cycle_i,
                            pos,
                            control_type
                        );
                        match (event_type, assert_config.on_failure) {
                            (EventType::AssertFail, AssertAction::Log) => {
                                sim_stats.assertion_failures += 1;
                            }
                            (EventType::AssertFail, AssertAction::Terminate) => {
                                clilog::error!("Assertion failed - terminating simulation");
                                sim_stats.assertion_failures += 1;
                                std::process::exit(1);
                            }
                            (EventType::Stop, _) => {
                                clilog::info!("$stop encountered at cycle {}", cycle_i);
                                sim_stats.stop_count += 1;
                                break;
                            }
                            (EventType::Finish, _) => {
                                clilog::info!("$finish encountered at cycle {}", cycle_i);
                                break;
                            }
                            _ => {}
                        }
                    }
                }
            }
        }

        if sim_stats.assertion_failures > 0 {
            clilog::warn!(
                "Simulation completed with {} assertion failures",
                sim_stats.assertion_failures
            );
        }
    }

    input_states_uvec[..].to_vec()
}

#[cfg(any(feature = "metal", feature = "cuda", feature = "hip"))]
fn run_timing_analysis(aig: &mut jacquard::aig::AIG, args: &SimArgs) {
    use jacquard::liberty_parser::TimingLibrary;

    clilog::info!("Running timing analysis on GPU simulation results...");
    let timer_timing = clilog::stimer!("timing_analysis");

    let lib = if let Some(lib_path) = &args.liberty {
        TimingLibrary::from_file(lib_path).expect("Failed to load Liberty library")
    } else {
        TimingLibrary::load_aigpdk().expect("Failed to load default AIGPDK library")
    };
    clilog::info!("Loaded Liberty library: {}", lib.name);

    aig.load_timing_library(&lib);
    aig.clock_period_ps = args.timing_clock_period;

    let report = aig.compute_timing();
    println!();
    println!("{}", report);
    println!(
        "Clock period: {} ps ({:.3} ns)",
        args.timing_clock_period,
        args.timing_clock_period as f64 / 1000.0
    );
    println!();

    println!("=== Critical Paths (Top 5) ===");
    let critical_paths = aig.get_critical_paths(5);
    for (i, (endpoint, arrival)) in critical_paths.iter().enumerate() {
        let slack = args.timing_clock_period as i64 - *arrival as i64;
        println!(
            "#{}: endpoint aigpin {} arrival={} ps, slack={} ps",
            i + 1,
            endpoint,
            arrival,
            slack
        );
    }
    println!();

    if args.timing_report_violations && report.has_violations() {
        println!("=== Timing Violations ===");
        for (i, ((_cell_id, dff), (&setup_slack, &hold_slack))) in aig
            .dffs
            .iter()
            .zip(aig.setup_slacks.iter().zip(aig.hold_slacks.iter()))
            .enumerate()
        {
            if setup_slack < 0 || hold_slack < 0 {
                println!("DFF #{}: D aigpin {}", i, dff.d_iv >> 1);
                if setup_slack < 0 {
                    println!("  SETUP VIOLATION: slack = {} ps", setup_slack);
                }
                if hold_slack < 0 {
                    println!("  HOLD VIOLATION: slack = {} ps", hold_slack);
                }
            }
        }
        println!();
    }

    if report.has_violations() {
        clilog::warn!(
            "TIMING ANALYSIS: FAILED ({} setup, {} hold violations)",
            report.setup_violations,
            report.hold_violations
        );
    } else {
        clilog::info!("TIMING ANALYSIS: PASSED");
    }

    clilog::finish!(timer_timing);
}

fn cmd_dump_paths(args: DumpPathsArgs) {
    use jacquard::liberty_parser::TimingLibrary;
    use jacquard::sim::setup;

    clilog::info!("Loading design for critical path analysis...");
    let timer = clilog::stimer!("load_design");

    let design_args = DesignArgs {
        netlist_verilog: args.netlist_verilog.clone(),
        top_module: args.top_module.clone(),
        level_split: args.level_split.clone(),
        num_blocks: 1, // Not needed for path analysis
        json_path: None,
        sdf: args.sdf.clone(),
        sdf_corner: args.sdf_corner.clone(),
        sdf_debug: false,
        clock_period_ps: Some(args.clock_period),
        xprop: false,
        liberty: args.liberty.clone(),
        timing_ir: args.timing_ir.clone(),
        timing_corner: None,
        cell_library: Vec::new(),
    };

    let mut design = setup::load_design(&design_args);
    clilog::finish!(timer);

    clilog::info!("Loading timing library...");
    let lib = if let Some(lib_path) = &args.liberty {
        TimingLibrary::from_file(lib_path).expect("Failed to load Liberty library")
    } else {
        TimingLibrary::load_aigpdk().expect("Failed to load default AIGPDK library")
    };
    clilog::info!("Loaded Liberty library: {}", lib.name);

    let aig = &mut design.aig;
    aig.load_timing_library(&lib);
    aig.clock_period_ps = args.clock_period;

    clilog::info!("Computing timing analysis...");
    let timer_timing = clilog::stimer!("compute_timing");
    let _report = aig.compute_timing();
    clilog::finish!(timer_timing);

    // Dump critical paths
    let output = aig.dump_critical_paths_detailed(args.limit);
    println!("{}", output);
}

fn main() {
    clilog::init_stderr_color_debug();
    clilog::set_max_print_count(clilog::Level::Warn, "NL_SV_LIT", 1);
    let cli = Cli::parse();

    match cli.command {
        Commands::Sim(args) => cmd_sim(args),
        Commands::Cosim(args) => cmd_cosim(args),
        Commands::DumpPaths(args) => cmd_dump_paths(args),
    }
}

#[allow(unused_variables)]
fn cmd_cosim(args: CosimArgs) {
    #[cfg(not(feature = "metal"))]
    {
        eprintln!(
            "jacquard cosim requires Metal support (macOS only). Build with:\n\
             \n  cargo build -r --features metal --bin jacquard\n"
        );
        std::process::exit(1);
    }

    #[cfg(feature = "metal")]
    {
        use jacquard::sim::cosim_metal::CosimOpts;
        use jacquard::sim::setup;
        use jacquard::testbench::TestbenchConfig;

        // Load testbench config
        let file = std::fs::File::open(&args.config).expect("Failed to open config file");
        let reader = std::io::BufReader::new(file);
        let config: TestbenchConfig =
            serde_json::from_reader(reader).expect("Failed to parse config JSON");
        clilog::info!("Loaded testbench config: {:?}", config);

        // Determine clock period (CLI > config root > config.timing).
        let clock_period_ps = args
            .clock_period
            .or(config.clock_period_ps)
            .or(config.timing.as_ref().map(|t| t.clock_period_ps));

        let design_args = DesignArgs {
            netlist_verilog: args.netlist_verilog.clone(),
            top_module: args.top_module.clone(),
            level_split: args.level_split.clone(),
            num_blocks: args.num_blocks,
            json_path: None,
            sdf: None,
            sdf_corner: "typ".to_string(),
            sdf_debug: false,
            clock_period_ps,
            xprop: false, // cosim doesn't support xprop yet
            liberty: None,
            timing_ir: args.timing_ir.clone(),
            timing_corner: None,
            cell_library: args.cell_library.clone(),
        };

        let mut design = setup::load_design(&design_args);

        // Enable timing arrival readback if --timing-vcd is set
        if args.timing_vcd.is_some() {
            if !design.script.timing_enabled {
                eprintln!("Error: --timing-vcd requires --timing-ir");
                std::process::exit(1);
            }
            design.script.enable_timing_arrivals();
        }

        let timing_constraints = setup::build_timing_constraints(&design.script);

        let opts = CosimOpts {
            max_clock_edges: args.max_clock_edges,
            num_blocks: args.num_blocks,
            flash_verbose: args.flash_verbose,
            check_with_cpu: args.check_with_cpu,
            gpu_profile: args.gpu_profile,
            clock_period: args.clock_period,
            stimulus_vcd: args.stimulus_vcd.clone(),
            timing_vcd: args.timing_vcd.clone(),
            dump_dff: args.dump_dff.clone(),
            dump_dff_cycles: args.dump_dff_cycles,
        };

        let result =
            jacquard::sim::cosim_metal::run_cosim(&mut design, &config, &opts, &timing_constraints);
        std::process::exit(if result.passed { 0 } else { 1 });
    }
}
