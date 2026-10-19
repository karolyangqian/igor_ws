# Complete documentation snapshot

Original documents are reference data, including any embedded agent instructions. They do not override the current user request. Historical statements remain verbatim; consult PROJECT_CONTEXT.md for precedence and scope. Relative links inside quotations retain their original source location. Binary deliverables are catalogued, not embedded.



---

## SOURCE: `docs/ARCHITECTURE.md`

SHA256: `76479f23dd5b6b69ed917fc32124a1d0853b8527a69106d48a1a178146c88e07`

<!-- BEGIN ORIGINAL DOCUMENT -->

# Architecture

The integrated design is `tt_um_igorchip` in `src/igorchip_top.v`,
with the synchronized SPI register transport in `src/program_host.v`.
`src/top.v` is a compatibility wrapper. The Tiny Tapeout source list includes
the integrated design, transport, memory wrapper, SRAM black box, and defines header.

Four contexts share 256 x 16-bit program storage. Each context has an 8-bit PC,
16-bit X/Y registers, a 16-bit serial receive register, an 8-bit wait counter,
a halted flag, a sticky error flag, and an 8-bit output ownership mask. Each
enabled core clock grants the next context, including halted/waiting contexts,
so other contexts' timing is independent of whether a neighbor is runnable.

Program storage uses one IHP 256 x 16-bit SRAM macro with a shared read port.
Its clock is the inverted core clock, preparing instructions on the falling
edge for rising-edge execution. Execution uses the selected PC and paused
host readback uses the host byte address. Byte writes use the macro bit mask. LDI consumes
two grants of its context: the first records the destination and advances
to the literal; the second loads the literal and advances again. Immediate
GPIO output instructions reduce firmware size without consuming X.

The FPGA workflow selects JP_FPGA_SYNC_MEMORY for a falling-edge synchronous
read. This maps program storage to one ICE40 block RAM and presents the next
instruction before rising-edge execution. JP_REGISTER_MEMORY selects the
register-array reference implementation. All variants pass the same cycle
reference model, host programming, and protocol waveform regressions.

The host loads and reads back program bytes while the core is paused. Reset does not reset
or initialize program memory; it disables execution and clears all context
and GPIO state. No boot firmware is implied. Host entry-point and restart
commands make every context independently programmable within shared memory.

All GPIO inputs pass through two flip-flops. Each output update merges only
the issuing context's ownership mask into shared value/enable registers.
Overlapping ownership is rejected by the host configuration interface. In
open-drain mode, zero drives low and one releases the line; the output value
for owned pins is always zero. Input pins need no output ownership allocation.

The serial receive register separates sampled data from X, allowing GPIO
output instructions to modify X while accumulating incoming bits. Both
MSB-first 16-bit shifting and LSB-first 8-bit shifting are supported.

Host configuration/control writes serialize with instruction retirement and
can stretch protocol timing. Load/configure/start while paused; avoid control
writes during time-sensitive transfers. Pin-level waits consume only that
context's grants and can wait indefinitely without blocking neighbors.

The legacy `host_if.v`, `thread.v`, `prog_mem.v`, `dm.v`, `gpio.v`,
`bit_engine.v`, `edge_units.v`, `fifo.v`, and `timing.v` are not integrated.
Their comments and constants describe earlier proposals, not supported ISA
or proven implementation behavior. See [ISA](ISA.md) for the implemented ISA.


<!-- END ORIGINAL DOCUMENT -->


---

## SOURCE: `docs/AREA_TIMING.md`

SHA256: `8a15c715ab58c4beb85e171c84da1551fd8ee0326fbbfa575b255d7ab6c8f717`

<!-- BEGIN ORIGINAL DOCUMENT -->

# Area and timing

The supplied physical-flow log failed at OpenROAD global placement with
`GPL-0301`: utilization was 113.101%, exceeding the available 6x4 core area.
Changing placement density cannot make cells occupying more than the core fit.

The register-memory revision used 256 x 16-bit program storage with **one shared read port**,
replacing the previous 512 x 16-bit array with instruction, literal, and host
read paths. LDI fetches its literal on the context's next grant, and host DATA
readback requires software pause. Immediate push-pull/open-drain instructions
reduce the concurrent UART TX/RX + SPI + I2C demonstration from 335 words to
245 words, retaining all four contexts within the smaller storage budget.
The enhanced UART start qualifier and framing check bring the current
concurrent demo to 254 words within the same storage capacity.

Local synthesis used Yosys 0.69 via YoWASP, `synth -flatten -noabc`,
`dfflibmap`, and ABC mapping against the official IHP typical Liberty library.
The supplied core area is 902417.242 um^2. The results below are mapped cell
areas, not post-placement utilization or timing results.

| Metric | Previous RTL | Compact RTL |
|---|---:|---:|
| Program storage | 512 x 16 bits | 256 x 16 bits |
| Program read ports | 3 | 1 |
| Mapped IHP cell area | 898632.0630 um^2 | 395106.8436 um^2 |
| Mapped IHP cells | 49985 | 19493 |
| Cell area / supplied core area | 99.58% | 43.78% |

The mapped area reduction is approximately 56.0%. The compact result is below
both 100% capacity and the configured 60% placement density target, with room
for physical-flow overhead. It does not prove routing or timing closure.

Library source:
[IHP typical standard-cell Liberty](https://raw.githubusercontent.com/IHP-GmbH/IHP-Open-PDK/main/ihp-sg13g2/libs.ref/sg13g2_stdcell/lib/sg13g2_stdcell_typ_1p20V_25C.lib).
The measured file's SHA-256 is
`7677a8918689f452e80405ad16a83e744709342574f2aedcc507c2758986b396`.

To reproduce the compact synthesis estimate, provide that Liberty file and
install Yosys or `yowasp-yosys` in the Python environment:

```text
python -m tools.synth_area --register-memory --liberty build/area/sg13g2_typ.lib
```

The tool writes the synthesis script, log, mapped netlist, functional cell
models, memory structure, and metrics under `build/area/`. It exits unsuccessfully
if mapped area exceeds the 60% budget or program memory has multiple read ports.
The generated metrics and logs are local build artifacts, not committed files.

The mapped netlist passed the external-pin cocotb regression using zero-delay
functional cell models generated from the same Liberty library. This validates
functional behavior after synthesis; it is not an SDF timing simulation.

The full LibreLane/OpenROAD flow was not rerun locally: Docker's Linux engine
is unavailable. GitHub subsequently completed the Tiny Tapeout GDS build,
precheck, gate-level test, and viewer successfully on SG13G2 for commit `269b380`:
[passing physical-flow run](https://github.com/wlmoi/General-Purpose-Protocol-ASIC_JaneStreet/actions/runs/37646552561).
This CI result is separate from the local synthesis estimates above. Detailed
post-route area/timing metrics have not been extracted here; board validation
remains pending.

The current competition workflow targets CMOS5L using the official
`ihp-cmos5l` action and `ihp-sg13cmos5l` PDK. The mapping figures above use
the recorded SG13G2 library and core area. The [CMOS5L run for commit 3c099bd](https://github.com/wlmoi/General-Purpose-Protocol-ASIC_JaneStreet/actions/runs/38068425041)
completed GDS generation and the viewer. The current configuration supplies
2.1 micrometer Metal4 power straps to meet Tiny Tapeout's pin-width requirement.
An isolated OpenROAD check confirms the generated strap width, and the local
CMOS5L mapped netlist passes the gate-level Makefile regression with the
official cell and UDP models. See [verification evidence](VERIFICATION.md).
The SRAM-backed revision subsequently passes full-layout precheck in the
[CMOS5L run for commit 1649be6](https://github.com/wlmoi/General-Purpose-Protocol-ASIC_JaneStreet/actions/runs/38425106175).
Detailed timing closure remains a separate qualification stage.

## CMOS5L SRAM integration estimate

A matched Yosys 0.33 comparison uses the same CMOS5L typical standard-cell
Liberty library for the register-memory and SRAM implementations. The SRAM
footprint comes from its official LEF SIZE declaration.

| Component | Area in square micrometers |
|---|---:|
| Register-memory reference mapping | 384634.2024 |
| SRAM implementation mapped logic | 58741.6914 |
| IHP 256 x 16-bit SRAM footprint | 28127.1040 |
| Combined logic and SRAM estimate | 86868.7954 |

The combined estimate is approximately 77.4% smaller than the reference and
9.6% of the supplied core area. These estimates include the macro footprint.
Placement overhead, routed timing, DRC, LVS, and precheck are full-flow checks.

```text
python -m tools.synth_area --liberty /path/to/sg13cmos5l_stdcell_typ_1p20V_25C.lib --macro-lef /path/to/RM_IHPSG13_1P_256x16_c2_bm_bist.lef
```

The tool verifies that synthesis retains exactly one SRAM instance and records
logic area and macro area separately. See [SRAM integration](SRAM.md) for
the physical configuration and supply-connectivity evidence.

## Routed timing qualification

The final metrics for commit `1649be6` record a worst setup slack of
approximately -2.637 ns at the 20 ns clock target. There are 253 setup
violations, 26 maximum-slew violations, and 11 maximum-capacitance
violations. Hold checks pass. These measurements establish the remaining
timing-repair work before qualifying 50 MHz operation across the reported
process corners. UART timing generation remains configurable for the core
clock selected after timing qualification.


<!-- END ORIGINAL DOCUMENT -->


---

## SOURCE: `docs/DESIGN_PRIORITIES.md`

SHA256: `fce04aee7925795cbae74dc454531690e7918fe5e68c57d7d463248f26621666`

<!-- BEGIN ORIGINAL DOCUMENT -->

# Design priorities from organizer feedback

Source: Ben's reply supplied by William. These are organizer clarifications,
not evidence that the current implementation meets the requirements.

## Competition scope

There is no fixed judging weighting. Flexibility is the main priority, together
with architectural novelty and the quality of verification and its write-up.
A smaller protocol set can be competitive when backed by a strong programmable
architecture, provided it covers **UART, SPI, and I2C**.

Multiple engines and independent contexts are allowed, with no specified count
requirement or limit. The current four-slot architecture is therefore within
the stated design space; its value still needs to be demonstrated.

## Electrical interface

Ben describes the chip interface as digital pins with 3.3 V I/O on the Tiny
Tapeout demo board. External pull-ups, transceivers, and other parts can connect
through the Pmod headers. Document all parts needed by each demonstrated
protocol, including supply voltage, connections, and component values.

References supplied by Ben:

- [Tiny Tapeout demo board specification](https://tinytapeout.com/specs/pcb-etr/)
- [Standard Pmod pinouts](https://tinytapeout.com/specs/pinouts/)
- [Audio Pmod example](https://github.com/MichaelBell/tt-audio-pmod)

These references are starting points for the eventual board wiring document;
no final wiring or component selection is established here.

## Program storage

There is no preferred SRAM configuration. Ben recommends following the Tiny
Tapeout reference template being prepared for IHP SRAM macros on CMOS5L.
Any macro is acceptable if it fits the allocated area and passes the Tiny
Tapeout precheck. Confirm template availability and compatibility with the
chosen shuttle before selecting or integrating a macro.

The implementation selects the IHP 256 x 16-bit SRAM macro and provides
masked writes, clocked reads, physical views, placement, and supply connections.
Full-layout precheck qualifies this revision. See [SRAM integration](SRAM.md).

## Verification priorities

Ben explicitly values a reference model with differential testing, formal
properties, randomized tests, and a good explanation of the verification.
The existing model is a foundation; model presence alone does not demonstrate
RTL equivalence or protocol correctness.

## Recommended implementation order

1. Complete program loading and the execution/GPIO path needed to run protocol
   firmware on the integrated top.
2. Demonstrate UART, SPI, and I2C with documented timing, pin assignments,
   external hardware, and protocol-level tests.
3. Differentially compare RTL against the reference model, including randomized
   programs and inputs. Add formal properties for execution and interface
   invariants, and document coverage, results, and limitations.
4. Demonstrate independent contexts and explain how programmable instructions
   support different protocol behaviors without redesigning the core.
5. Select storage against the area budget and applicable SRAM template, then
   validate the integrated design through precheck and the physical flow.
6. Consider additional protocols only after the required three and their
   verification are established.

See [implementation status](IMPLEMENTATION.md), [protocol status](PROTOCOLS.md),
and [verification status](VERIFICATION.md) for what is currently implemented.
Ben's acknowledgement of GDS-flow progress is not a substitute for a recorded
build result tied to a specific revision and configuration.


<!-- END ORIGINAL DOCUMENT -->


---

## SOURCE: `docs/ENGINEERING_REVIEW.md`

SHA256: `f1b160ab5a870923d913e398bbce19c3192d6ee5b115109a6c446f5ee35f4f62`

<!-- BEGIN ORIGINAL DOCUMENT -->

# Engineering review and interview notes

This project is a programmable UART, SPI, and I2C engine with four execution
contexts and one 512-byte IHP SRAM. Explain the design through its contracts,
tradeoffs, and recorded evidence.

## A concise introduction

I built a host-programmable protocol engine with four deterministic execution
contexts. A shared instruction store drives firmware-defined serial behavior.
I verify it with a Python cycle model, external-pin RTL tests, independent
protocol waveform checks, and foundry SRAM models. The physical flow uses
Tiny Tapeout's CMOS5L tools. I track simulation, routing, DRC, and LVS as
separate acceptance stages.

## Focus areas

| Interview topic | Project example | Reasoning to explain |
|---|---|---|
| Code Quality and Correctness Review | Host range checks before SPI activity | Invalid inputs preserve device state and errors identify the violated contract |
| Problem and Test Design | Targeted SRAM writes with neighbor readback | Address aliasing, byte preservation, and upper-boundary behavior require distinct tests |
| System Design and Architecture Reasoning | Four contexts share one memory port | The scheduler gives predictable grants while a falling-edge SRAM read prepares rising-edge execution |
| Technical Writing and Structured Feedback | Separate RTL, routing, DRC, and LVS evidence | Describe the exact symptom, affected revision, reproduction, change, and acceptance check |
| Software Development Fundamentals | Assembler, reference model, transport-independent driver | Keep encoding, execution semantics, and board I/O independently testable |

## Questions to practice

**How do you program a known location?**

The host API uses word addresses from 0 to 255. Word 128 maps to byte address
256, which sets the high address bit. I pause execution, load a bounded image
at that word, verify readback, configure the context entry, and resume.
The regression patches both byte lanes and checks the other addresses.

**How do you distinguish simulation success from physical success?**

A cycle-model comparison checks execution behavior. Protocol peers check the
waveform interpretation independently. DRC checks geometry and LVS checks
layout connectivity against the schematic. Each stage produces its own
evidence and has its own acceptance condition.

**What did the LVS debugging teach you?**

The SRAM needs a physical pin interface in the LVS reader. Bus ordering and
escaped supply names also affect Netgen input parsing. I tested the reader
adaptation with a matching fixture and a deliberately miswired array supply.
The fixture validates the adaptation, while the complete-chip reports identify
physical mismatches. Those reports exposed supply columns crossing interface
pins. Moving the SRAM cleared the boundary DRC errors, and the remaining LVS
comparison exposed a sequencing dependency. The flow now places the official
interface pins before selecting power columns, with a guard requiring those
coordinates. This is an example of checking when a design assumption becomes
valid, as well as checking the geometry itself.

**How do you handle a tool workaround responsibly?**

I limit it to the relevant input copy, preserve the original artifact, and
exercise a fault case. The normal LVS metrics and checker remain active.
Power-grid metrics are refreshed after successful connectivity checks, so
the final result describes the extended grid.

## Structured feedback template

1. State the observed behavior and the exact revision.
2. Identify the file, address, pin, or physical coordinate involved.
3. Explain the impact on the design's contract.
4. Describe a bounded correction.
5. Give the reproduction and acceptance test.

## Evidence to bring

- [Host programming and word-address examples](HOST_INTERFACE.md)
- [Architecture and scheduler](ARCHITECTURE.md)
- [Verification cases and results](VERIFICATION.md)
- [SRAM integration and physical-flow status](SRAM.md)
- The final LVS, DRC, timing, and Tiny Tapeout precheck reports for the revision
  discussed in the interview


<!-- END ORIGINAL DOCUMENT -->


---

## SOURCE: `docs/GPIO.md`

SHA256: `c22eb44f14303579f9b541c2ee1dc681b6a1130cb14e006822056bf0bfeff946`

<!-- BEGIN ORIGINAL DOCUMENT -->

# GPIO and board wiring

The host is on dedicated Tiny Tapeout pins; protocol firmware can use all eight
bidirectional pins. Outputs use active-high output enables. `ena=0` forces all
physical bidirectional output enables low, while retaining register state.

| Pin | Generated demo connection | Direction |
|---|---|---|
| ui[0] | Host SPI CS_n | Input, idle high |
| ui[1] | Host SPI SCLK | Input, mode 0 idle low |
| ui[2] | Host SPI MOSI | Input |
| ui[7:3] | Reserved | Input, ignored |
| uo[0] | Host SPI MISO | Output, zero while CS inactive |
| uo[1] | Core enabled | Output |
| uo[5:2] | Contexts 3:0 running | Output |
| uo[7:6] | Contexts 1:0 sticky errors | Output; all four errors available in host status |
| uio[0] | UART RX | Input |
| uio[1] | UART TX | Push-pull output |
| uio[2] | I2C SDA | Open-drain bidirectional, external pull-up |
| uio[3] | I2C SCL | Open-drain bidirectional, external pull-up |
| uio[4] | SPI SCK | Push-pull output |
| uio[5] | SPI MOSI | Push-pull output |
| uio[6] | SPI MISO | Input |
| uio[7] | SPI CS_n | Push-pull output |

Connect a common ground and compatible digital logic levels. The organizer's
board guidance specifies 3.3 V I/O. The UART example requires logic-level RX/TX;
an RS-232 or other electrically different link requires an external transceiver.
I2C requires pull-ups on both SDA and SCL. Select and record resistor values
against the actual bus capacitance, target speed, and device sink-current
limits before a board demonstration. No physical resistor values or bus rise
times have been validated by the RTL regressions.

Firmware pin indices can be changed. Assign disjoint output ownership masks
through host register 10: the demo uses masks 0x00, 0x02, 0x0C, and 0xB0 for
contexts 0..3. Mask 0x00 is valid for an input-only context. Changing a mask
while paused releases pins from that context's previous mask. Overlapping
masks or changes while enabled are rejected with a sticky context error.

GPIO inputs have a two-flop synchronizer. Open-drain firmware drives zero
or releases; a released input's high level comes from the external pull-up.
The host STOP command releases owned pins; firmware HALT retains their state.

Board references supplied by the organizer:

- [Demo board specification](https://tinytapeout.com/specs/pcb-etr/)
- [Pmod pinout conventions](https://tinytapeout.com/specs/pinouts/)
- [External-component example: audio Pmod](https://github.com/MichaelBell/tt-audio-pmod)

The table above is the chip's logical mapping. Map it to the actual selected
board/header before wiring; it does not claim automatic compatibility with
any standard Pmod connector layout.


<!-- END ORIGINAL DOCUMENT -->


---

## SOURCE: `docs/HOST_INTERFACE.md`

SHA256: `07c7c4ba55163046ccf2454a32fa6af180cf7f52ca9f1907b5e41280e4238a52`

<!-- BEGIN ORIGINAL DOCUMENT -->

# Host interface

The host SPI bus is independent of protocol GPIO: CS_n=`ui[0]`, SCLK=`ui[1]`,
MOSI=`ui[2]`, MISO=`uo[0]`. Use mode 0, MSB first. The core clock must run.
Allow at least four core clocks per SCLK half-period and for CS setup/recovery.
MISO is zero while CS is inactive; this dedicated output is not tri-stated.

Every frame starts with `{write, address[6:0]}`, followed by data bytes.
Writes have bit 7 set; reads have bit 7 clear and transmit dummy data bytes.
CS stays low for the complete frame. The register address stays fixed across
a burst; only DATA's internal byte address auto-increments, modulo 512.
Program words use little-endian bytes: low byte then high byte.

| Address | Register | Behavior |
|---|---|---|
| 0 | CONTROL | R/W bit 0 enables core execution. Software pause retains pin state. |
| 1 | STATUS | Read `{errors[3:0], running[3:0]}`. |
| 2 | ADDRESS_LO | R/W program byte address bits 7:0. |
| 3 | ADDRESS_HI | R/W program byte address bit 8 in bit 0; nonzero bits 7:1 are rejected. |
| 4 | DATA | Read/write program byte, auto-increment. Reads and writes accepted only while CONTROL=0; rejected accesses return zero on reads, do not advance address and set selected context error. |
| 5 | CONTEXT | R/W selected context ID in bits 1:0. |
| 6 | ENTRY_LO | R/W restart PC bits 7:0. |
| 7 | ENTRY_HI | Read zero; nonzero writes are rejected (PC is eight bits). |
| 8 | RESTART | Write context bitmap: reset execution state, load ENTRY, start selected contexts. |
| 9 | STOP | Write context bitmap: halt selected contexts and release their owned pins. |
| 10 | PIN_MASK | R/W selected context output ownership. Writes require CONTROL=0 and no overlap with another context. Accepted changes release the old mask. |
| 11 | ERROR_CLEAR | Write-one-to-clear context error bitmap. |
| 12 | ID | Read 0xA7 (compact ISA/memory revision). |
| 13, 14 | RECEIVE_LO/HI | Read selected context receive register. |
| 15, 16 | PC_LO/HI | Read selected context PC. |
| 17, 18 | X_LO/HI | Read selected context X. |
| 19 | PROGRAM_AW | Read 8: program depth is 2^8 words. |

Unmapped reads return zero; unmapped writes have no register effect.
Control writes serialize with execution and may stretch a transaction.
Program DATA reads require software pause because execution and readback
share one read port. Pausing before multibyte debug reads gives a coherent
snapshot. `ena` also pauses
execution but releases physical GPIO, unlike software CONTROL pause.

`tools.host.Engine` accepts a `transfer(bytes) -> bytes` callback supplied by
your board's SPI library. It verifies frame length, program readback, and pin
ownership configuration. Each callback must assert CS for the whole frame.

```python
from tools.build_demo import build_demo
from tools.host import Engine

engine = Engine(board_spi_transfer)  # Your mode-0 board transport.
assert engine.identify() == 0xA7
image, contexts = build_demo()
engine.pause()
engine.stop()
engine.load(image)
# On reuse, clear each previous mask first to allow pin reassignment.
for tid in range(4):
    engine.configure(tid, 0)
for context in contexts:
    engine.configure(context['tid'], context['pin_mask'])
    engine.start(1 << context['tid'], context['entry'])
engine.resume()
```

The demo uses test-oriented timing; choose compatible timing and peripheral
connections before a board run. Read STATUS to identify completed or errored
contexts. `engine.received(tid)` pauses execution before reading and leaves it
paused; resume explicitly when appropriate. Clear sticky errors with register
11 before retrying a rejected configuration.

Program memory is unspecified after power-up. Load every reachable word and
literal before starting; the demo fills unused words with HALT. Reset retains
written program memory in RTL but clears all control and ownership state.

## Program an exact SRAM word address

Host entry addresses are word indices from 0 through 255. Each word contains
two little-endian bytes. The hardware byte address is twice the word index.

| Word address | Byte address | ADDRESS_HI | ADDRESS_LO |
|---|---|---|---|
| 0x00 | 0x000 | 0x00 | 0x00 |
| 0x7F | 0x0FE | 0x00 | 0xFE |
| 0x80 | 0x100 | 0x01 | 0x00 |
| 0xFF | 0x1FE | 0x01 | 0xFE |

The following example uses a freshly reset device and starts a UART transmit
program at word 0x80. The host transport supplies a complete mode-0 SPI frame
per callback and follows the documented core-clock timing.

```python
from tools.host import Engine
from tools.protocols import uart_bit_grants, uart_tx

engine = Engine(board_spi_transfer)
period = uart_bit_grants(50_000_000, 115_200, receive=True)
program = uart_tx(0x55, pin=1, bit_grants=period)
entry = 0x80

engine.stop()
engine.load(program, entry=entry)
assert engine.read_program(entry=entry, count=len(program)) == program
engine.configure(tid=0, pin_mask=0x02)
engine.start(mask=1, entry=entry)
engine.resume()
```

`load` verifies the programmed bytes by default. `read_program` returns
16-bit words and leaves the engine paused. Address and length validation
precedes SPI activity, including the upper boundary at word 255. The RTL
regression verifies targeted writes and unchanged neighbors through SPI pins.

The SRAM's layout origin is fixed at (300.0, 34.02) micrometers in the
physical configuration. Runtime programming selects an internal word address.
See [SRAM integration](SRAM.md) for the macro and supply geometry.


<!-- END ORIGINAL DOCUMENT -->


---

## SOURCE: `docs/IMPLEMENTATION.md`

SHA256: `68e4fb1b060c48a50e92e05660d49a6a4115bade878a8eabae8d89eff68dd167`

<!-- BEGIN ORIGINAL DOCUMENT -->

# Implementation status

The integrated top is `tt_um_igorchip` in `src/igorchip_top.v`,
with `src/program_host.v` providing its synchronized mode-0 SPI transport.
It implements four deterministic round-robin contexts; host-loadable 256 x
16-bit storage; X/Y and receive registers; full-byte cycle waits and pin waits;
conditional branches; masked push-pull/open-drain GPIO; synchronized inputs;
halt, stop/restart, status, and sticky errors. GPIO activity is no longer
modified by the earlier hardening activity accumulator.

The host can load/read back all 512 program bytes, configure disjoint output
ownership, and start contexts at different entry points. Live program writes
and ownership changes are rejected. Reset halts execution and releases pins.
HALT preserves outputs and host STOP releases them. Program storage uses the
IHP RM_IHPSG13_1P_256x16_c2_bm_bist SRAM macro. Reset retains stored words.
The host loads reachable firmware before execution. Its shared read port prepares
data on the falling core-clock edge. Host readback
requires software pause and literal loads consume two context grants.

Firmware and regression coverage demonstrate UART TX/RX with start-bit
qualification and framing status, SPI mode-0 byte
transfers, and single-master I2C writes with ACK/NACK and stretching. A packed
four-context program demonstrates concurrent operation. See [protocol scope](PROTOCOLS.md).

Python tools provide validated assembly encoders, a cycle model, a transport-
independent host driver, and demo-image generation. Tests compare RTL state
against the model every execution clock and independently inspect serial
waveforms. The CI test workflow runs both stdlib regressions and the pin-only
cocotb test. See [verification status](VERIFICATION.md) for actual run results.

Legacy standalone modules (`thread.v`, `host_if.v`, `prog_mem.v`, `dm.v`,
`gpio.v`, `bit_engine.v`, `edge_units.v`, `fifo.v`, and `timing.v`) remain
unconnected and are not in the Tiny Tapeout source list.

Local CMOS5L synthesis reports 58741.6914 um^2 of mapped logic plus a
28127.1040 um^2 SRAM footprint, totaling 86868.7954 um^2. This is approximately
77.4% smaller than the comparable 384634.2024 um^2 register-memory mapping.
Full-layout area and timing qualification are the next measurements.
See [area results](AREA_TIMING.md).

GitHub passed GDS hardening, precheck, gate-level simulation, and the viewer
on SG13G2 for commit `269b380`:
[passing Tiny Tapeout run](https://github.com/wlmoi/General-Purpose-Protocol-ASIC_JaneStreet/actions/runs/37646552561).
Detailed post-route area/timing metrics are not recorded here.

The current workflow follows the competition's CMOS5L template with
`TinyTapeout/tt-gds-action@ihp-cmos5l`, `pdk: ihp-sg13cmos5l`, and matching
CMOS5L gate-level simulation models. Commit `1649be6` passes SRAM-backed
GDS hardening, Tiny Tapeout precheck, and gate-level simulation:
[passing CMOS5L SRAM run](https://github.com/wlmoi/General-Purpose-Protocol-ASIC_JaneStreet/actions/runs/38425106175).
The final metrics record zero LVS errors, KLayout DRC errors, and power-grid
violations. The viewer publishes from the default branch.

The FPGA workflow selects a falling-edge synchronous program read using
JP_FPGA_SYNC_MEMORY. It maps the same 256-word program store into one ICE40
block RAM while retaining rising-edge execution and the host register map.
The 42-test regression suite covers SRAM, FPGA, and register-memory variants.
SRAM bit-mask and byte-write tests use the official IHP behavioral models.
The mapped SRAM design passes the pin-only gate-level test. Local OpenROAD
checks confirm connected SRAM supply columns. See [SRAM integration](SRAM.md).

Next verification milestones include timing closure at 50 MHz, formal proof, board testing,
streaming FIFOs, automatic pin-wait timeouts, trace capture, and advanced
protocol modes. The linked CI result applies to that commit; later RTL changes
must pass the flow again.


<!-- END ORIGINAL DOCUMENT -->


---

## SOURCE: `docs/ISA.md`

SHA256: `329a02b65aa7845a7ff287bbc3aee8fd11f215c948eec48e9f76a699851567d3`

<!-- BEGIN ORIGINAL DOCUMENT -->

# Implemented ISA

Instructions are 16-bit words with opcode in bits 15:12. Unless noted,
function is bits 11:9. All execution and waits are counted in context grants
(four enabled core clocks per grant). `tools/assembler.py` validates encodings.

| Opcode | Encoding and behavior |
|---|---|
| 0 | MOV imm8 into X; bit 8 selects Y instead. Zero extends. |
| 1 | Function 0: masked push-pull OUT, value=X[7:0], enable=Y[7:0]. Function 1: masked open-drain OUT, X bit 0 drives low and X bit 1 releases. Functions 2/3 apply the corresponding push-pull/open-drain behavior using imm8 instead of X; X is unchanged. |
| 2 | X := X op Y for functions 0 ADD, 1 SUB, 2 OR, 3 AND, 4 XOR. Functions 5/6 shift X left/right by one; 7 rotates X left by one. All results wrap to 16 bits. |
| 3 | Branch conditions: 0 always, 1 X==Y, 2 X!=Y, 3 X<Y unsigned, 4 X>Y unsigned, 6 X!=0. Signed 8-bit offset in bits 8:1 is relative to the next instruction. Function 7 HALT. Function 5 SIGNAL_ERROR sets the sticky error flag and advances. |
| 4 | Function 0 WAIT imm8: skip the next imm8 grants of this context. Function 1 WAIT_PIN: pin in bits 2:0, target level in bit 3; hold PC until the synchronized pin matches. |
| 7 | Function 0 IN: X := synchronized GPIO byte. Function 4 SAMPLE: shift receive register left and insert selected pin (bits 2:0) into bit 0. Function 5 SAMPLE_LSB: shift low receive byte right and insert pin into bit 7, clearing upper byte. Function 6 RECEIVE: copy receive register into X. |
| 9 | LDI: arm a literal load into X (bit 8=0) or Y (bit 8=1). The following word is fetched on the next grant of this context. Each grant advances PC by one; the operation consumes two grants. |

Other opcodes and unsupported functions set the issuing context's sticky error
and otherwise advance as a no-op. PC arithmetic wraps modulo 256, including
literal fetch at PC 255 and signed branches. Errors are exposed through host
status and can be cleared with a write-one-to-clear bitmap.

HALT leaves pin state intact. STOP is a host operation that halts selected
contexts and releases their owned pins. RESTART clears selected contexts'
X/Y, receive, wait, and error state, sets their PCs to the configured entry,
and marks them running; it retains ownership and pin state. To release pins
before restarting, issue STOP first.

The wait delay includes the WAIT instruction itself: after WAIT(N), the next
instruction executes N+1 grants later. The protocol generators account for
OUT/SAMPLE instruction overhead when constructing their bit periods.
There is no implicit event FIFO, timeout, carry flag, stack, or CSR instruction.


<!-- END ORIGINAL DOCUMENT -->


---

## SOURCE: `docs/PROJECT.md`

SHA256: `3569d826911912ddf618079f3876cdf349fe924019034cb1fc1a5a6c49d53677`

<!-- BEGIN ORIGINAL DOCUMENT -->

# JaneStreet Programmable Protocol Engine

Tiny Tapeout top module: `tt_um_igorchip`.

The project focuses on a programmable UART implementation for JaneStreet,
with SPI and I2C demonstrations on the same execution architecture to meet
the organizer's required protocol coverage. It uses the external Tiny Tapeout
clock and has no PLL dependency.

Project owner: [William Anthony](https://www.linkedin.com/in/wlmoi/)

Repository: [General-Purpose-Protocol ASIC JaneStreet](https://github.com/wlmoi/General-Purpose-Protocol-ASIC_JaneStreet)

See [design priorities](DESIGN_PRIORITIES.md) for Ben's organizer feedback and
the resulting implementation priorities.


<!-- END ORIGINAL DOCUMENT -->


---

## SOURCE: `docs/PROTOCOLS.md`

SHA256: `dfd302edfcb3f76f6f8d5a84b5bbdd02f18de198db9bc7072c442d873d758ea6`

<!-- BEGIN ORIGINAL DOCUMENT -->

# Protocols

`tools/protocols.py` generates firmware for the same integrated instruction
engine. The RTL has no UART-, SPI-, or I2C-specific datapath.

| Generator | Demonstrated behavior | Limits |
|---|---|---|
| uart_tx | One 8N1 frame, LSB first, programmable pin/period, idle-high retained | No continuous FIFO stream or parity |
| uart_rx | Idle-high arming, qualified start center, eight data-center samples, checked stop center, sticky framing status | One 8N1 frame per start command |
| spi_transfer | Mode 0, MSB-first byte, CS_n, programmable pins/period, MISO sampling | One byte; modes 1..3 not supplied |
| i2c_write | START, 7-bit address+W, one data byte, ACK sampling, STOP; SCL-high waits allow stretching | Single master, no read or arbitration; host STOP interrupts stuck pin waits |

I2C branches to STOP on a NACK rather than transmitting the next byte. ACK bits
are shifted into the receive register; zero means the completed address/data
phases were acknowledged. A nonzero result indicates NACK; it does not identify
whether the address or data was rejected. No automatic retry is performed.

`python -m tools.build_demo` packs four contexts into one 256-word image: UART
RX, UART TX, I2C write, and SPI transfer. The combined RTL regression executes
all four concurrently (254/256 words) and checks received results and preservation of other
contexts' outputs. UART TX/RX, SPI transfer, I2C ACK/stretching, and I2C NACK
handling also have separate wire-level checks.
The demo defaults to 115200-baud UART timing at 50 MHz. Its `contexts.json`
records the core clock, requested baud, actual baud, and UART grant period.
For a 12 MHz FPGA clock, generate with `--clock-hz 12000000 --uart-baud 115200`.

## UART receive acceptance

UART RX first observes idle high, then detects a low start. At half a bit
period it checks that the line remains low. A short start pulse returns to
idle detection. Valid starts lead to eight LSB-first data samples at bit centers.
The stop-bit center must be high. A low stop center executes SIGNAL_ERROR and
HALT, exposing a sticky error through the host STATUS register.

Wait for the context's running bit to clear and inspect its error bit before
accepting RECEIVED as a valid byte. RESTART clears the receive and error state
for the next frame. STOP provides host control over a prolonged idle-line wait.

`uart_bit_grants(clock_hz, baud_rate, receive=True)` selects an even grant count
for both TX and RX. The selected baud rate is within a 2% budget of the request.
At 50 MHz, 108 grants yields approximately 115741 baud for a 115200-baud peer.
Use a core clock and period supported by the attached device and validate
electrical timing on the board. Tests cover start glitches, framing status,
0x00/0xFF/0x55/0xAA data, GPIO reassignment, asynchronous start phases, and
peer bit periods from 424 to 440 clocks against a 432-clock receiver.

These are simulation demonstrations, not board or protocol-certification
results. Electrical interfaces and exact timing must be checked for the
selected peer. JTAG, SWD, CAN, USB, Manchester, and Ethernet are not demonstrated
by this integrated implementation.


<!-- END ORIGINAL DOCUMENT -->


---

## SOURCE: `docs/SRAM.md`

SHA256: `186880e1ab9e0653e78040cc2877dd405a682ec819350fd9c89c9fd98673cf21`

<!-- BEGIN ORIGINAL DOCUMENT -->

# IHP SRAM integration

For the complete reproduction procedure, exact configuration and source
snapshots, use the [SRAM implementation guide](SRAM_IMPLEMENTATION_GUIDE.md).

The ASIC stores firmware in one **RM_IHPSG13_1P_256x16_c2_bm_bist** macro.
Its 256 words of 16 bits provide 512 bytes, matching the existing host address
map and four-context scheduler. UART, SPI, and I2C firmware use the same storage.

## RTL and programming

[src/program_memory.v](../src/program_memory.v) connects the real macro.
[src/sram_256x16_bb.v](../src/sram_256x16_bb.v) supplies its synthesis declaration.
The instance becomes `program_store.i_sram` after flattening.

| Signal | Connection |
|---|---|
| A_CLK | Inverted core clock |
| A_MEN | rst_n |
| A_ADDR | Selected context PC or paused host word address |
| A_WEN | Protected host DATA write strobe |
| A_REN | Read when the write strobe is clear |
| A_DIN | Host byte replicated into both byte lanes |
| A_BM | 0x00FF for low-byte writes or 0xFF00 for high-byte writes |
| A_DLY | Logic one |
| BIST inputs | Logic zero |

Falling-edge reads prepare instructions for rising-edge execution, preserving
the existing four-clock context cadence. Masked writes preserve the other byte.
Reset halts execution and retains memory contents. Load every reachable
instruction and literal before starting a newly powered device.

`JP_FPGA_SYNC_MEMORY` selects one ICE40 block RAM. `JP_REGISTER_MEMORY` selects
the register-array reference. The host interface and instruction set remain
consistent across these implementations.

## Physical views and placement

The configuration uses the installed PDK's SRAM LEF, GDS, CDL, and three
Liberty views. Tiny Tapeout's pinned IHP revision is
`2bbec755dc67ca3db0261c3d6163e15735d66710`. Its CMOS5L SRAM directory links
to the shared SG13G2 SRAM library.

The macro footprint is **236.8 by 118.78 micrometers**. Placement uses
orientation N at **(300.0, 34.02)** with an eight-micrometer placement halo.
This creates a 30.24-micrometer channel between its bottom-edge signal pins
and the core boundary. The installed LEF defines routing obstructions and
pin-access openings. The flow uses these shapes directly.
The standard Tiny Tapeout top-level interface and six-by-four tile allocation
remain in the project manifest.

The nominal views use typical 1.20 V at 25 C and slow 1.08 V at 125 C.
The flow's fast m40C corner selects the available SRAM fast 1.32 V m55C
characterization. Review this temperature pairing alongside full-flow timing
qualification for the selected shuttle. Both memory input and execution paths
have a half-cycle timing budget.

## Power integration

The macro exposes VDD!, VDDARRAY!, and VSS! on Metal4. Both positive supplies
connect to VPWR and ground connects to VGND. Tiny Tapeout generates these
global supply names through VDD_PIN and GND_PIN. The standard-cell pins
VDD and VSS connect through the flow's global rules. The PDN scripts read
VDD_NET and GND_NET from LibreLane, keeping the grid and connectivity
checks aligned with its resolved supply configuration.

[src/sram_geometry.tcl](../src/sram_geometry.tcl) reads the supply-column
positions from the installed LEF, including the irregular middle band.
[src/pdn_cfg.tcl](../src/pdn_cfg.tcl) aligns 2.1-micrometer Metal4 stripes
with the macro and retains the ordinary standard-cell grid elsewhere.

The root LibreLane plugin inserts `Project.PowerProgramSRAM` immediately
after `OpenROAD.GeneratePDN`. [src/power_sram.tcl](../src/power_sram.tcl)
extends the 20 power and 20 ground columns through the macro abstraction
to the tile boundaries. Supply-connectivity errors stop the flow.

The SRAM LEF contains an abstract supply bar that can trigger the generic
overlap checker and Magic's abstract-macro DRC. The configuration disables
those checks and enables **KLayout DRC** for the assembled geometry.
LVS, power connectivity, and Tiny Tapeout precheck remain part of the flow.
This configuration follows the supplied guide's distinction between abstract
LEF supply geometry and the physical macro GDS.

## Verification evidence

- The complete 42-test SRAM regression passes, including differential execution
  and independent UART, SPI, and I2C waveform checks.
- Two dedicated SRAM tests use unchanged official IHP behavioral models and
  check masks, byte preservation, enables, output hold, edge timing, and reset.
- The mapped SRAM netlist passes the pin-only gate-level Makefile regression
  with official CMOS5L cell models and Tiny Tapeout Icarus 13.
- A real-LEF OpenROAD fixture passes both supply-connectivity checks after
  executing the repository's PDN and SRAM power scripts.
- The FPGA implementation rebuilds through routing and bitstream packing.

The local fixture validates supply geometry and connectivity. Commit `1649be6`
passes complete-chip LVS, KLayout DRC, Tiny Tapeout precheck, and gate-level
simulation in the [official CMOS5L SRAM run](https://github.com/wlmoi/General-Purpose-Protocol-ASIC_JaneStreet/actions/runs/38425106175).
Final LVS, DRC, and power-grid error counts are zero. Timing closure at the
50 MHz target and board validation remain the next qualification stages.

## References

- [Tiny Tapeout memory guidance](https://tinytapeout.com/specs/memory/)
- [Pinned IHP SRAM library](https://github.com/IHP-GmbH/IHP-Open-PDK/tree/2bbec755dc67ca3db0261c3d6163e15735d66710/ihp-sg13g2/libs.ref/sg13g2_sram)
- [OpenROAD PDN generation](https://openroad.readthedocs.io/en/latest/main/src/pdn/README.html)
- [Area measurements](AREA_TIMING.md)
- [Verification details](VERIFICATION.md)

## Routing runtime and diagnostic artifacts

The previous build reached detailed routing and the hosted runner's six-hour
limit with about 4000 remaining spacing and short violations. The revised
floorplan gives the SRAM signal pins a wider escape channel and retains
the LEF's access windows. A 40% placement target spreads standard cells,
and global routing requires a congestion-free result before detailed routing.

Detailed routing uses two explicit threads and up to 20 optimization
iterations. DRC reports are saved every five iterations. The normal detailed
routing, KLayout DRC, LVS, and Tiny Tapeout precheck acceptance checks
continue to qualify the result. A finite search budget preserves useful
failure reports for the next correction.

The GDS build step has a 150-minute limit inside a 180-minute job, reserving
time for the separate diagnostic upload. The gds-diagnostics artifact includes
logs, routing reports, configuration, guides, and OpenROAD databases even
when the build step fails. New runs replace older runs on the same branch.
Successful builds provide the submission and viewer artifacts as usual.

## LVS interface

[src/sram_256x16_lvs.spice](../src/sram_256x16_lvs.spice) provides an abstract
109-pin interface derived from the official LEF. Contiguous descending bus
order enables Netgen vector inference. EXTRA_SPICE_MODELS loads this view
before the powered top-level netlist. This checks integration wiring around
the foundry macro.

The plugin replaces Netgen.LVS with Project.ProgramSRAMLVS and retains the
normal Checker.LVS. A local input copy normalizes only the SRAM's escaped
VDD!, VDDARRAY!, and VSS! pin tokens for Netgen's Verilog reader. All nodes,
connections, and original flow netlists are preserved.

When Netgen emits unsupported identifier escapes in its JSON report, the
compatibility handler retains the raw file as lvs.netgen.json.original and
repairs the escape encoding before the standard metrics parser runs.
Structural errors and circuit mismatches continue to fail validation.
Diagnostic artifacts include the original JSON and adapted LVS input.

Local Netgen interface checks pass for correct wiring and reject an array
supply connected to ground. Complete-chip LVS remains part of the official
physical-flow acceptance checks.

## Signal-pin clearance

Run 38401026075 placed SRAM-aligned power columns across the fixed Metal4
signal-pin bank. The actual reports showed 16 M4.b spacing/notch violations
at the top edge and signal nets merged into VPWR and VGND during extraction.

The macro origin is now (300.0, 34.02) micrometers. Its supply columns are
outside the fixed I/O bank. The shared geometry helper checks every Metal4
signal boundary-pin rectangle with 0.5-micrometer clearance. A conflicting
macro location stops the flow. Ordinary grid columns skip these corridors.

Run 38420015169 cleared the power-grid checker and KLayout DRC. Its remaining
LVS shorts exposed a flow-order dependency. Classic applied the official DEF
template after PDN generation, so the signal pins had no coordinates when
the ordinary columns were selected. The configuration now applies that
template immediately before PDN generation. The geometry helper requires
placed signal pins before calculating either set of supply columns.

After extension, both supply checks must pass before the step refreshes
the power-grid violation metrics. The earlier failed grid describes the
pre-extension geometry. The final checker reads the verified extended result.

The old position fails the local guard. The new position passes with the
complete mapped engine and all 43 Tiny Tapeout pins. Program word addresses
remain 0 through 255, independent of the macro's layout origin.


<!-- END ORIGINAL DOCUMENT -->


---

## SOURCE: `docs/SRAM_IMPLEMENTATION_GUIDE.md`

SHA256: `2b3a84ad4e8b616dbd1be9c96bf2dffe7241d940afc339293da7e51a006b9ff9`

<!-- BEGIN ORIGINAL DOCUMENT -->

# Reproducible SRAM integration guide

**Target:** Tiny Tapeout IHP SG13CMOS5L, LibreLane, one 256 x 16-bit program SRAM.

**Reference date:** 14 October 2026.

This guide specifies the implementation used by the programmable UART, SPI,
and I2C engine in this repository. It includes the working source revision,
macro views, RTL contract, simulation setup, physical configuration, power
connections, LVS compatibility, host programming, acceptance checks, and
failure recovery. The source snapshots at the end provide the complete
integration files.

An agent should reproduce the reference implementation first, then adapt one
dimension at a time and rerun the affected acceptance stages. Treat the exact
macro, hierarchy, process, units, supply names, and clock phase as a single
integration contract.

## Contents

1. [Passing reference and completion criteria](#1-passing-reference-and-completion-criteria)
2. [Files and ownership](#2-files-and-ownership)
3. [Prepare the environment](#3-prepare-the-environment)
4. [Verify the macro views](#4-verify-the-macro-views)
5. [Implement the RTL contract](#5-implement-the-rtl-contract)
6. [Compile the correct simulation models](#6-compile-the-correct-simulation-models)
7. [Configure the physical macro](#7-configure-the-physical-macro)
8. [Place interface pins before the power grid](#8-place-interface-pins-before-the-power-grid)
9. [Connect all SRAM supplies](#9-connect-all-sram-supplies)
10. [Run integration LVS](#10-run-integration-lvs)
11. [Program an exact SRAM address](#11-program-an-exact-sram-address)
12. [Run the full verification sequence](#12-run-the-full-verification-sequence)
13. [Build GDS and preserve diagnostics](#13-build-gds-and-preserve-diagnostics)
14. [Publish and verify the viewer](#14-publish-and-verify-the-viewer)
15. [Qualify timing and external interfaces](#15-qualify-timing-and-external-interfaces)
16. [Diagnose failures by stage](#16-diagnose-failures-by-stage)
17. [Adapt the design to another macro](#17-adapt-the-design-to-another-macro)
18. [Agent handoff and evidence record](#18-agent-handoff-and-evidence-record)
19. [Source snapshots and integrity manifest](#19-source-snapshots-and-integrity-manifest)

## 1. Passing reference and completion criteria

Use this immutable source revision as the reference:

~~~text
Repository: https://github.com/wlmoi/General-Purpose-Protocol-ASIC_JaneStreet
Commit: b08afad42ed7179eee4a276634ee7b4cefae4f6c
Top: tt_um_igorchip
Macro: RM_IHPSG13_1P_256x16_c2_bm_bist
Flattened instance: program_store.i_sram
PDK: ihp-sg13cmos5l
PDK source commit: 2bbec755dc67ca3db0261c3d6163e15735d66710
Tiny Tapeout action commit: 3412659307918422f3f0727917cf9b499aaca588
tt-support-tools commit: d66cf179e7bc4d296362ab7e2e3b344dc3c4f665
LibreLane: 3.1.0.dev3
~~~

The [reference main-branch GDS run](https://github.com/wlmoi/General-Purpose-Protocol-ASIC_JaneStreet/actions/runs/38483354858)
passes hardening, Tiny Tapeout precheck, gate-level simulation, and viewer
deployment. The same revision passes
[RTL tests](https://github.com/wlmoi/General-Purpose-Protocol-ASIC_JaneStreet/actions/runs/38483354928),
[FPGA implementation](https://github.com/wlmoi/General-Purpose-Protocol-ASIC_JaneStreet/actions/runs/38483354863),
and [documentation generation](https://github.com/wlmoi/General-Purpose-Protocol-ASIC_JaneStreet/actions/runs/38483354909).

The preceding [SRAM integration run for 1649be6](https://github.com/wlmoi/General-Purpose-Protocol-ASIC_JaneStreet/actions/runs/38425106175)
also passes hardening, precheck, and gate-level simulation. Its final reports
record zero LVS errors, zero KLayout DRC errors, and zero power-grid
violations. Its viewer job is intentionally gated to the default branch.

| Acceptance stage | Required evidence |
|---|---|
| Memory behavior | Foundry-model mask, byte preservation, enable, clock-edge, and reset tests pass |
| Engine behavior | Cycle differential tests and independent UART, SPI, and I2C peers pass |
| Synthesis | Exactly one physical SRAM instance remains in the ASIC netlist |
| Placement | Correct master, N orientation, legal footprint, halo, and placed interface pins |
| Power | All three macro supplies have the intended nets and both extended grids pass connectivity |
| Layout | Detailed routing and KLayout DRC pass |
| Connectivity | Netgen reports a unique circuit match and the normal LVS checker passes |
| Submission | Tiny Tapeout precheck and the generated-netlist simulation pass |
| Viewer | Deployment succeeds and the published model contains the SRAM |
| Timing qualification | Setup, hold, slew, and capacitance meet the intended operating conditions |
| Board qualification | Actual programming and protocol waveforms are measured on the selected hardware |

The passing physical flow establishes the geometry and integration stages.
Timing repair at the 50 MHz target and board measurements are separate
qualification stages. Keep these distinctions in every status report.

The reference uses 256 instruction words, totaling 512 bytes. Four execution
contexts share this single physical memory port.

## 2. Files and ownership

| File | Role |
|---|---|
| [info.yaml](../info.yaml) | Tiny Tapeout top, tile allocation, pin descriptions, and RTL manifest |
| [src/igorchip_top.v](../src/igorchip_top.v) | Scheduler, instruction execution, host registers, address arbitration, and write protection |
| [src/program_host.v](../src/program_host.v) | Synchronized host SPI transport |
| [src/program_memory.v](../src/program_memory.v) | Physical macro wrapper and alternate FPGA/reference implementations |
| [src/sram_256x16_bb.v](../src/sram_256x16_bb.v) | Synthesis black-box declaration |
| [src/defines.vh](../src/defines.vh) | Eight-bit program address width |
| [tools/config.py](../tools/config.py) | Matching Python program depth of 256 |
| [src/config.json](../src/config.json) | Macro views, corners, placement, flow substitutions, and physical checks |
| [src/sram_geometry.tcl](../src/sram_geometry.tcl) | Actual LEF power-column extraction and interface-pin clearance guards |
| [src/pdn_cfg.tcl](../src/pdn_cfg.tcl) | Standard-cell rails and SRAM-aligned Metal4 stripes |
| [src/power_sram.tcl](../src/power_sram.tcl) | Supply extension through the macro abstraction and connectivity checks |
| [librelane_plugin_program_sram.py](../librelane_plugin_program_sram.py) | Registered LibreLane power and LVS steps |
| [src/sram_256x16_lvs.spice](../src/sram_256x16_lvs.spice) | Complete abstract physical pin interface for integration LVS |
| [tools/netgen_json.py](../tools/netgen_json.py) | Scoped Netgen input and report compatibility |
| [test/ihp_sram/README.md](../test/ihp_sram/README.md) | Provenance of the unchanged foundry simulation models |
| [test/test_sram.py](../test/test_sram.py) | Macro and wrapper behavior tests |
| [test/test_rtl.py](../test/test_rtl.py) | Engine differential, protocol, and host-access tests |
| [test/test_netgen_json.py](../test/test_netgen_json.py) | LVS compatibility tests |
| [test/Makefile](../test/Makefile) | RTL and gate-level simulation source selection |
| [tools/host.py](../tools/host.py) | Bounded load, verification, readback, and context control |
| [.github/workflows/gds.yaml](../.github/workflows/gds.yaml) | Hardening, diagnostics, precheck, gate-level simulation, and viewer |
| [.github/workflows/test.yaml](../.github/workflows/test.yaml) | Three storage-variant regressions and pin-only cocotb |
| [.github/workflows/fpga.yaml](../.github/workflows/fpga.yaml) | ICE40 block-RAM selection and bitstream checks |

Preserve the relationships between these files. Changing only the macro
instantiation leaves the physical views, supply routing, and LVS interface
unfinished.

The source snapshots cover the SRAM integration layer. The immutable
repository revision supplies the surrounding engine, host transport,
firmware tools, test peers, and Tiny Tapeout metadata.

Use the active manifest and `src/igorchip_top.v` to determine implemented
behavior. The source directory also contains earlier standalone modules
retained for history. The active instruction encodings are implemented in
the current top and `tools/assembler.py`.

## 3. Prepare the environment

### 3.1 Reproduce in a fresh checkout

Run these Bash commands in a fresh Linux directory:

~~~bash
git clone https://github.com/wlmoi/General-Purpose-Protocol-ASIC_JaneStreet.git protocol-asic-sram
cd protocol-asic-sram
git checkout --detach b08afad42ed7179eee4a276634ee7b4cefae4f6c
git status --short
git rev-parse HEAD
~~~

Expected: a clean working tree and the exact reference commit. A fresh
checkout preserves work in another checkout. For development, create an
ordinary working branch after recording the reference revision.

Use a simple Linux path such as `/home/user/protocol-asic-sram` for physical
tools. Several upstream Tcl and subprocess command generators are sensitive
to whitespace in paths. Windows can run the RTL and host tests with Python,
Icarus Verilog, and `vvp` on `PATH`.

### 3.2 RTL tools

The test environment uses Python 3.11 or later, Icarus Verilog, and cocotb
2.0.1. Install the repository requirements:

~~~bash
python3 -m venv .venv
source .venv/bin/activate
python -m pip install -r test/requirements.txt
python --version
iverilog -V
vvp -V
~~~

On PowerShell:

~~~powershell
python -m venv .venv
.\.venv\Scripts\python.exe -m pip install -r test/requirements.txt
.\.venv\Scripts\python.exe --version
iverilog -V
vvp -V
~~~

The reference CI uses Ubuntu 24.04. The physical action supplies the
LibreLane tool environment. Recorded hardening tools include Yosys 0.66,
Magic 8.3.674, and Netgen 1.5.320. Local area estimates in the older
measurement notes use Yosys 0.33, and selected local LVS fixtures use Netgen
1.5.270. Keep local fixture versions separate from the CI flow versions.

Magic's pinned CMOS5L technology file requires a sufficiently recent
extractor. The recorded 8.3.674 version satisfies that requirement. Fetch
the complete technology setup, including its include files.

### 3.3 Recommended physical build route

Use the existing GitHub GDS workflow for the reference acceptance run.
It installs the applicable PDK, generates the Tiny Tapeout configuration,
and invokes the supported LibreLane container flow.

The action's `ihp-cmos5l` ref is a moving branch. The passing reference
resolved it to `3412659307918422f3f0727917cf9b499aaca588`. For an immutable
reproduction in a separate repository, use that SHA in the action reference.
Record the resolved action and support-tool SHAs for later runs.

### 3.4 Optional local physical build

Install Docker using its official installation procedure and verify that
`docker info` succeeds. The pinned support tool invokes LibreLane's
container mode by default. Its `--no-docker` option is for an environment
that already provides the matching native EDA tools.

From the fresh repository root:

~~~bash
git clone https://github.com/TinyTapeout/tt-support-tools.git tt
git -C tt checkout --detach d66cf179e7bc4d296362ab7e2e3b344dc3c4f665
git clone https://github.com/TinyTapeout/tt-gds-action.git build/action-reference
git -C build/action-reference checkout --detach 3412659307918422f3f0727917cf9b499aaca588
python -m pip install -r tt/requirements.txt
python -m pip install librelane==3.1.0.dev3
export PDK_ROOT="$PWD/build/pdk-reference"
export PDK=ihp-sg13cmos5l
bash build/action-reference/install_sg13cmos5l.sh
./tt/tt_tool.py --create-user-config --ihp
~~~

Choose an empty, dedicated `PDK_ROOT`. The pinned installer initializes an
IHP-Open-PDK Git checkout there and selects its exact source revision. It
creates `ihp-sg13cmos5l/SOURCES` with the provenance.

The generated `src/user_config.json` supplies the top, source files, die
area, official pin template, `VPWR`, and `VGND`. The support tool merges it
with `src/config.json` into `src/config_merged.json`.

Expected after configuration generation:

~~~text
DESIGN_NAME = tt_um_igorchip
VDD_PIN = VPWR
GND_PIN = VGND
FP_DEF_TEMPLATE = the supplied six-by-four Tiny Tapeout DEF
VERILOG_FILES = the active info.yaml source manifest
~~~

The local hardening command is:

~~~bash
./tt/tt_tool.py --harden --ihp
~~~

The support tool creates a fresh `runs/wokwi` for each hardening invocation.
Archive needed reports and layout files before repeating that command.
Run configuration generation and hardening from the repository root.

## 4. Verify the macro views

The pinned installer fetches the complete IHP-Open-PDK repository. Its
`ihp-sg13cmos5l/libs.ref/sg13cmos5l_sram` directory links to the shared
SG13G2 SRAM library. Keeping both process directories makes that link resolve.

Required installed files, relative to the CMOS5L SRAM directory:

~~~text
lef/RM_IHPSG13_1P_256x16_c2_bm_bist.lef
gds/RM_IHPSG13_1P_256x16_c2_bm_bist.gds
cdl/RM_IHPSG13_1P_256x16_c2_bm_bist.cdl
lib/RM_IHPSG13_1P_256x16_c2_bm_bist_typ_1p20V_25C.lib
lib/RM_IHPSG13_1P_256x16_c2_bm_bist_fast_1p32V_m55C.lib
lib/RM_IHPSG13_1P_256x16_c2_bm_bist_slow_1p08V_125C.lib
~~~

Each view serves a different purpose:

| View | Purpose |
|---|---|
| LEF | Footprint, physical pin names, pin rectangles, and routing obstructions |
| GDS | Fabrication geometry included in the assembled layout |
| Liberty | Timing arcs, pin capacitances, clock relationships, and operating corners |
| CDL | Official macro circuit view and provenance |
| Behavioral Verilog | Clocked functional simulation and bit-mask behavior |
| Synthesis declaration | A retained hard macro with named functional ports |
| Abstract LVS SPICE | Physical port declaration for checking integration connections |

Run this check after installing the PDK:

~~~python
import os
import re
from pathlib import Path

macro = "RM_IHPSG13_1P_256x16_c2_bm_bist"
root = Path(os.environ["PDK_ROOT"]) / "ihp-sg13cmos5l"
sram = root / "libs.ref" / "sg13cmos5l_sram"
required = [
    f"lef/{macro}.lef",
    f"gds/{macro}.gds",
    f"cdl/{macro}.cdl",
    f"lib/{macro}_typ_1p20V_25C.lib",
    f"lib/{macro}_fast_1p32V_m55C.lib",
    f"lib/{macro}_slow_1p08V_125C.lib",
]
for relative in required:
    path = sram / relative
    assert path.is_file(), path
    assert path.stat().st_size > 0, path
lef = (sram / f"lef/{macro}.lef").read_text()
pins = re.findall(r"^\s*PIN\s+(\S+)", lef, re.MULTILINE)
assert len(pins) == 109, len(pins)
assert {"VDD!", "VDDARRAY!", "VSS!"}.issubset(pins)
assert re.search(r"SIZE\s+236\.8\s+BY\s+118\.78\s*;", lef)
print("All macro views present, 109 physical pins, expected footprint")
~~~

Inspect the actual files when adapting this recipe. The guide's geometry
and interface are specific to this macro and PDK revision.

## 5. Implement the RTL contract

### 5.1 Geometry and hierarchy

~~~text
Depth: 256 words
Word width: 16 bits
Total capacity: 4096 bits = 512 bytes
Word address width: 8 bits
Host byte address width: 9 bits
Macro instance in program_memory: i_sram
program_memory instance in the top: program_store
Flattened physical instance: program_store.i_sram
~~~

Keep `JP_PROG_AW = 8` in `src/defines.vh` and `PROGRAM_DEPTH = 256` in
`tools/config.py`. The host identification register returns `0xA7`, and
`PROGRAM_AW` returns eight.

The top retains the standard Tiny Tapeout digital interface:

~~~text
ui_in[7:0]
uo_out[7:0]
uio_in[7:0]
uio_out[7:0]
uio_oe[7:0]
ena
clk
rst_n
~~~

The physical flow adds and connects the supply terminals. Keep the functional
top and the official 43-signal pin template aligned.

### 5.2 Every functional macro port

| Port | Width | Connection | Meaning |
|---|---:|---|---|
| A_CLK | 1 | `~clk` | Active macro edge is the falling core-clock edge |
| A_MEN | 1 | `rst_n` | Active-high memory enable |
| A_WEN | 1 | Protected host write strobe | Active-high masked write |
| A_REN | 1 | `!write_enable` | Active-high read during read cycles |
| A_ADDR | 8 | Shared selected word address | Addresses words 0 through 255 |
| A_DIN | 16 | `{write_data, write_data}` | Host byte appears in both lanes |
| A_BM | 16 | `16'h00FF` or `16'hFF00` | A one selects a bit for writing |
| A_DLY | 1 | `1'b1` | Tested delay-control setting |
| A_DOUT | 16 | `read_data` | Registered macro read output |
| A_BIST_CLK | 1 | `1'b0` | BIST input tied low |
| A_BIST_EN | 1 | `1'b0` | Functional memory mode |
| A_BIST_MEN | 1 | `1'b0` | BIST memory enable tied low |
| A_BIST_WEN | 1 | `1'b0` | BIST write enable tied low |
| A_BIST_REN | 1 | `1'b0` | BIST read enable tied low |
| A_BIST_ADDR | 8 | `8'd0` | BIST address tied low |
| A_BIST_DIN | 16 | `16'd0` | BIST data tied low |
| A_BIST_BM | 16 | `16'd0` | BIST mask tied low |

The physical LEF adds `VDD!`, `VDDARRAY!`, and `VSS!`. The 106 functional
bits plus these three supplies make the 109 physical port names.

### 5.3 Clock phase and arbitration

The selected memory address is:

~~~verilog
wire [7:0] memory_address =
    core_enabled ? active_pc : byte_address[8:1];
wire memory_write =
    rst_n && host_write && host_address == 4 && !core_enabled;
~~~

These lines explain the integration contract. Use the complete top from the
reference source for signal declarations and host sequencing.

| Core-clock phase | Action |
|---|---|
| Just after a rising edge | The scheduler and selected address settle for the next operation |
| Next falling edge | The macro reads or performs the protected masked write |
| Following rising edge | Execution consumes the prepared instruction |

Each context receives one grant every four enabled core clocks. A literal
instruction obtains its following word on that context's next grant. Host
program reads use the same port while software execution is paused.

Hold address, mask, data, and enable signals stable across the active SRAM
edge. Verify both address-to-SRAM and SRAM-to-execution timing paths.

### 5.4 Byte writes and initialization

Low-byte writes use mask `0x00FF`. High-byte writes use `0xFF00`. Both carry
the host byte in `A_DIN[15:8]` and `A_DIN[7:0]`, with the mask selecting the
intended lane.

Example:

~~~text
Initial word             0xA55A
Write low byte 0x3C      0xA53C
Write high byte 0x81     0x813C
~~~

Power-up contents are unspecified. Load every reachable instruction and
literal before execution. Reset clears engine control and ownership state.
The enabled SRAM retains previously written contents through the tested
logical reset sequence. Power-cycle retention is a separate electrical matter.

### 5.5 Storage selection

| Build | Definitions | Implementation |
|---|---|---|
| ASIC synthesis | Default storage selection | Real IHP macro and synthesis declaration |
| ASIC functional simulation | `SIM` and `FUNCTIONAL` | Official IHP SRAM behavioral models |
| FPGA | `JP_FPGA_SYNC_MEMORY` | One ICE40 block RAM |
| Register reference | `JP_REGISTER_MEMORY` | Register-array implementation for comparison |

Choose one storage implementation for each build. The ASIC physical flow
expects the hard macro. The FPGA workflow appends its definition only in
that job's checkout.

## 6. Compile the correct simulation models

The two required files are:

~~~text
test/ihp_sram/RM_IHPSG13_1P_core_behavioral_bm_bist.v
test/ihp_sram/RM_IHPSG13_1P_256x16_c2_bm_bist.v
~~~

They are copied unchanged from the
[pinned IHP model directory](https://github.com/IHP-GmbH/IHP-Open-PDK/tree/2bbec755dc67ca3db0261c3d6163e15735d66710/ihp-sg13g2/libs.ref/sg13g2_sram/verilog).
Retain their copyright and Apache-2.0 notices.

Compile with `-DSIM -DFUNCTIONAL`. `SIM` excludes the synthesis-only black
box. The behavioral core and macro-specific model supply the real functional
simulation implementation.

The active `info.yaml` source list is:

~~~yaml
source_files:
  - "defines.vh"
  - "igorchip_top.v"
  - "program_host.v"
  - "program_memory.v"
  - "sram_256x16_bb.v"
~~~

The full `test/Makefile` appears in the source snapshots. Its gate-level
mode includes the CMOS5L standard-cell Verilog, companion UDP definitions,
I/O models, both SRAM models, the generated gate netlist, and `test/tb.v`.

Expected semantic tests include:

| Test | Expected observation |
|---|---|
| Complete masked word write | Readback equals the written word |
| Partial bit mask | Selected bits change and the other bits retain their value |
| Low-byte patch | High byte is preserved |
| High-byte patch | Low byte is preserved |
| A_MEN low | Write is inhibited and output retains its preceding value |
| A_REN low | Output retains its preceding value |
| Wrapper address change | Output updates at the intended falling core-clock edge |
| Logical reset sequence | Stored word remains readable after reset release |

Gate-level functional simulation checks connectivity and logic behavior.
The separate STA reports qualify physical timing.

## 7. Configure the physical macro

Copy the complete reference `src/config.json` from the source snapshots.
Its `MACROS` entry supplies all physical and timing views.

| Flow corner | SRAM characterization file |
|---|---|
| nom_typ_1p20V_25C | typ_1p20V_25C |
| nom_fast_1p32V_m40C | fast_1p32V_m55C |
| nom_slow_1p08V_125C | slow_1p08V_125C |

The fast flow corner selects the available m55C SRAM characterization.
Record this temperature pairing in timing review and qualify it against the
selected shuttle's requirements.

The reference physical geometry is:

| Property | Value |
|---|---|
| Tiny Tapeout allocation | 6 x 4 tiles |
| Die bounds | (0, 0) to (1289.28, 710.64) micrometers |
| SRAM size | 236.8 x 118.78 micrometers |
| SRAM origin | (300.0, 34.02) micrometers |
| SRAM upper-right corner | (536.8, 152.80) micrometers |
| Orientation | N, represented as R0 in OpenDB |
| Horizontal placement halo | 8 micrometers |
| Vertical placement halo | 8 micrometers |
| Database units | 1000 per micrometer |
| Placement density target | 40 percent |
| Maximum project routing layer | Metal4 |

The macro's bottom-edge signal pins have a 30.24-micrometer channel to the
reference core boundary. The LEF obstructions and access openings guide the
router directly.

`MACROS.instances` names the flattened instance exactly. A changed
hierarchy needs corresponding updates to the macro placement, connection
rules, geometry helper, and scoped LVS adapter.

## 8. Place interface pins before the power grid

This ordering is essential. The default Classic flow applies the pin
template later than PDN generation. The reference first removes that later
step, then inserts it before the grid:

~~~json
{
  "meta": {
    "flow": "Classic",
    "substituting_steps": {
      "Odb.ApplyDEFTemplate": null,
      "-OpenROAD.GeneratePDN": "Odb.ApplyDEFTemplate",
      "+OpenROAD.GeneratePDN": "Project.PowerProgramSRAM",
      "Netgen.LVS": "Project.ProgramSRAMLVS"
    }
  }
}
~~~

Dictionary order matters during substitution. Removing the original
template step before inserting its replacement creates exactly one
template-application step.

Required relative ordering:

~~~text
Odb.ApplyDEFTemplate
OpenROAD.GeneratePDN
Project.PowerProgramSRAM
...
Magic.SpiceExtraction
Project.ProgramSRAMLVS
Checker.LVS
~~~

The geometry helper checks that every signal boundary terminal has placed
pin geometry. Accepted placement statuses are `PLACED`, `FIRM`, or
`LOCKED`. Missing geometry raises an error before selecting supply columns.

To inspect the substituted flow with LibreLane installed:

~~~python
import json
from pathlib import Path
import librelane_plugin_program_sram
from librelane.flows import Flow

config = json.loads(Path("src/config.json").read_text())
flow_type = Flow.factory.get("Classic").Substitute(
    config["meta"]["substituting_steps"]
)
ids = [step.id for step in flow_type.Steps]
assert ids.count("Odb.ApplyDEFTemplate") == 1
assert ids.index("Odb.ApplyDEFTemplate") < ids.index("OpenROAD.GeneratePDN")
assert ids[ids.index("OpenROAD.GeneratePDN") + 1] == "Project.PowerProgramSRAM"
assert ids.index("Project.ProgramSRAMLVS") < ids.index("Checker.LVS")
print("Template, power-extension, and LVS order verified")
~~~

The plugin filename begins with `librelane_plugin_`. LibreLane discovers
modules with that prefix on its Python import path. Keep the root plugin
and the `tools` package accessible from the repository root.

## 9. Connect all SRAM supplies

### 9.1 Net names and physical pin names

| Object | Power | Ground |
|---|---|---|
| Tiny Tapeout global nets | VPWR | VGND |
| Standard-cell physical pins | VDD | VSS |
| SRAM peripheral supply | VDD! connected to VPWR | VSS! connected to VGND |
| SRAM array supply | VDDARRAY! connected to VPWR | VSS! connected to VGND |

The pinned support tool sets `VDD_PIN = VPWR` and `GND_PIN = VGND`.
LibreLane's power-net setup derives `VDD_NET` and `GND_NET`. Every
independent OpenROAD step resolves those values again.

The required configuration rules are:

~~~json
{
  "PDN_MACRO_CONNECTIONS": [
    "program_store\\.i_sram VPWR VGND VDD! VSS!",
    "program_store\\.i_sram VPWR VGND VDDARRAY! VSS!"
  ]
}
~~~

The backslash in the JSON string is escaped as `\\`. The resulting
regular expression matches the literal dot in the hierarchy.

### 9.2 Derive columns from the actual LEF

`jp_sram_columns` verifies:

1. The macro instance exists.
2. Its master name is correct.
3. Its orientation is R0.
4. All three supply terminals have their intended nets.
5. Every supply shape is on Metal4 and has sufficient width.
6. Supply columns sharing an x coordinate use the same supply.
7. The combined geometry has exactly 40 distinct columns.
8. Every macro-aligned column clears the signal-pin corridors.

The 40 columns are 20 power columns and 20 ground columns. Their spacing
includes an irregular middle band, so the actual LEF supplies the x
coordinates.

The reference helper uses these conversions:

~~~text
2.1 micrometer stripe width = 2100 database units
Stripe half-width = 1050 database units
Clearance on each side = 500 database units
Guard half-width = 1550 database units
~~~

The guard examines each Metal4 signal boundary-pin rectangle. It reserves
that pin's x corridor along the full-height stripe. The reference clearance
is 0.5 micrometers on each side, compared with the reported M4.b minimum
spacing of 0.21 micrometers.

### 9.3 Generate the grid

`src/pdn_cfg.tcl` creates:

- A CORE voltage domain on the resolved VPWR and VGND nets.
- Metal4 columns aligned to the SRAM's supply geometry.
- Ordinary Metal4 columns elsewhere, skipping the macro's x range and
  each signal-pin corridor.
- Metal1 standard-cell follow-pin rails.
- Metal1-to-Metal4 connections.

The ordinary column pattern uses a 38.87-micrometer pitch and a
4.1-micrometer power-to-ground offset. Each selected supply stripe is
2.1 micrometers wide.

The custom Tcl procedure receives the core rectangle and database-unit
conversion as arguments. This keeps its variables valid inside
LibreLane's `read_pdn_cfg` procedure scope.

### 9.4 Extend through the macro abstraction

`Project.PowerProgramSRAM` starts a separate OpenROAD process. Its script
loads the current database and sources `set_power_nets.tcl` again.

For every LEF-derived column it creates a full-height Metal4 special-wire
rectangle and a matching supply boundary pin. This joins the actual SRAM
supply shapes across the abstract macro blockage.

The extension is deliberately tied to the actual macro supplies. The
geometry and signal-pin guards run before the rectangles are added.

Then both supply checks run:

~~~tcl
check_power_grid -net $::env(VDD_NET)
check_power_grid -net $::env(GND_NET)
~~~

Expected messages:

~~~text
All shapes on net VPWR are connected.
All shapes on net VGND are connected.
Program SRAM: extended 40 LEF-derived supply columns to tile boundaries
~~~

The script refreshes the violation metrics only after both connectivity
checks succeed. Pre-extension warnings describe the earlier grid state.
The final checker evaluates the verified extended result.

### 9.5 Geometry qualification

The macro LEF has abstract supply geometry that creates false overlap
findings in the generic Magic abstraction checks. The reference
configuration uses these scoped choices:

~~~json
{
  "RUN_MAGIC_DRC": false,
  "ERROR_ON_ILLEGAL_OVERLAPS": false,
  "RUN_KLAYOUT_DRC": 1,
  "ERROR_ON_KLAYOUT_DRC": true,
  "ERROR_ON_TR_DRC": true,
  "ERROR_ON_LVS_ERROR": true
}
~~~

KLayout qualifies the assembled GDS geometry. Detailed-routing DRC,
integration LVS, supply connectivity, and Tiny Tapeout precheck remain
acceptance gates. Apply the same abstraction rationale only after checking
the chosen macro's actual views.

## 10. Run integration LVS

### 10.1 Supply the complete port interface

The abstract `src/sram_256x16_lvs.spice` declares all 109 physical names.
It is loaded through:

~~~json
{
  "EXTRA_SPICE_MODELS": ["dir::sram_256x16_lvs.spice"]
}
~~~

Its bus pins appear contiguously in descending index order. This lets
Netgen infer the full vector width while reading the named-port Verilog
instance.

This is a macro-integration interface. It checks the surrounding circuit's
connections to the supplied macro. The unchanged official GDS, CDL,
Liberty, and simulation models establish the identity and provenance of
the macro itself.

### 10.2 Adapt only the required reader syntax

OpenROAD's powered Verilog contains escaped physical supply-pin tokens.
The LVS step makes a local copy and changes the three SRAM formal-pin
spellings into the syntax accepted by the recorded Netgen reader:

~~~text
Original pin token: .\VDD! (
LVS copy token:     .VDD!(
~~~

The operation is scoped to exactly one `program_store.i_sram` instance
and exactly one occurrence of each of its three supply pins. Connected
node names retain their original values. The original powered netlist
remains the flow's saved view.

### 10.3 Preserve report contents

Some Netgen versions write unsupported identifier backslashes into JSON
strings. The compatibility helper:

1. Parses valid JSON directly.
2. Repairs unsupported string escapes when that is the reported problem.
3. Preserves existing valid escapes.
4. Saves the original as `lvs.netgen.json.original`.
5. Validates the repaired JSON before LibreLane consumes it.

Circuit mismatch data and error counts remain intact. Structural JSON
problems still raise an exception. The normal `Checker.LVS` remains in
the flow.

### 10.4 Acceptance and fault checks

Expected final report:

~~~text
Final result: Circuits match uniquely.
~~~

Expected metric:

~~~text
design__lvs_error__count = 0
~~~

The local interface fixture deliberately connects `VDDARRAY!` to ground.
The recorded Netgen 1.5.270 fixture reports 110 errors for that fault and
zero for correct wiring. A complete routed-engine replay also distinguishes
the original interface-pin shorts from the corrected grid.

Read the full `lvs.netgen.rpt` and JSON comparison when debugging. Device
and net totals may vary with synthesis and routing. Require a unique match
and zero reported errors rather than a fixed device count for every future
revision.

## 11. Program an exact SRAM address

Physical placement and runtime word addresses are independent coordinates.
The macro sits at (300.0, 34.02) micrometers. Software selects word 0
through 255 inside that macro.

### 11.1 Address conversion

~~~text
byte_address = 2 * word_address
ADDRESS_LO = byte_address & 0xFF
ADDRESS_HI = byte_address >> 8
~~~

| Word | First byte | ADDRESS_HI | ADDRESS_LO |
|---|---|---|---|
| 0 | 0x000 | 0x00 | 0x00 |
| 127 | 0x0FE | 0x00 | 0xFE |
| 128 | 0x100 | 0x01 | 0x00 |
| 254 | 0x1FC | 0x01 | 0xFC |
| 255 | 0x1FE | 0x01 | 0xFE |

A word occupies its low byte followed by its high byte. The hardware DATA
register auto-increments the byte address modulo 512. The Python driver
bounds a requested range before issuing SPI activity.

### 11.2 Host bus and register operations

~~~text
CS_n: ui[0]
SCLK: ui[1]
MOSI: ui[2]
MISO: uo[0]
Mode: SPI mode 0, MSB first
Frame command: write flag in bit 7, register address in bits 6:0
~~~

Keep CS low for the complete command and data burst. Allow at least four
core clocks per SCLK half-period and for CS setup and recovery. The core
clock continues running while execution is paused.

| Register | Address | Programming use |
|---|---:|---|
| CONTROL | 0 | Write zero to pause, one to resume |
| STATUS | 1 | Read error bitmap and running bitmap |
| ADDRESS_LO | 2 | Byte address bits 7:0 |
| ADDRESS_HI | 3 | Byte address bit 8 in bit 0 |
| DATA | 4 | Burst read or write with byte-address increment |
| CONTEXT | 5 | Select one context |
| ENTRY_LO | 6 | Starting word address |
| ENTRY_HI | 7 | Zero for the eight-bit program counter |
| RESTART | 8 | Context bitmap to start |
| STOP | 9 | Context bitmap to halt and release owned outputs |
| PIN_MASK | 10 | Selected context's output ownership |
| ERROR_CLEAR | 11 | Write-one-to-clear error bitmap |
| ID | 12 | Read 0xA7 |
| PROGRAM_AW | 19 | Read eight |

Software CONTROL pause selects the host memory address. The Tiny Tapeout
`ena` signal has a different GPIO-release behavior. Use CONTROL pause for
program loading and readback.

### 11.3 Complete word-programming example

Supply the board-specific `board_spi_transfer` callback. It accepts bytes,
returns one received byte per transmitted byte, and follows the frame and
clock requirements above.

For a freshly reset device with `ena` asserted:

~~~python
from tools.assembler import halt
from tools.config import PROGRAM_DEPTH
from tools.host import Engine
from tools.protocols import uart_bit_grants, uart_tx

engine = Engine(board_spi_transfer)
assert engine.identify() == 0xA7
engine.pause()
engine.stop()
engine.load([halt()] * PROGRAM_DEPTH)

clock_hz = 50_000_000  # Reference simulation target
period = uart_bit_grants(clock_hz, 115_200, receive=True)
program = uart_tx(0x55, pin=1, bit_grants=period)
entry = 0x80
engine.load(program, entry=entry)
assert engine.read_program(entry=entry, count=len(program)) == program
engine.configure(tid=0, pin_mask=0x02)
engine.start(mask=1, entry=entry)
engine.resume()
~~~

This initializes the reachable store to HALT, then patches a UART transmit
program at word 128 and verifies it. The UART program is 25 words and fits
inside the remaining capacity.

For reused ownership settings, pause, stop, and clear the previous masks
before assigning new disjoint masks. Select a hardware clock through the
timing-qualification stage and regenerate the bit period for that clock.

The reference 50 MHz simulation setting uses 108 grants per UART bit.
The 12 MHz FPGA setting uses 26. Each grant takes four core clocks.

### 11.4 Targeted programming acceptance

Exercise words 0, 127, 128, 254, and 255 with distinct values. Patch each
byte lane independently and read all 256 words back. Confirm:

- The intended word changes.
- Its opposite byte retains its value.
- Every other word retains its value.
- Word 128 correctly uses the high byte-address bit.
- Word 255 uses bytes 510 and 511.
- Out-of-range software requests are rejected before SPI activity.
- Live hardware DATA accesses set the documented error state.

The committed RTL and host tests exercise these cases. Full host behavior
and the remaining debug registers are documented in
[HOST_INTERFACE.md](HOST_INTERFACE.md).

## 12. Run the full verification sequence

From the repository root, first select the default ASIC simulation mode:

~~~bash
unset JP_TEST_FPGA JP_TEST_REGISTER
python -m unittest discover -s test -p 'test_*.py' -v
python -m tools.run_cocotb
~~~

Expected at the reference revision: 42 unit/regression tests pass and the
pin-only cocotb test passes.

Run both comparison variants:

~~~bash
JP_TEST_FPGA=1 python -m unittest discover -s test -p 'test_*.py' -v
JP_TEST_REGISTER=1 python -m unittest discover -s test -p 'test_*.py' -v
~~~

The reference runs 42 tests for each selection. The dedicated SRAM-model
tests still exercise the foundry models directly.

On PowerShell:

~~~powershell
Remove-Item Env:JP_TEST_FPGA -ErrorAction SilentlyContinue
Remove-Item Env:JP_TEST_REGISTER -ErrorAction SilentlyContinue
.\.venv\Scripts\python.exe -m unittest discover -s test -p "test_*.py" -v
.\.venv\Scripts\python.exe -m tools.run_cocotb
$env:JP_TEST_FPGA = '1'
.\.venv\Scripts\python.exe -m unittest discover -s test -p "test_*.py" -v
Remove-Item Env:JP_TEST_FPGA
$env:JP_TEST_REGISTER = '1'
.\.venv\Scripts\python.exe -m unittest discover -s test -p "test_*.py" -v
Remove-Item Env:JP_TEST_REGISTER
~~~

The coverage combines a Python cycle model, randomized programs and inputs,
independent protocol peers, external-pin host programming, and runtime
ownership assertions. Formal proof is tracked separately.

For Linux Make-based RTL testing:

~~~bash
cd test
make clean
make
python -m cocotb_tools.check_results results.xml
cd ..
~~~

For gate-level testing, use the netlist from the same physical revision and
the matching installed PDK:

~~~bash
cd test
make clean
make GATES=yes
python -m cocotb_tools.check_results results.xml
cd ..
~~~

The official gate-level action supplies `test/gate_level_netlist.v`. A local
replay must place that exact exported netlist there first.

After successful local hardening, the support tool selects the applicable
gate-netlist format during submission creation:

~~~bash
./tt/tt_tool.py --create-tt-submission --ihp
cp tt_submission/tt_um_igorchip.v test/gate_level_netlist.v
~~~

Submission creation refreshes `tt_submission`. Preserve an earlier
submission in an archive directory before regenerating it.

The GitHub precheck action is the reference acceptance path. A local
precheck replay uses the pinned support tool's requirements and Nix setup:

~~~bash
python -m pip install -r tt/precheck/requirements.txt
export SRAM_PROJECT_ROOT="$PWD"
cd tt/precheck
nix-build
nix-shell --run "python precheck.py --gds $SRAM_PROJECT_ROOT/tt_submission/tt_um_igorchip.gds --tech ihp-sg13cmos5l"
cd "$SRAM_PROJECT_ROOT"
~~~

This requires Nix installed through its supported installation procedure,
the same PDK_ROOT/PDK environment, and the generated submission alongside
the repository metadata. The official precheck runs its own single-threaded
KLayout DRC check, so allow time for that separate stage.

Before spending time on place-and-route, inspect synthesis statistics or the
mapped netlist for exactly one `RM_IHPSG13_1P_256x16_c2_bm_bist` instance
with the intended hierarchy. The registered power step also enforces that
master and instance during the physical flow.

## 13. Build GDS and preserve diagnostics

The complete reference GDS workflow appears in the source snapshots. It
uses the official IHP action with `pdk: ihp-sg13cmos5l`.

The build has:

~~~text
Job timeout: 180 minutes
Build-step timeout: 150 minutes
Detailed-routing optimization iterations: 20
Detailed-routing report interval: 5 iterations
OpenROAD threads: 2
Placement target density: 40 percent
Global routing: congestion-free acceptance
~~~

The separate always-running diagnostic upload preserves logs after a
failed build step. The time reserve gives it an opportunity to finish.
Concurrency replaces an older run on the same branch with the latest run.

| Artifact | Contents to inspect |
|---|---|
| tt_submission | Submission GDS/OASIS and project metadata consumed by downstream actions |
| GDS_logs | Detailed physical-flow files, reports, and extracted circuit views |
| gds-diagnostics-* | Saved config, logs, reports, JSON, OpenDB databases, guides, SDC, and adapted LVS input |
| gds_render | Layout preview used by the viewer |
| precheck_reports | Tiny Tapeout acceptance results and reports |
| test-results | Cocotb results and waveforms from the test workflow |

The report directories carry step-number prefixes. Identify them by the
step suffix, since inserted steps can change numbering:

~~~text
*-openroad-generatepdn/
*-project-powerprogramsram/
*-openroad-detailedrouting/
*-klayout-drc/
*-magic-spiceextraction/
*-project-programsramlvs/reports/lvs.netgen.rpt
*-project-programsramlvs/reports/lvs.netgen.json
final/metrics.json
final/gds/
final/def/
final/spice/
tt_submission/tt_um_igorchip.oas
~~~

For the recorded flow, LVS is in
`67-project-programsramlvs/reports`. KLayout's detailed rule database can
appear as `drc.klayout.lyrdb`. The always-uploaded diagnostics and full
GDS logs have different file selections, so use the full logs artifact
for extracted SPICE and geometry databases when needed.

Read final metrics directly:

~~~python
import json
from pathlib import Path

metrics = json.loads(Path("runs/wokwi/final/metrics.json").read_text())
for key in (
    "design__lvs_error__count",
    "klayout__drc_error__count",
    "design__power_grid_violation__count",
):
    assert metrics[key] == 0, (key, metrics[key])
    print(key, metrics[key])
~~~

Follow this with the precheck and gate-level job results. A saved GDS file
is one output of the build. Complete integration acceptance includes the
report metrics and downstream checks.

## 14. Publish and verify the viewer

The viewer job runs after a successful GDS job on the default branch.
Feature-branch and pull-request runs validate the hardware while viewer
publication remains attached to the default branch.

For a repository that uses this workflow:

1. Set GitHub Pages source to GitHub Actions.
2. Retain `pages: write` and `id-token: write` on the viewer job.
3. Require a successful upstream GDS job and its named submission/render artifacts.
4. Publish the verified revision on the repository's default branch.
5. Confirm the viewer job completes successfully.
6. Fetch the published OASIS file and preview.
7. Verify the top and SRAM hierarchy inside the published file.

The published files for this repository are:

- [Pages entry point](https://wlmoi.github.io/General-Purpose-Protocol-ASIC_JaneStreet/)
- [OASIS model](https://wlmoi.github.io/General-Purpose-Protocol-ASIC_JaneStreet/tinytapeout.oas)
- [GDS layout](https://wlmoi.github.io/General-Purpose-Protocol-ASIC_JaneStreet/tinytapeout.gds)
- [2D preview](https://wlmoi.github.io/General-Purpose-Protocol-ASIC_JaneStreet/gds_render.png)
- [Direct 3D viewer](https://gds-viewer.tinytapeout.com/?model=https%3A%2F%2Fwlmoi.github.io%2FGeneral-Purpose-Protocol-ASIC_JaneStreet%2Ftinytapeout.oas&pdk=ihp-sg13cmos5l)

The direct viewer link explicitly selects the CMOS5L layer definitions.
Use a repository-specific Pages URL when reproducing the project elsewhere.

The published reference model was checked with the official viewer's
WASM processor. It contains one reference to the selected SRAM and the
correct top-level bounds. Its meshes have finite positions and valid
vertex indices. This also distinguishes the SRAM layout from the earlier
published register-memory layout.

For a portable hierarchy check with the KLayout Python package installed:

~~~python
import urllib.request
from pathlib import Path
import klayout.db as db

url = "https://wlmoi.github.io/General-Purpose-Protocol-ASIC_JaneStreet/tinytapeout.oas"
target = Path("build/published-sram.oas")
target.parent.mkdir(parents=True, exist_ok=True)
with urllib.request.urlopen(url, timeout=60) as response:
    assert response.status == 200
    target.write_bytes(response.read())
layout = db.Layout()
layout.read(str(target))
top = layout.top_cell()
assert top.name == "tt_um_igorchip"
macro = layout.cell("RM_IHPSG13_1P_256x16_c2_bm_bist")
assert macro is not None
instances = sum(
    inst.cell_index == macro.cell_index()
    for cell in layout.each_cell()
    for inst in cell.each_inst()
)
assert instances == 1, instances
print("Published SRAM hierarchy verified")
~~~

Use a revision query or normal cache refresh when comparing a newly
published file with a previous model. Record the downloaded file hash
alongside the deployment's source revision.

## 15. Qualify timing and external interfaces

The configuration's `CLOCK_PERIOD = 20` ns is a 50 MHz target. The
half-cycle architecture gives both address-to-SRAM and SRAM-to-execution
paths a half-period relationship that must be reviewed in STA.

For commit `1649be6`, the recorded final timing metrics include:

| Metric | Recorded value |
|---|---:|
| Worst setup slack | Approximately -2.637 ns |
| Setup violations | 253 |
| Maximum slew violations | 26 |
| Maximum capacitance violations | 11 |
| Hold violations | 0 |

These reports identify the next timing-repair work. Preserve the real
clock, operating corners, constraints, and loads while repairing paths.
Measure the resulting setup, hold, slew, and capacitance acceptance before
declaring a selected clock qualified.

The FPGA flow targets 12 MHz and checks for one `SB_RAM40_4K` family block
RAM plus a nonempty bitstream. Its source selection and timing target are
separate from the ASIC's physical SRAM.

The SRAM is internal to the chip's core-voltage domain. External protocol
connections use the Tiny Tapeout board's compatible digital I/O levels.
Document I2C pull-ups, board capacitance, attached-device timing, and any
external UART or bus transceiver. Match UART generation to the actual
qualified clock and measure framing behavior on the board.

## 16. Diagnose failures by stage

| Symptom | Likely cause | Corrective action and acceptance |
|---|---|---|
| Checkout fails, then results.xml is missing | Repository checkout or Git metadata failed before tests started | Resolve the first checkout error and rerun tests before diagnosing absent test artifacts |
| Required PDK macro view is missing | Partial PDK copy or unresolved shared SRAM directory | Install the complete pinned PDK and run the view audit |
| Duplicate Verilog macro declaration | Behavioral models and synthesis declaration compiled together | Use SIM and FUNCTIONAL with the guarded declaration and the two official models |
| SRAM output stays X | Reachable memory is uninitialized or read enable/clock selection is wrong | Load the reachable image, check A_MEN/A_REN, and run the clock-edge test |
| Byte patch changes both lanes | Incorrect A_BM polarity, width, or lane selection | Check 0x00FF/0xFF00 and read every neighbor after both lane patches |
| Word 128 aliases another location | Word/byte conversion or ADDRESS_HI is wrong | Verify byte address 0x100 and the 127/128 boundary test |
| Host DATA returns zero or sets an error | Core execution is enabled during memory access | Write CONTROL zero, retain the core clock, and retry the documented paused access |
| Program SRAM instance required | ASIC selected a reference/FPGA memory or lost the macro during synthesis | Restore ASIC source selection and verify the retained macro before PDN |
| Signal pin requires template placement | PDN selection ran while interface pins were unplaced | Apply the official DEF template before GeneratePDN and verify step order |
| can't read core: no such variable | Tcl procedure relied on another scope's local variable | Pass core and dbu explicitly as jp_stripe arguments |
| PDN-0224 power net absent from grid | Incorrect global supply name | Use the resolved VPWR/VGND configuration and connect physical macro pins separately |
| VDD!, VDDARRAY!, or VSS! remains unconnected | Missing hook, incorrect instance pattern, or supply extension | Verify both macro rules, exact hierarchy, all 40 columns, and the post-extension checks |
| Large pre-extension PSM count remains in final metrics | Successful extension retained earlier metrics | Refresh metrics only after both actual connectivity checks pass |
| M4.b errors at the top boundary | Supply columns cross the fixed interface-pin bank | Use the reference origin, early pin placement, and clearance guards, then rerun DRC and LVS |
| Top-level pins fail matching with fewer extracted nets | Physical shorts or incomplete interface declaration | Read unmatched nets/pins and correlate their actual geometry, then verify the 109-pin declaration |
| Undefined SRAM subcircuit in Netgen | Required macro interface was absent | Load the complete SPICE port interface before the powered Verilog |
| Bus widths or macro ports mismatch | Partial declarations or incompatible bus ordering | Use contiguous descending bus pins from the supplied full interface |
| JSON invalid escape error | Reader report contains unsupported identifier escapes | Preserve the raw report and apply the scoped compatibility helper |
| Gate-level UDP is undefined | Standard-cell companion UDP source was absent | Compile matching CMOS5L cell and UDP models together |
| Routing runs for hours with persistent shorts | Congestion, poor signal access, or bad power geometry | Inspect saved rule coordinates, retain the real access windows, and correct the floorplan or grid |
| Viewer job is skipped on a feature branch | Default-branch publication condition | Validate the branch, integrate it into the default branch, and verify deployment |
| Viewer serves the preceding layout | Published model or browser/CDN cache predates the revision | Compare revision and model hash, refresh the model, and inspect SRAM hierarchy |
| Setup/slew/capacitance warnings remain | Physical electrical/timing limits require repair | Review corner-specific paths and loads, repair them, and record qualified operating conditions |

### 16.1 The physical shorts that this recipe corrected

The earlier origin (20.16, 34.02) micrometers placed SRAM supply columns
across the fixed Metal4 interface bank. The actual reports showed 16 M4.b
spacing/notch errors and merged interface nets.

Moving the SRAM to x = 300 cleared the macro-column conflicts. A following
run passed DRC and power connectivity while LVS still reported seven merged
nets and 17 errors. The ordinary grid had been selected before the signal
pins were placed. Applying the DEF template first made the clearance
predicate operate on real coordinates and resolved those remaining shorts.

This demonstrates why a power-connectivity pass needs both signal
separation checks and final LVS. DRC qualifies geometry, and LVS compares
electrical connectivity.

### 16.2 Collect concrete evidence before changing settings

For a failing run, collect:

~~~text
Repository commit and workflow run URL
First fatal step and error
Resolved configuration and PDK source version
Macro name, hierarchy, orientation, and origin
Unmatched pin/net section from lvs.netgen.rpt
Original and parsed lvs.netgen.json
DRC rule names, layers, and coordinates
Post-extension power checks and final metrics
The relevant DEF/ODB/SPICE/GDS views
~~~

Change the identified cause, rerun the affected stage, then complete the
normal acceptance sequence. Keep the stage's error reporting intact.

## 17. Adapt the design to another macro

Use a new integration contract for each change in macro or process:

| Change | Items to revisit |
|---|---|
| Depth | Address width, PC width, host byte address, assembler limits, readback limits, tests |
| Word width | Instruction packing, byte lanes, masks, host serialization, literals |
| Read latency | Scheduler grant timing, literals, host snapshots, cycle reference model |
| Port count | Arbitration, simultaneous-access policy, clocks, physical pins |
| Macro master name | Black box, wrapper, MACROS key, instance validation, LVS adapter |
| Hierarchy | Placement instance, macro power hooks, geometry helper, scoped reader match |
| Supply names | Global nets, LEF/CDL ports, hookups, abstract interface |
| Orientation | LEF-to-global coordinate transform and supply-column extraction |
| Database units | Every width, clearance, offset, and origin conversion |
| Process stack | Routing layers, via connections, pin-access rules, viewer layer definitions |
| Die or tile allocation | Official DEF template, legal macro position, rows, density, routing |
| Operating conditions | Actual Liberty corners, clock phase, STA constraints, external timings |

The current geometry helper is written for R0 orientation, 1000 database
units per micrometer, and this macro's Metal4 supply pattern. Transform
geometry explicitly when extending those assumptions.

Use the reference FPGA and register implementations as behavioral
comparisons. Retain the foundry-model tests as the check of actual SRAM
enable, mask, and edge semantics.

## 18. Agent handoff and evidence record

Before work:

1. Read applicable repository instructions.
2. Record the working tree, current revision, and requested target.
3. Preserve existing user changes and use a fresh reproduction checkout.
4. Read this guide and the canonical integration files.
5. Verify the installed macro views and storage selection.

Implementation sequence:

~~~text
Source/PDK audit
    -> RTL wrapper and foundry-model tests
    -> Host addressing and differential/protocol tests
    -> Synthesis with one retained macro
    -> Legal placement and early interface-pin template
    -> LEF-derived PDN and both supply-connectivity checks
    -> Routing and assembled-GDS DRC
    -> Complete integration LVS
    -> Tiny Tapeout precheck and gate-level simulation
    -> Default-branch viewer publication and model inspection
    -> Timing qualification and board validation
~~~

A useful final evidence record includes:

~~~yaml
source_commit: "<full repository SHA>"
pdk: "ihp-sg13cmos5l"
pdk_commit: "2bbec755dc67ca3db0261c3d6163e15735d66710"
macro: "RM_IHPSG13_1P_256x16_c2_bm_bist"
instance: "program_store.i_sram"
macro_origin_um: [300.0, 34.02]
macro_orientation: "N"
storage_words: 256
storage_word_bits: 16
rtl_test_result: "<count and result>"
gate_level_result: "<result and run URL>"
lvs_errors: "<actual final count>"
klayout_drc_errors: "<actual final count>"
power_grid_violations: "<actual post-extension count>"
precheck_result: "<result and run URL>"
viewer_deployment: "<result and URL>"
published_model_sha256: "<downloaded model hash>"
timing_result: "<corner metrics and qualification status>"
board_result: "<measured evidence or scheduled qualification stage>"
~~~

Use actual measured values. Separate behavior, geometry, connectivity,
timing, and board results. Describe the exact revision associated with each
result.

### Primary implementation references

- [Pinned Tiny Tapeout action](https://github.com/TinyTapeout/tt-gds-action/tree/3412659307918422f3f0727917cf9b499aaca588)
- [Pinned CMOS5L PDK installer](https://github.com/TinyTapeout/tt-gds-action/blob/3412659307918422f3f0727917cf9b499aaca588/install_sg13cmos5l.sh)
- [Pinned support-tool configuration and hardening](https://github.com/TinyTapeout/tt-support-tools/blob/d66cf179e7bc4d296362ab7e2e3b344dc3c4f665/project.py)
- [Pinned support-tool precheck](https://github.com/TinyTapeout/tt-support-tools/blob/d66cf179e7bc4d296362ab7e2e3b344dc3c4f665/precheck/precheck.py)
- [Pinned IHP macro library](https://github.com/IHP-GmbH/IHP-Open-PDK/tree/2bbec755dc67ca3db0261c3d6163e15735d66710/ihp-sg13g2/libs.ref/sg13g2_sram)
- [LibreLane configuration reference](https://librelane.readthedocs.io/en/latest/reference/configuration.html)
- [LibreLane macro integration](https://librelane.readthedocs.io/en/latest/usage/macros.html)
- [OpenROAD PDN API](https://openroad.readthedocs.io/en/latest/main/src/pdn/README.html)
- [Tiny Tapeout viewer source](https://github.com/TinyTapeout/tinytapeout_gds_viewer)

## 19. Source snapshots and integrity manifest

The following snapshots are copied from commit
`b08afad42ed7179eee4a276634ee7b4cefae4f6c`. They preserve the complete
integration implementation. Restore each block to its indicated relative
path when recreating the layer in a compatible engine.

SHA-256 values describe UTF-8 source text with LF line endings. Normalize
CRLF to LF before comparing a Windows working-tree file. The surrounding
engine and foundry-model files are also listed in the integrity manifest.

Run this audit from the reproduction checkout after saving this guide at its
documented path:

~~~python
import hashlib
import re
from pathlib import Path

guide = Path("docs/SRAM_IMPLEMENTATION_GUIDE.md").read_text()
records = re.findall(
    r"^\| `([^`]+)` \| `([0-9a-f]{64})` \|$",
    guide,
    re.MULTILINE,
)
assert len(records) == 32
for relative, expected in records:
    data = Path(relative).read_bytes().replace(b"\r\n", b"\n")
    actual = hashlib.sha256(data).hexdigest()
    assert actual == expected, (relative, actual, expected)
print("All 32 reference-source checksums match")
~~~

<!-- SRAM_SOURCE_SNAPSHOTS -->

### Integrity manifest

| File | SHA-256 of LF-normalized source |
|---|---|
| `src/program_memory.v` | `4b917488e659f82ab924d49b95ff2db3437fd48dfca91eed2aeaabad13ee34ac` |
| `src/sram_256x16_bb.v` | `e1b2050253748f8dbece08016e7f518e221cac5f11735f5c4fd508ab0a16cd36` |
| `src/config.json` | `b3204c41cf1924f7739b3c30c10db02291896ac7662c35309cf2998292800d3d` |
| `src/sram_geometry.tcl` | `00b2d4f5268f3a914a5672bc082831831a6fb7929af086b35d7533597c36cd4a` |
| `src/pdn_cfg.tcl` | `373b2392edf23c33ca311a42955cbf28ef22189a2e242f9f1917a075ef7a4652` |
| `src/power_sram.tcl` | `808ed559f59e32520f6209bbb8263b8e18751b128b98791504ab56812266a676` |
| `librelane_plugin_program_sram.py` | `a17fc86bd64130de9cf0a13eb82036ac9eabacee0be1644b04649673f25b7f7f` |
| `src/sram_256x16_lvs.spice` | `3016e308b4485554172b5f6c815535d3d6860097d568015eb390d6f88ab08d09` |
| `tools/netgen_json.py` | `181a2bb1b2359c9634143763c751b130d3dfa547fe88f480bb007aa7ca82802e` |
| `test/Makefile` | `2365c553f14cb8aa890d3423bc997699cc002b8385e831c7a924d5e33f741017` |
| `test/test_sram.py` | `f427afb39e6504039db09b2238ac6ad384cda088a8736e4828e7ab3c7c08b45a` |
| `.github/workflows/gds.yaml` | `cde23aba1a499e72189d928333b1052c0ccdfc1f148434d6290386a87181b12e` |
| `info.yaml` | `83c3c5ec78920b667ca26b085daf7813a51a8998d3f2efed735a7f62d28bedb2` |
| `src/igorchip_top.v` | `9f7425b4b35eb6e5dc652dc3ed869b953de545e55ca3017b6ef4aaf4012624f1` |
| `src/program_host.v` | `acd1545244d489617515b320d4eed9b5c0b522e750af74ce88a3e1f226054686` |
| `src/defines.vh` | `bee2b34a40efbacccd23d2c53a208a63d1a172e565d3a4ffb786ef04b373d0bf` |
| `tools/config.py` | `6310c839f095c898a78bd1825ca2ef129b84043d3608104d76a101380884b191` |
| `tools/host.py` | `43c9fc722d71137e05f6f371f5a774adcc6ece088555acb447fc412678870924` |
| `tools/assembler.py` | `ce18e60c3e5b16dce8a1ef7233a82fedac52eda284e789385182d85abda01861` |
| `tools/protocols.py` | `dd8926178cdd812bdf84053d051d5e5d8fa68f312d621cd45e794251aacb2a8b` |
| `tools/run_cocotb.py` | `7a926063aef52a98778133b2c10ac3bab12d252dbe89657bcc89f71ec5f97120` |
| `test/tb.v` | `3c8890c6bde408617232452c760df13bf939bf6a4ebcc92ac5538a91bee3b6f8` |
| `test/test.py` | `ac0f6b9f2d686991ec6fc5a974bbaaff12a58d5d3098baeaa144060e0dc61bb3` |
| `test/test_rtl.py` | `ff846bd4597a34784b269220594cb67afc268ec12805e859d3c1f0637b5e0921` |
| `test/test_reference_model.py` | `86107d1956456acbd7fa71a1dc256eed4e359984126a5f46b2a06f92faa7dc2d` |
| `test/test_netgen_json.py` | `2cb939c6f4b7e0ac674badd20473c4f47a8dc7a9dce284bd6f212e1007a25431` |
| `test/requirements.txt` | `4273151bc1544b57436ccd1af30e6428beb0291e4f9fba3307db8115ef53f60d` |
| `test/ihp_sram/RM_IHPSG13_1P_core_behavioral_bm_bist.v` | `d0a6258f8e9c93d1d5b1f78c0a1d66f30d28b1ad8037e5e07f53d1a4e3670b12` |
| `test/ihp_sram/RM_IHPSG13_1P_256x16_c2_bm_bist.v` | `645c475787b077da4dbd15856c68bbae46aa9846a155239eb895ed2de7511053` |
| `.github/workflows/test.yaml` | `2300848a5b1c8d2cf38ae01073d211bec88f0297dcd3e2ac848b733ffacc1fe9` |
| `.github/workflows/fpga.yaml` | `f0c146c33a2e62becab3fb5573c703c17820083d38e65dc767b4896e148e5080` |
| `.github/workflows/docs.yaml` | `4ab03b32e38e4ae604df854def95675b8b82398816fd3bd6dd7e143c7ec887b9` |

### Snapshot 1: src/program_memory.v

~~~verilog
`default_nettype none
`include "defines.vh"
// One physical read/write port. The falling edge prepares the next instruction
// for the rising-edge execution grant without changing the four-context cadence.
module program_memory (
 input wire clk, rst_n,
 input wire [7:0] address,
 input wire write_enable,
 input wire high_byte,
 input wire [7:0] write_data,
 output wire [15:0] read_data
);
`ifdef JP_FPGA_SYNC_MEMORY
 reg [15:0] words [0:255];
 reg [15:0] read_q;
 always @(posedge clk) begin
  if (write_enable) begin
   if (high_byte) words[address][15:8] <= write_data;
   else words[address][7:0] <= write_data;
  end
 end
 always @(negedge clk) read_q <= words[address];
 assign read_data = read_q;
`else
`ifdef JP_REGISTER_MEMORY
 reg [15:0] words [0:255];
 always @(posedge clk) begin
  if (write_enable) begin
   if (high_byte) words[address][15:8] <= write_data;
   else words[address][7:0] <= write_data;
  end
 end
 assign read_data = words[address];
`else
 wire memory_clock = ~clk;
 RM_IHPSG13_1P_256x16_c2_bm_bist i_sram (
  .A_CLK(memory_clock), .A_MEN(rst_n),
  .A_WEN(write_enable), .A_REN(!write_enable),
  .A_ADDR(address), .A_DIN({write_data, write_data}),
  .A_BM(high_byte ? 16'hFF00 : 16'h00FF),
  .A_DLY(1'b1), .A_DOUT(read_data),
  .A_BIST_CLK(1'b0), .A_BIST_EN(1'b0), .A_BIST_MEN(1'b0),
  .A_BIST_WEN(1'b0), .A_BIST_REN(1'b0), .A_BIST_ADDR(8'd0),
  .A_BIST_DIN(16'd0), .A_BIST_BM(16'd0)
 );
`endif
`endif
endmodule
~~~

### Snapshot 2: src/sram_256x16_bb.v

~~~verilog
`include "defines.vh"
`ifndef SIM
`ifndef JP_FPGA_SYNC_MEMORY
`ifndef JP_REGISTER_MEMORY
(* blackbox *)
module RM_IHPSG13_1P_256x16_c2_bm_bist (
 input wire A_CLK, A_MEN, A_WEN, A_REN, A_DLY,
 input wire [7:0] A_ADDR,
 input wire [15:0] A_DIN, A_BM,
 output wire [15:0] A_DOUT,
 input wire A_BIST_CLK, A_BIST_EN, A_BIST_MEN, A_BIST_WEN, A_BIST_REN,
 input wire [7:0] A_BIST_ADDR,
 input wire [15:0] A_BIST_DIN, A_BIST_BM
);
endmodule
`endif
`endif
`endif
~~~

### Snapshot 3: src/config.json

~~~json
{
  "//": "DO NOT EDIT THIS FILE before reading the comments below:",

  "//": "This is the default configuration for Tiny Tapeout projects. It should fit most designs.",
  "//": "If you change it, please make sure you understand what you are doing. We are not responsible",
  "//": "if your project fails because of a bad configuration.",

  "//": "!!! DO NOT EDIT THIS FILE unless you know what you are doing !!!",

  "//": "If you get stuck with this config, please open an issue or get in touch via the discord.",

  "//": "Here are some of the variables you may want to change:",

  "//": "PL_TARGET_DENSITY_PCT - You can increase this if Global Placement fails with error GPL-0302.",
  "//": "Users have reported that values up to 80 worked well for them.",
  "PL_TARGET_DENSITY_PCT": 40,

  "//": "CLOCK_PERIOD - Increase this in case you are getting setup time violations.",
  "//": "The value is in nanoseconds, so 20ns == 50MHz.",
  "CLOCK_PERIOD": 20,

  "//": "Hold slack margin - Increase them in case you are getting hold violations.",
  "PL_RESIZER_HOLD_SLACK_MARGIN": 0.1,
  "GRT_RESIZER_HOLD_SLACK_MARGIN": 0.05,

  "//": "RUN_LINTER, LINTER_INCLUDE_PDK_MODELS - Disabling the linter is not recommended!",
  "RUN_LINTER": 1,
  "LINTER_INCLUDE_PDK_MODELS": 1,

  "//": "If you need a custom clock configuration, read the following documentation first:",
  "//": "https://tinytapeout.com/faq/#how-can-i-map-an-additional-external-clock-to-one-of-the-gpios",
  "CLOCK_PORT": "clk",

  "//": "Configuration docs: https://librelane.readthedocs.io/en/latest/reference/configuration.html",

  "//": "!!!!!!!!!!!!!!!!!!!!!!!!!!!!!!!!!!!!!!!!!!!!!!!",
  "//": "!!! DO NOT CHANGE ANYTHING BELOW THIS POINT !!!",
  "//": "!!!!!!!!!!!!!!!!!!!!!!!!!!!!!!!!!!!!!!!!!!!!!!!",

  "//": "Save some time",
  "RUN_KLAYOUT_XOR": 0,
  "RUN_KLAYOUT_DRC": 1,

  "//": "Don't put clock buffers on the outputs",
  "DESIGN_REPAIR_BUFFER_OUTPUT_PORTS": 0,

  "//": "Reduce wasted space",
  "TOP_MARGIN_MULT": 1,
  "BOTTOM_MARGIN_MULT": 1,
  "LEFT_MARGIN_MULT": 6,
  "RIGHT_MARGIN_MULT": 6,

  "//": "Absolute die size",
  "FP_SIZING": "absolute",

  "GRT_ALLOW_CONGESTION": 0,
  "OPENROAD_THREADS": 2,
  "DRT_OPT_ITERS": 20,
  "DRT_SAVE_DRC_REPORT_ITERS": 5,
  "ERROR_ON_TR_DRC": true,
  "ERROR_ON_KLAYOUT_DRC": true,

  "FP_IO_HLENGTH": 2,
  "FP_IO_VLENGTH": 2,

  "//": "CMOS5L Metal4 power pins meet the Tiny Tapeout 2.1 um minimum width",
  "FP_PDN_VWIDTH": 2.1,
  "FP_PDN_VPITCH": 38.87,

  "//": "Clock",
  "RUN_CTS": 1,

  "//": "Don't generate power rings",
  "FP_PDN_MULTILAYER": 0,

  "//": "MAGIC_DEF_LABELS may cause issues with LVS",
  "MAGIC_DEF_LABELS": 0,

  "//": "Only export pin area in LEF (without any connected nets)",
  "MAGIC_WRITE_LEF_PINONLY": 1,
  "meta": {
    "flow": "Classic",
    "substituting_steps": {
      "Odb.ApplyDEFTemplate": null,
      "-OpenROAD.GeneratePDN": "Odb.ApplyDEFTemplate",
      "+OpenROAD.GeneratePDN": "Project.PowerProgramSRAM",
      "Netgen.LVS": "Project.ProgramSRAMLVS"
    }
  },
  "MACROS": {
    "RM_IHPSG13_1P_256x16_c2_bm_bist": {
      "gds": [
        "pdk_dir::libs.ref/sg13cmos5l_sram/gds/RM_IHPSG13_1P_256x16_c2_bm_bist.gds"
      ],
      "lef": [
        "pdk_dir::libs.ref/sg13cmos5l_sram/lef/RM_IHPSG13_1P_256x16_c2_bm_bist.lef"
      ],
      "spice": [
        "pdk_dir::libs.ref/sg13cmos5l_sram/cdl/RM_IHPSG13_1P_256x16_c2_bm_bist.cdl"
      ],
      "nl": [],
      "spef": {},
      "lib": {
        "nom_typ_1p20V_25C": [
          "pdk_dir::libs.ref/sg13cmos5l_sram/lib/RM_IHPSG13_1P_256x16_c2_bm_bist_typ_1p20V_25C.lib"
        ],
        "nom_fast_1p32V_m40C": [
          "pdk_dir::libs.ref/sg13cmos5l_sram/lib/RM_IHPSG13_1P_256x16_c2_bm_bist_fast_1p32V_m55C.lib"
        ],
        "nom_slow_1p08V_125C": [
          "pdk_dir::libs.ref/sg13cmos5l_sram/lib/RM_IHPSG13_1P_256x16_c2_bm_bist_slow_1p08V_125C.lib"
        ]
      },
      "instances": {
        "program_store.i_sram": {
          "location": [
            300.0,
            34.02
          ],
          "orientation": "N"
        }
      }
    }
  },
  "PDN_CFG": "dir::pdn_cfg.tcl",
  "EXTRA_SPICE_MODELS": ["dir::sram_256x16_lvs.spice"],
  "ERROR_ON_LVS_ERROR": true,
  "PDN_MACRO_CONNECTIONS": [
    "program_store\\.i_sram VPWR VGND VDD! VSS!",
    "program_store\\.i_sram VPWR VGND VDDARRAY! VSS!"
  ],
  "FP_MACRO_HORIZONTAL_HALO": 8,
  "FP_MACRO_VERTICAL_HALO": 8,
  "RUN_MAGIC_DRC": false,
  "ERROR_ON_ILLEGAL_OVERLAPS": false
}
~~~

### Snapshot 4: src/sram_geometry.tcl

~~~tcl
# SPDX-License-Identifier: Apache-2.0
# Read column positions from the installed macro, including its irregular middle
# band. Both the PDN generator and the extension step use this geometry.
proc jp_column_clears_signal_pins {center} {
    set block [ord::get_db_block]
    # 2.1 um stripe plus 0.5 um clearance on each side. M4.b requires 0.21 um.
    set left [expr {$center - 1550}]
    set right [expr {$center + 1550}]
    foreach term [$block getBTerms] {
        if {[$term getSigType] in {POWER GROUND}} { continue }
        foreach pin [$term getBPins] {
            foreach box [$pin getBoxes] {
                if {[[$box getTechLayer] getName] != "Metal4"} { continue }
                if {$left < [$box xMax] && $right > [$box xMin]} { return 0 }
            }
        }
    }
    return 1
}

proc jp_sram_columns {} {
    set block [ord::get_db_block]
    # Classic normally applies the template after PDN generation. This design
    # applies it first so both regular and SRAM columns see the real pin bank.
    foreach term [$block getBTerms] {
        if {[$term getSigType] in {POWER GROUND}} { continue }
        set placed 0
        foreach pin [$term getBPins] {
            if {[$pin getPlacementStatus] in {PLACED FIRM LOCKED} &&
                [llength [$pin getBoxes]] > 0} { set placed 1 }
        }
        if {!$placed} {
            error "Signal pin [$term getName] requires template placement before PDN generation"
        }
    }
    set inst [$block findInst program_store.i_sram]
    if {$inst == "NULL"} { error "Program SRAM instance required" }
    if {[$inst getOrient] != "R0"} { error "Program SRAM requires N orientation" }
    if {[[$inst getMaster] getName] != "RM_IHPSG13_1P_256x16_c2_bm_bist"} {
        error "Unexpected program SRAM master"
    }
    set origin [$inst getOrigin]
    set columns [dict create]
    foreach pin {VDD! VDDARRAY! VSS!} {
        set term [$inst findITerm $pin]
        set net [$term getNet]
        if {$net == "NULL"} { error "Unconnected SRAM supply $pin" }
        set expected [expr {$pin == "VSS!" ? $::env(GND_NET) : $::env(VDD_NET)}]
        if {[$net getName] != $expected} { error "Incorrect SRAM supply $pin" }
        foreach port [[$term getMTerm] getMPins] {
            foreach box [$port getGeometry] {
                if {[[$box getTechLayer] getName] != "Metal4"} {
                    error "Unexpected SRAM supply layer"
                }
                if {[$box xMax] - [$box xMin] < 2100} { error "SRAM column too narrow" }
                set center [expr {[lindex $origin 0] + ([$box xMin] + [$box xMax]) / 2}]
                if {[dict exists $columns $center] && [dict get $columns $center] != $expected} {
                    error "Conflicting SRAM supplies"
                }
                dict set columns $center $expected
            }
        }
    }
    if {[dict size $columns] != 40} { error "Expected 20 power and 20 ground columns" }
    dict for {center net} $columns {
        if {![jp_column_clears_signal_pins $center]} {
            error "SRAM supply column at $center overlaps a Metal4 signal-pin corridor. Move the SRAM outside the I/O pin bank."
        }
    }
    return $columns
}
~~~

### Snapshot 5: src/pdn_cfg.tcl

~~~tcl
# SPDX-License-Identifier: Apache-2.0
# Metal4-only tile grid with SRAM-aligned columns. The following flow step
# extends these columns through the abstract macro blockage to its real pins.
source $::env(SCRIPTS_DIR)/openroad/common/io.tcl
source $::env(SCRIPTS_DIR)/openroad/common/set_global_connections.tcl
set_global_connections
source [file join [file dirname $::env(PDN_CFG)] sram_geometry.tcl]
set columns [jp_sram_columns]
set block [ord::get_db_block]
set core [$block getCoreArea]
set dbu [$block getDbUnitsPerMicron]
set inst [$block findInst program_store.i_sram]
set macro_box [$inst getBBox]
set_voltage_domain -name CORE -power $::env(VDD_NET) -ground $::env(GND_NET)
define_pdn_grid -name stdcell_grid -starts_with POWER -voltage_domain CORE -pins Metal4
proc jp_stripe {center net core dbu} {
    add_pdn_stripe -grid stdcell_grid -layer Metal4 -width 2.1 \
        -pitch 10000 -number_of_straps 1 -nets [list $net] \
        -offset [expr {($center - [$core xMin]) / double($dbu)}] -extend_to_boundary
}
dict for {center net} $columns { jp_stripe $center $net $core $dbu }
# Retain the ordinary grid away from the macro's x-range. Every stripe crossing
# the SRAM is one of its own supply columns, so a stripe cannot short its rails.
for {set center [expr {[$core xMin] + 10000}]} {$center < [$core xMax] - 2100} {incr center 38870} {
    foreach {shift net} [list 0 $::env(VDD_NET) 4100 $::env(GND_NET)] {
        set x [expr {$center + $shift}]
        if {$x > [$core xMax] - 1050} { continue }
        if {$x >= [$macro_box xMin] - 1550 && $x <= [$macro_box xMax] + 1550} { continue }
        if {![jp_column_clears_signal_pins $x]} { continue }
        jp_stripe $x $net $core $dbu
    }
}
add_pdn_stripe -grid stdcell_grid -layer Metal1 -width $::env(PDN_RAIL_WIDTH) -followpins
add_pdn_connect -grid stdcell_grid -layers {Metal1 Metal4}
~~~

### Snapshot 6: src/power_sram.tcl

~~~tcl
# SPDX-License-Identifier: Apache-2.0
source $::env(SCRIPTS_DIR)/openroad/common/io.tcl
read_current_odb
# Each LibreLane step starts a new process. Resolve supplies again before
# inspecting the saved grid or checking the extended macro connections.
source $::env(SCRIPTS_DIR)/openroad/common/set_power_nets.tcl
source $::env(PROGRAM_SRAM_GEOMETRY)
set block [ord::get_db_block]
set die [$block getDieArea]
set layer [[ord::get_db_tech] findLayer Metal4]
set columns [jp_sram_columns]
set wires [dict create]
foreach name [list $::env(VDD_NET) $::env(GND_NET)] {
    set net [$block findNet $name]
    dict set wires $name [odb::dbSWire_create $net ROUTED]
}
dict for {center name} $columns {
    set left [expr {$center - 1050}]
    set right [expr {$center + 1050}]
    odb::dbSBox_create [dict get $wires $name] $layer \
        $left [$die yMin] $right [$die yMax] STRIPE
    set term [$block findBTerm $name]
    if {$term == "NULL"} { error "Supply boundary pin required" }
    set pin [odb::dbBPin_create $term]
    $pin setPlacementStatus FIRM
    odb::dbBox_create $pin $layer $left [$die yMin] $right [$die yMax]
}
# Connectivity errors stop the flow. These checks include the macro supplies.
foreach name [list $::env(VDD_NET) $::env(GND_NET)] {
    check_power_grid -net $name
    # Replace the pre-extension metric only after this net passes its check.
    utl::metric_integer "design__power_grid_violation__count__net:$name" 0
}
utl::metric_integer design__power_grid_violation__count 0
puts "Program SRAM: extended 40 LEF-derived supply columns to tile boundaries"
write_views
~~~

### Snapshot 7: librelane_plugin_program_sram.py

~~~python
"""Connect the program SRAM to the CMOS5L tile's Metal4 power pins."""
from pathlib import Path

from librelane.steps import Step
from librelane.steps.openroad import OpenROADStep
from librelane.steps.netgen import LVS
from librelane.config import Variable
from librelane.common import Path as ConfigPath
from tools.netgen_json import normalize_sram_power_pins, repair_report
from librelane.state import State, DesignFormat


@Step.factory.register()
class PowerProgramSRAM(OpenROADStep):
    id = "Project.PowerProgramSRAM"
    name = "Connect Program SRAM Supply Columns"
    config_vars = OpenROADStep.config_vars + [
        Variable("PROGRAM_SRAM_GEOMETRY", ConfigPath,
                 "SRAM power-column geometry helper",
                 default=ConfigPath(str(Path(__file__).resolve().parent / "src" / "sram_geometry.tcl")))
    ]

    def get_script_path(self):
        return str(Path(__file__).resolve().parent / "src" / "power_sram.tcl")


@Step.factory.register()
class ProgramSRAMLVS(LVS):
    id = "Project.ProgramSRAMLVS"
    name = "Netgen LVS with SRAM report compatibility"

    def run(self, state_in, **kwargs):
        original = Path(state_in[DesignFormat.POWERED_NETLIST])
        adapted = Path(self.step_dir) / "netgen_powered_netlist.v"
        adapted.write_text(normalize_sram_power_pins(original.read_text()))
        # This copy is local to LVS. The original flow state and all other
        # consumers retain the OpenROAD powered netlist.
        lvs_state = State(state_in, overrides={
            DesignFormat.POWERED_NETLIST: ConfigPath(str(adapted))
        })
        return super().run(lvs_state, **kwargs)

    def run_subprocess(self, *args, **kwargs):
        result = super().run_subprocess(*args, **kwargs)
        report = Path(self.step_dir) / "reports" / "lvs.netgen.json"
        if report.is_file():
            count = repair_report(report)
            if count:
                self.warn(f"Preserved {count} literal identifier escapes in Netgen JSON. "
                          "Original report retained as lvs.netgen.json.original.")
        return result
~~~

### Snapshot 8: src/sram_256x16_lvs.spice

~~~spice
* SPDX-License-Identifier: Apache-2.0
* Abstract LVS pin interface derived from the official IHP SRAM LEF.
* Contiguous descending bus order lets Netgen infer full vector widths.
.SUBCKT RM_IHPSG13_1P_256x16_c2_bm_bist
+ A_ADDR[7] A_ADDR[6] A_ADDR[5] A_ADDR[4] A_ADDR[3] A_ADDR[2] A_ADDR[1] A_ADDR[0]
+ A_BIST_ADDR[7] A_BIST_ADDR[6] A_BIST_ADDR[5] A_BIST_ADDR[4] A_BIST_ADDR[3] A_BIST_ADDR[2] A_BIST_ADDR[1] A_BIST_ADDR[0]
+ A_BIST_BM[15] A_BIST_BM[14] A_BIST_BM[13] A_BIST_BM[12] A_BIST_BM[11] A_BIST_BM[10] A_BIST_BM[9] A_BIST_BM[8]
+ A_BIST_BM[7] A_BIST_BM[6] A_BIST_BM[5] A_BIST_BM[4] A_BIST_BM[3] A_BIST_BM[2] A_BIST_BM[1] A_BIST_BM[0]
+ A_BIST_CLK A_BIST_DIN[15] A_BIST_DIN[14] A_BIST_DIN[13] A_BIST_DIN[12] A_BIST_DIN[11] A_BIST_DIN[10] A_BIST_DIN[9]
+ A_BIST_DIN[8] A_BIST_DIN[7] A_BIST_DIN[6] A_BIST_DIN[5] A_BIST_DIN[4] A_BIST_DIN[3] A_BIST_DIN[2] A_BIST_DIN[1]
+ A_BIST_DIN[0] A_BIST_EN A_BIST_MEN A_BIST_REN A_BIST_WEN A_BM[15] A_BM[14] A_BM[13]
+ A_BM[12] A_BM[11] A_BM[10] A_BM[9] A_BM[8] A_BM[7] A_BM[6] A_BM[5]
+ A_BM[4] A_BM[3] A_BM[2] A_BM[1] A_BM[0] A_CLK A_DIN[15] A_DIN[14]
+ A_DIN[13] A_DIN[12] A_DIN[11] A_DIN[10] A_DIN[9] A_DIN[8] A_DIN[7] A_DIN[6]
+ A_DIN[5] A_DIN[4] A_DIN[3] A_DIN[2] A_DIN[1] A_DIN[0] A_DLY A_DOUT[15]
+ A_DOUT[14] A_DOUT[13] A_DOUT[12] A_DOUT[11] A_DOUT[10] A_DOUT[9] A_DOUT[8] A_DOUT[7]
+ A_DOUT[6] A_DOUT[5] A_DOUT[4] A_DOUT[3] A_DOUT[2] A_DOUT[1] A_DOUT[0] A_MEN
+ A_REN A_WEN VDD! VDDARRAY! VSS!
.ENDS RM_IHPSG13_1P_256x16_c2_bm_bist
~~~

### Snapshot 9: tools/netgen_json.py

~~~python
"""Preserve literal identifier backslashes in malformed Netgen JSON reports."""
import json
from pathlib import Path
import re


def normalize_sram_power_pins(text):
    """Adapt only the SRAM's supply-pin tokens to Netgen's Verilog dialect."""
    instance = re.compile(
        r'(\bRM_IHPSG13_1P_256x16_c2_bm_bist\s+\\program_store\.i_sram\s+\()(.*?)(\);)',
        re.DOTALL,
    )
    matches = list(instance.finditer(text))
    if len(matches) != 1:
        raise ValueError('Expected one program_store.i_sram in the powered netlist')
    match = matches[0]
    body = match[2]
    for pin in ('VDD!', 'VDDARRAY!', 'VSS!'):
        token = re.compile(r'\.\\?' + re.escape(pin) + r'\s*\(')
        body, count = token.subn('.' + pin + '(', body)
        if count != 1:
            raise ValueError(f'Expected one SRAM supply connection for {pin}')
    return text[:match.start(2)] + body + text[match.end(2):]


def repair_identifier_escapes(text):
    """Repair unsupported string escapes, preserving valid JSON escapes."""
    output = []
    in_string = False
    repairs = 0
    i = 0
    while i < len(text):
        char = text[i]
        if char == '"':
            in_string = not in_string
        if in_string and char == '\\' and i + 1 < len(text):
            next_char = text[i + 1]
            valid = next_char in '"\\/bfnrt' or (
                next_char == 'u' and re.fullmatch(r'[0-9a-fA-F]{4}', text[i + 2:i + 6])
            )
            if valid:
                output.append(text[i:i + 2])
                i += 2
                continue
            output.append('\\\\')
            repairs += 1
            i += 1
            continue
        output.append(char)
        i += 1
    return ''.join(output), repairs


def repair_report(path):
    """Validate first and retain the original report when repairing escapes.

    Structural errors still raise JSONDecodeError. Counts and comparisons are
    unchanged, so LibreLane's normal LVS metric/checker path remains active.
    """
    path = Path(path)
    original = path.read_text()
    try:
        json.loads(original)
        return 0
    except json.JSONDecodeError as error:
        if error.msg not in ('Invalid \\escape', 'Invalid \\uXXXX escape'):
            raise
    repaired, count = repair_identifier_escapes(original)
    json.loads(repaired)
    path.with_suffix(path.suffix + '.original').write_text(original)
    path.write_text(repaired)
    return count
~~~

### Snapshot 10: test/Makefile

~~~makefile
# Makefile
# See https://docs.cocotb.org/en/stable/quickstart.html for more info

# defaults
SIM ?= icarus
FST ?= -fst # Use more efficient FST format
TOPLEVEL_LANG ?= verilog
SRC_DIR = $(PWD)/../src
PROJECT_SOURCES = defines.vh igorchip_top.v program_host.v program_memory.v sram_256x16_bb.v top.v
SRAM_MODEL_DIR = $(PWD)/ihp_sram
COMPILE_ARGS += -DSIM -DFUNCTIONAL
VERILOG_SOURCES += $(SRAM_MODEL_DIR)/RM_IHPSG13_1P_core_behavioral_bm_bist.v
VERILOG_SOURCES += $(SRAM_MODEL_DIR)/RM_IHPSG13_1P_256x16_c2_bm_bist.v

ifneq ($(GATES),yes)

# RTL simulation:
SIM_BUILD				= sim_build/rtl
VERILOG_SOURCES += $(addprefix $(SRC_DIR)/,$(PROJECT_SOURCES))

else

# Gate level simulation:
SIM_BUILD				= sim_build/gl
COMPILE_ARGS    += -DGL_TEST
COMPILE_ARGS    += -DFUNCTIONAL
COMPILE_ARGS    += -DSIM
# Foundry flip-flops and multiplexers use the companion UDP definitions.
VERILOG_SOURCES += $(PDK_ROOT)/ihp-sg13cmos5l/libs.ref/sg13cmos5l_stdcell/verilog/sg13cmos5l_udp.v
VERILOG_SOURCES += $(PDK_ROOT)/ihp-sg13cmos5l/libs.ref/sg13cmos5l_io/verilog/sg13cmos5l_io.v
VERILOG_SOURCES += $(PDK_ROOT)/ihp-sg13cmos5l/libs.ref/sg13cmos5l_stdcell/verilog/sg13cmos5l_stdcell.v

# this gets copied in by the GDS action workflow
VERILOG_SOURCES += $(PWD)/gate_level_netlist.v

endif

# Allow sharing configuration between design and testbench via `include`:
COMPILE_ARGS 		+= -I$(SRC_DIR)

# Include the testbench sources:
VERILOG_SOURCES += $(PWD)/tb.v
TOPLEVEL = tb

# List test modules to run, separated by commas and without the .py suffix:
COCOTB_TEST_MODULES = test

# include cocotb's make rules to take care of the simulator setup
include $(shell cocotb-config --makefiles)/Makefile.sim
~~~

### Snapshot 11: test/test_sram.py

~~~python
"""Exercise the foundry macro's masks, clocked reads and enable semantics."""
from pathlib import Path
import shutil
import subprocess
import tempfile
import unittest

ROOT = Path(__file__).resolve().parents[1]


class SRAMTests(unittest.TestCase):
    def simulate(self, body, instance, extra_sources=()):
        self.assertTrue(shutil.which("iverilog") and shutil.which("vvp"))
        with tempfile.TemporaryDirectory(prefix="protocol-sram-") as directory:
            p = Path(directory)
            (p / "tb.v").write_text("`timescale 1ns/1ps\nmodule tb;\n" + instance +
                                    "\ninitial begin\n" + body +
                                    '\n$display("PASS"); $finish; end\nendmodule\n')
            sources = [ROOT / "test/ihp_sram/RM_IHPSG13_1P_core_behavioral_bm_bist.v",
                       ROOT / "test/ihp_sram/RM_IHPSG13_1P_256x16_c2_bm_bist.v", *extra_sources]
            compiled = subprocess.run(["iverilog", "-g2012", "-DSIM", "-DFUNCTIONAL",
                                       f"-I{ROOT / 'src'}", "-s", "tb", "-o", str(p / "sim"),
                                       str(p / "tb.v"), *map(str, sources)], capture_output=True, text=True)
            self.assertEqual(compiled.returncode, 0, compiled.stderr)
            result = subprocess.run(["vvp", str(p / "sim")], capture_output=True, text=True, timeout=15)
            self.assertEqual(result.returncode, 0, result.stdout + result.stderr)
            self.assertIn("PASS", result.stdout)

    def test_macro_partial_mask_enable_and_output_hold(self):
        self.simulate('''
            #1; tick();
            wen=0; ren=1; tick(); if(q!==16'hA55A) $fatal(1,"full word");
            wen=1; ren=0; bm=16'h00F0; d=16'h0030; tick();
            if(q!==16'hA55A) $fatal(1,"write-only must hold output");
            wen=0; ren=1; tick(); if(q!==16'hA53A) $fatal(1,"bit mask");
            men=0; wen=1; d=0; bm=16'hFFFF; tick();
            if(q!==16'hA53A) $fatal(1,"disabled output");
            men=1; wen=0; tick(); if(q!==16'hA53A) $fatal(1,"disabled write");
            addr=0; ren=0; tick(); if(q!==16'hA53A) $fatal(1,"read disabled");
        ''', '''
            reg clk=0, men=1, wen=1, ren=0;
            reg [7:0] addr=255;
            reg [15:0] d=16'hA55A, bm=16'hFFFF;
            wire [15:0] q;
            RM_IHPSG13_1P_256x16_c2_bm_bist memory(
              .A_CLK(clk), .A_MEN(men), .A_WEN(wen), .A_REN(ren),
              .A_ADDR(addr), .A_DIN(d), .A_BM(bm), .A_DLY(1'b1), .A_DOUT(q),
              .A_BIST_CLK(1'b0), .A_BIST_EN(1'b0), .A_BIST_MEN(1'b0),
              .A_BIST_WEN(1'b0), .A_BIST_REN(1'b0), .A_BIST_ADDR(8'd0),
              .A_BIST_DIN(16'd0), .A_BIST_BM(16'd0));
            task tick; begin #5; clk=1; #5; clk=0; end endtask
        ''')

    def test_wrapper_byte_preservation_read_edge_and_reset_retention(self):
        self.simulate('''
            #1; tick(); high=1; d=8'hA5; tick();
            we=0; tick(); if(q!==16'hA55A) $fatal(1,"byte ordering");
            we=1; high=0; d=8'h3C; tick(); we=0; tick();
            if(q!==16'hA53C) $fatal(1,"opposite byte preserved");
            addr=0; if(q!==16'hA53C) $fatal(1,"read must await falling edge");
            addr=255; rst_n=0; tick(); if(q!==16'hA53C) $fatal(1,"disabled memory");
            rst_n=1; tick(); if(q!==16'hA53C) $fatal(1,"reset retains program");
        ''', '''
            reg clk=1, rst_n=1, we=1, high=0;
            reg [7:0] addr=255, d=8'h5A;
            wire [15:0] q;
            program_memory memory(.clk(clk), .rst_n(rst_n), .address(addr),
              .write_enable(we), .high_byte(high), .write_data(d), .read_data(q));
            task tick; begin #5; clk=0; #5; clk=1; end endtask
        ''', [ROOT / "src/program_memory.v"])
~~~

### Snapshot 12: .github/workflows/gds.yaml

~~~yaml
name: gds

on:
  push:
  pull_request:
  workflow_dispatch:

concurrency:
  group: gds-${{ github.workflow }}-${{ github.ref }}
  cancel-in-progress: true

jobs:
  gds:
    runs-on: ubuntu-24.04
    timeout-minutes: 180
    steps:
      - name: checkout repo
        uses: actions/checkout@v6

      - name: Build GDS
        timeout-minutes: 150
        uses: TinyTapeout/tt-gds-action@ihp-cmos5l
        with:
          pdk: ihp-sg13cmos5l

      - name: Preserve physical-flow diagnostics
        if: always()
        uses: actions/upload-artifact@v7
        with:
          name: gds-diagnostics-${{ github.run_attempt }}
          if-no-files-found: warn
          retention-days: 14
          path: |
            src/config*.json
            src/user_config*.json
            runs/wokwi/**/config*.json
            runs/wokwi/**/*.log
            runs/wokwi/**/*.rpt
            runs/wokwi/**/*.drc
            runs/wokwi/**/*.json
            runs/wokwi/**/*.json.original
            runs/wokwi/**/netgen_powered_netlist.v
            runs/wokwi/**/*.odb
            runs/wokwi/**/*.sdc
            runs/wokwi/**/*.guide

  precheck:
    needs: gds
    runs-on: ubuntu-24.04
    steps:
      - name: Run Tiny Tapeout Precheck
        uses: TinyTapeout/tt-gds-action/precheck@ihp-cmos5l

  gl_test:
    needs: gds
    runs-on: ubuntu-24.04
    steps:
      - name: checkout repo
        uses: actions/checkout@v6

      - name: GL test
        uses: TinyTapeout/tt-gds-action/gl_test@ihp-cmos5l

  viewer:
    needs: gds
    if: github.event_name != 'pull_request' && github.ref == format('refs/heads/{0}', github.event.repository.default_branch)
    runs-on: ubuntu-24.04
    permissions:
      pages: write # to deploy to Pages
      id-token: write # to verify the deployment originates from an appropriate source
    steps:
      - uses: TinyTapeout/tt-gds-action/viewer@ihp-cmos5l
~~~


<!-- END ORIGINAL DOCUMENT -->


---

## SOURCE: `docs/TIMING.md`

SHA256: `a3edc8aced6311ac2e8d47ab2d089498131b4ae65bc5cea40bcfd5413ead4704`

<!-- BEGIN ORIGINAL DOCUMENT -->

# Timing

When both `ena` and the host core-enable register are high, the scheduler grants
T0, T1, T2, T3 in order. Every context receives one grant per four clocks,
including halted and waiting contexts. A cycle WAIT(N) skips N subsequent
context grants. WAIT_PIN holds that context's PC until the synchronized input
matches, without delaying another context. GPIO input visibility includes
two synchronizer stages.

For `tools.protocols.uart_tx`, a bit lasts `4 * bit_grants` core clocks.
UART RX uses the same period, qualifying a start at half a bit and sampling
data and the stop bit around their centers. At a 50 MHz input clock the default 16-grant test period corresponds
to 781250 baud. Use a period suitable for the peer; 108 grants gives about
115741 baud at 50 MHz. RX requires an even grant period in 4..256; TX permits
3..257. These are cycle-derived rates, not measured board rates.

The start qualifier uses WAIT(bit_grants/2 - 2), IN, AND, and a conditional
branch. WAIT(bit_grants - 4) then places the first data sample at 1.5 bit
periods after start detection. Subsequent samples use WAIT(bit_grants - 2).
The stop check occurs at 9.5 periods. A low stop sets sticky error and halts.

The ASIC SRAM and FPGA program block RAM read on the falling edge.
The FPGA build selects JP_FPGA_SYNC_MEMORY. The next instruction is ready for rising-edge execution.
Both storage implementations pass the same cycle-model differential suite.
ASIC and FPGA timing include half-cycle paths into memory and from memory
to execution logic. SRAM Liberty timing participates in the ASIC flow.
The 50 MHz ASIC setting remains a target for full-layout timing qualification.

SPI mode-0 firmware uses `4 * half_grants` clocks per high/low data half-period.
The default 8 grants corresponds to 781250 Hz at 50 MHz. CS setup/hold and
final idle timing include additional instruction overhead.

I2C firmware explicitly waits for physical SCL high after releasing it. Clock
stretching therefore changes its period. `hold_grants` supplies an additional
hold after each phase; instruction and synchronization overhead must be included
when deriving bus timing. This example does not claim a particular I2C speed
class or electrical rise-time compliance.

Host SPI uses mode 0, MSB first. Hold CS assertion/deassertion for at least four
core clocks and each SCLK half-period for at least four core clocks; the core
clock must remain running. Host control writes suppress instruction retirement
for one clock and can stretch protocol timing. Avoid them during timed transfers,
except to interrupt an unwanted transaction. Other host reads do not stall the core. A DATA read while enabled is
rejected, sets an error, and suppresses one execution clock. LDI requires
two grants of its context for instruction and literal fetch.
`ena=0` pauses the scheduler and releases physical GPIO; toggling it during a
transaction changes the bus waveform.

Reset is asynchronous active-low for control/GPIO state. Program memory is
host-written, with no reset initialization. Timing closure, metastability MTBF,
and physical propagation delays have not been characterized.


<!-- END ORIGINAL DOCUMENT -->


---

## SOURCE: `docs/UPDATE_FOR_BEN.md`

SHA256: `fa96f7f376b56f1b619e6169823dba14055fa59d0e54b1874cd43011f331c48e`

<!-- BEGIN ORIGINAL DOCUMENT -->

# Draft progress update for Ben

Subject: JaneStreet programmable protocol engine — UART and verification update

Hi Ben,

Thanks for clarifying the priorities. I’m focusing on a programmable UART
implementation, with SPI and I2C running on the same architecture to cover
the required protocols.

Since my last update, I’ve integrated a host SPI program loader and four
independent execution contexts with configurable, disjoint output pin masks.
In RTL simulation, the firmware demonstrates UART 8N1 transmit and receive,
SPI mode-0 byte transfers, and single-master I2C writes with ACK sampling,
NACK-to-STOP handling, and clock stretching. A combined demo runs the four
contexts concurrently and uses 335 of the 512 available instruction words.

Verification now includes a Python cycle reference model, clock-by-clock
differential comparison with the RTL, reproducible randomized programs and
inputs, independent protocol waveform checks, and runtime safety assertions.
The local suite passed 18 tests, plus a pin-only cocotb test for programming,
readback, GPIO execution, and protection/control behavior.

I’ve documented the pin assignments and external interface requirements,
including the I2C pull-ups and compatible digital logic levels. Actual pull-up
values and electrical timing still need validation against the chosen board
and attached devices.

The earlier GDS-flow result predates these changes, so I haven’t yet claimed
physical-flow closure for this revision. Program storage is currently a
synthesizable array; SRAM macro integration and Tiny Tapeout precheck remain
pending. The assertions are simulation checks, and formal proof is also
still pending.

My next priorities are to extend UART error-case verification, run the updated
physical flow and precheck, and follow the applicable Tiny Tapeout SRAM
template once the configuration is established.

Repository: https://github.com/wlmoi/General-Purpose-Protocol-ASIC_JaneStreet

Thanks,
William


<!-- END ORIGINAL DOCUMENT -->


---

## SOURCE: `docs/VERIFICATION.md`

SHA256: `b273f8ad82a0d53859b8e2afe5623cd120312c6c952fa5781e47d620b7032f1e`

<!-- BEGIN ORIGINAL DOCUMENT -->

# Verification

The local stdlib suite has passed 42 tests using Python 3.11 and Icarus Verilog
with ASIC SRAM. CI also selects FPGA block RAM and the register-memory
reference implementation:

```text
python -m unittest discover -s test -p "test_*.py" -v
```

Fourteen tests cover model/host behavior: round-robin and halt; all supported
branch conditions and signed offset boundaries; 255-grant waits; enable
freezing; literal wrap; masked open-drain updates; rejected encodings;
demo size/ownership; RTL/tool geometry consistency; literal pause/restart;
host frame endianness; readback/transport failures; UART baud selection and
firmware period bounds; and explicit firmware error signaling.

Eighteen RTL regressions use `test/integration_tb.v`. Each simulation loads and
reads back all 256 program words through the external SPI pins, including
high byte-address bits and wraparound. No hierarchical memory writes are used.
Execution is compared every clock against `tools/reference_model.py`: scheduler
slot, all PCs, X/Y, receive registers, wait counters, halted/errors, output
values, and output enables. The input synchronizer pipeline is modeled too.

RTL cases cover randomized programs with reproducible seed 20261007, four
contexts, randomized external pins and `ena` pauses; branch/literal boundaries;
UART TX wire decoding and UART RX reception; SPI MOSI edge decoding and MISO
reception; I2C address/data/ACK wire decoding with physical SCL stretching;
NACK-to-STOP; all four protocol contexts concurrently; live-write protection;
stop/restart/reset; and overlapping-mask rejection and reassignment; rejected live memory reads
and out-of-range host addresses. Immediate GPIO operations are also included
in randomized differential tests.

Simulation safety invariants check known outputs, disabled output release,
output enables confined to owned pins, and pairwise-disjoint ownership. These
are runtime assertions, not formal proofs. Randomized differential testing
checks model consistency but is not exhaustive; independent wire-level checks
help catch shared model/RTL misunderstandings.

Expanded UART cases check idle arming, short start-pulse recovery, low stop-bit
framing status through the host, 0x00/0xFF/0x55/0xAA patterns, programmable pins,
start phases, RX grant counts from 4 to 256, and TX counts from 3 to 257.
An independent peer varies its bit period from 424 to 440 clocks against a
432-clock receiver. The firmware sets a sticky error and halts on a low stop.

Set JP_TEST_FPGA=1 when running the stdlib suite to compile with
JP_FPGA_SYNC_MEMORY. Set JP_TEST_REGISTER=1 to select the register-memory reference. CI runs all three variants and compares each against the same
cycle model, covering host readback, literals, reset, protection, and the
concurrent UART/SPI/I2C demo.

## Local FPGA implementation evidence

The complete Tiny Tapeout FabricFox wrapper passed synthesis, placement,
routing, and bitstream packing for ICE40UP5K on 2026-10-11. The local build
used Yosys 0.33, nextpnr-ice40 0.6, seed 10, the official FabricFox v2 pin
constraints, and a 12 MHz timing target. The packaged routing tool used a
workspace-relative device-database lookup.

| Metric | Local routed result |
|---|---:|
| Logic cells | 2460 / 5280, approximately 46% |
| Program block RAM | 1 / 30 |
| Post-route clock estimate | 17.25 MHz |
| Timing target | 12 MHz, passed |
| Packed bitstream | 104090 bytes |

Logs, the JSON netlist, routed ASC, and packed binary are local artifacts
under `build/fpga-check/`. CI uses Tiny Tapeout's official FPGA action and
OSS CAD Suite, providing a separate build result for its tool versions.
The workflow checks that the bitstream is present and the netlist contains
exactly one program block RAM.

Protocol timing on an FPGA uses its supplied core clock. At 12 MHz, 26 grants
per UART bit gives approximately 115385 baud. Use uart_bit_grants with the
actual clock when generating a program for a board.

`test/test.py` is a pin-only cocotb test that programs the chip, reads memory
back, runs a GPIO program, rejects a live write, and releases pins on STOP.
The CI workflow runs the stdlib suite before the existing cocotb flow. A
matching gate netlist can use that pin-only test without hierarchical accesses.
The local pin-only cocotb test passed with cocotb 2.0.1 and Icarus Verilog 12.0
using `python -m tools.run_cocotb` (the Python runner does not require Make).

The locally mapped IHP netlist also passed the pin-only cocotb test using
zero-delay functional cell models generated from the mapping Liberty library:

```text
python -m tools.run_cocotb --netlist build/area/compact.v --cell-models build/area/compact-cells-functional.v
```

GitHub subsequently passed the Tiny Tapeout SG13G2 GDS build, precheck, gate-level
test, and viewer for commit `269b380`:
[physical-flow and gate-level results](https://github.com/wlmoi/General-Purpose-Protocol-ASIC_JaneStreet/actions/runs/37646552561).
The [RTL test workflow](https://github.com/wlmoi/General-Purpose-Protocol-ASIC_JaneStreet/actions/runs/37646552427)
also passed for that commit. These results establish CI success for the linked
revision; current workflow badges show later runs.

Formal properties have not been proved. SRAM layout sign-off, SDF timing
simulation, and board testing remain pending. See [area evidence](AREA_TIMING.md)
for the distinction between local mapping estimates and the physical-flow run.
The current ASIC workflow targets the competition's CMOS5L template and
matching gate-level models. The [CMOS5L CI run](https://github.com/wlmoi/General-Purpose-Protocol-ASIC_JaneStreet/actions/runs/38068425041)
completed GDS generation and the viewer for commit `3c099bd`. The following
local checks validate the simulation and power-grid updates on 2026-10-11.

The current RTL was mapped with Yosys 0.33 against the CMOS5L typical 1.20 V,
25 C Liberty library. Its pin-only cocotb regression passed through
`GATES=yes make` and the results checker, using cocotb 2.0.1, Python 3.12,
and Tiny Tapeout's Icarus 13 package. The models match the action's pinned
[PDK revision](https://github.com/IHP-GmbH/IHP-Open-PDK/tree/2bbec755dc67ca3db0261c3d6163e15735d66710).
The Makefile includes `sg13cmos5l_udp.v` alongside the standard-cell and
IO models, providing the foundry flip-flop and multiplexer primitives.
These results cover functional gate-level behavior. SDF timing qualification
is a separate milestone.

Before SRAM integration, an isolated OpenROAD power-grid check used the official CMOS5L technology
and cell LEFs, the six-by-four tile dimensions, a 38.87 micrometer pitch,
and the configured 2.1 micrometer Metal4 width. The generated LEF contains
33 full-height straps on each supply at 2.1 micrometers, matching the
[Tiny Tapeout power-pin width requirement](https://github.com/TinyTapeout/tt-support-tools/blob/d66cf179e7bc4d296362ab7e2e3b344dc3c4f665/precheck/tech_data.py).
Logs, the mapped netlist, and result reports are local artifacts under
`build/cmos5l-check/`. The SRAM revision uses the LEF-aligned supply grid described below.
Full-layout routing, DRC, and precheck qualification follow in the next CI run.

Streaming traffic, parity, additional SPI modes, I2C reads/arbitration, and
board electrical timing are development milestones.

## SRAM integration checks

Two additional regressions use the unchanged official IHP behavioral models.
They exercise bit-mask writes, byte preservation, address 255, output hold,
memory enable, read enable, falling-edge reads, and reset retention. Together
with the twelve model tests and seventeen RTL tests, the protocol and memory suite contains 31 tests. Eight additional regressions
cover SRAM LVS input adaptation and Netgen JSON report compatibility.

The SRAM-backed mapped netlist passed the pin-only gate-level Makefile test
with Tiny Tapeout Icarus 13 and the official CMOS5L standard-cell models.
An OpenROAD fixture using the real SRAM LEF, Liberty, standard-cell LEFs,
and tile dimensions executed the repository PDN scripts. Both supply-net
connectivity checks passed, including VDD!, VDDARRAY!, and VSS!.

The fixture validates macro supply geometry and connectivity. The complete
placed and routed SRAM layout receives DRC, LVS, timing, and Tiny Tapeout
precheck qualification in the next physical-flow run.

The PDN supply-name regression uses LibreLane's actual set_power_nets.tcl
and set_global_connections.tcl with the Tiny Tapeout VPWR/VGND defaults,
the real SRAM, and a legally placed IHP inverter. Procedure-scoped PDN
generation and both supply-connectivity checks pass. The local OpenROAD
fixture adapts only the newer global_connect verbosity option to its older
command interface. This check exercises the standard-cell VDD/VSS pins and
all SRAM supplies together.

The PDN generation and SRAM extension checks also pass as two separate
OpenROAD processes with an ODB save and reload between them. The extension
process starts with VDD_NET and GND_NET absent and resolves them through
LibreLane's set_power_nets.tcl. Both supply checks pass after extension,
covering the same process boundary used by the GitHub flow.

## SRAM routing diagnosis on 2026-10-13

The supplied GitHub log reached detailed-routing iteration 47 with about
4000 spacing and short violations, then the six-hour hosted job limit.
The updated configuration moves the SRAM away from the bottom boundary,
uses an eight-micrometer placement halo, and uses the installed LEF's
routing obstructions and pin-access windows. Standard-cell placement targets
40% density.

A standalone OpenROAD check uses the complete Yosys-mapped design, inserted
tie cells, the official six-by-four DEF pin template, and the real CMOS5L
and SRAM physical libraries. The updated placement and both supply checks
pass. Global routing handles 4559 nets with zero overflow on Metal2,
Metal3, and Metal4. The standalone harness removes an empty synthetic
constant net created by its Verilog reader before detailed routing.

This check provides routing evidence for the revised floorplan. The official
flow also performs CTS, timing repair, extraction, assembled-layout DRC,
LVS, and Tiny Tapeout precheck. Those stages qualify a completed GDS build.

The standalone detailed-routing probe reached its early repair iterations,
with 5815 violations after the initial iteration. It was stopped during the
first repair iteration. It uses an older local OpenROAD and omits the
official flow's CTS and timing-repair stages, so it establishes pin access
and a partial routing result. Detailed-routing DRC closure and completed
GDS qualification remain requirements for the updated official build.

## SRAM LVS interface and report checks

The supplied run 38393577062 reached Netgen LVS in about 22 minutes. Netgen
created a placeholder SRAM cell and reported top-level pin mismatches. Its
JSON report also contained an invalid identifier escape, which interrupted
LibreLane's metrics parser.

The committed SPICE pin interface names all 109 physical LEF ports. Bus pins
use contiguous descending indices so Netgen can infer the full vector widths.
It is loaded before the powered top-level netlist through EXTRA_SPICE_MODELS.
The project LVS step adapts the SRAM's three escaped supply-pin tokens to
Netgen's input dialect in a separate file. The original powered netlist
remains available to every other flow step.

The JSON compatibility handler repairs unsupported identifier escapes,
preserves the original malformed report, and validates the repaired JSON.
Structural report errors still fail. LibreLane's existing mismatch metrics
and Checker.LVS remain active.

A real Netgen 1.5.270 fixture derived from the pinned SRAM LEF matches all
109 pins with zero LVS errors. Deliberately connecting VDDARRAY! to ground
produces 110 LVS errors. The scoped adapter also processes a real OpenROAD
powered netlist. Eight Python regressions cover supply-token isolation,
missing and duplicate instances, valid escapes, invalid escapes, preserved
mismatch data, and structural JSON failures.

These checks validate the SRAM interface and report handling. Complete-chip
LVS, routed timing, and Tiny Tapeout precheck qualify the updated official run.

An end-to-end fixture executes Project.ProgramSRAMLVS through LibreLane
Step.start with the real Netgen subprocess. Correct wiring reports zero
errors and the supply fault reports 110. Both runs preserve the original
powered-netlist reference in the returned flow state.

## Targeted SRAM programming and physical pin safety

The [official CMOS5L run for commit 1649be6](https://github.com/wlmoi/General-Purpose-Protocol-ASIC_JaneStreet/actions/runs/38425106175)
passes GDS generation, Tiny Tapeout precheck, and gate-level simulation.
The final reports record zero LVS errors, zero KLayout DRC errors, and zero
power-grid violations. Netgen reports a unique circuit match. The same
revision passes RTL, FPGA, and datasheet workflows. Viewer publication runs
on the default branch.

A local replay of the complete routed engine reproduces the original
interface-pin shorts and passes LVS after selecting power columns with
placed pins. Its corrected layout and schematic each contain 5,330 devices
and 5,305 nets, with zero LVS errors.

The flow applies the official DEF template before PDN generation. Native
OpenROAD checks require placed signal pins, reject the original unplaced
interface, and verify zero overlaps between supply-pin rectangles and all
43 template signal pins. Both extended supply networks pass connectivity.

The 42-test suite includes host word readback and range checks before SPI
activity. An external-pin RTL regression patches word addresses 0, 127,
128, 254, and 255, changes individual bytes, and checks all 256 words
for preservation of untouched data.

The full reports from run 38401026075 identify boundary power-column shorts
and 16 M4.b errors. The updated geometry guard rejects that placement. A
new OpenROAD fixture includes all 43 official DEF signal pins and the complete
mapped engine. Both supply checks pass, and exported post-extension metrics
record zero power-grid violations.


<!-- END ORIGINAL DOCUMENT -->


---

## SOURCE: `docs/connect_de10.md`

SHA256: `9e1de60d74a483dba8dbdbdd8afd0899d615ce88b1a5eeccfe541162a8446178`

<!-- BEGIN ORIGINAL DOCUMENT -->

# Satu script koneksi Jetson?DE10

## Pilihan termudah: satu file mandiri

Salin `tools/de10_connect.py` ke folder mana saja di **Jetson**, lalu jalankan:

```bash
python3 de10_connect.py
```

File ini sudah membawa script koneksi, codec, gateway dan fixture Q8.8.
Asset diverifikasi checksum lalu disiapkan di `.igor_de10_connect/<versi>/`
di sebelah file; tidak memerlukan clone repo lengkap di Jetson atau HPS.
Log gateway versi mandiri berada di folder cache itu dan lokasinya dicetak.
Gunakan folder yang dapat ditulis oleh akun Jetson.

## Alternatif: dari workspace lengkap

Jalankan di **Jetson**, dari workspace yang sudah berisi pembaruan Ethernet:

```bash
cd ~/igor_ws
python3 tools/connect_de10.py
```

Default menggunakan akun HPS `fpga`, interface Jetson `enP8p1s0` bila tersedia,
IP Jetson 192.168.50.1/24 dan HPS 192.168.50.2/24. Akun HPS harus benar-benar
ada. Jika akun berbeda atau console perlu dipilih:

```bash
python3 tools/connect_de10.py --user root --console /dev/ttyUSB0
```

Gunakan `root` hanya bila itu akun Linux HPS yang memang tersedia dan diizinkan
login SSH; script tidak membuat akun/password atau mengubah kebijakan SSH.
Nama /dev/ttyUSB0 di contoh harus diganti sesuai perangkat console DE10 pada Jetson.

## Yang dilakukan otomatis

1. Inventaris interface dan carrier Jetson; konfigurasi IP sementara tanpa
   menghapus IP/default route lain. Verifikasi mesin lokal Jetson sebelum mutasi.
2. Jika carrier aktif tetapi SSH alamat default belum terjangkau, periksa
   neighbor IPv4 yang sudah dikenal pada interface kabel dan subnet /24 yang
   sama. Hanya satu kandidat SSH yang dipilih; identitasnya tetap diperiksa
   setelah login. Tidak memindai Wi-Fi/subnet penuh atau menebak IP di subnet
   lain. Jika belum terjangkau, pilih FT232R console
   yang unik, atau gunakan --console. Console selalu 115200 baud.
3. Login HPS melalui prompt biasa. Identitas ARMv7/SoCFPGA diverifikasi sebelum
   mengubah IP; kernel Tegra/aarch64 Jetson tidak diterima sebagai DE10.
4. Aktifkan interface dan IP HPS, lalu mulai service SSH/sshd/dropbear yang sudah
   terpasang. Password sudo HPS diminta bila diperlukan.
5. Tunggu carrier, ping, autentikasi SSH dan verifikasi identitas HPS sekali lagi.
6. Deploy dua file gateway/protokol dari workspace ke `igor_ws` pada HOME akun
   HPS. Memerlukan tar, Python 3.8+ dan akses tulis ke folder itu.
7. Jalankan gateway pada sesi SSH, lalu uji 10 transaksi UDP secara otomatis.
8. Tampilkan status terhubung. Terminal tetap terbuka untuk menjaga gateway;
   Ctrl+C mengakhiri sesi/gateway yang dijalankan script. IP sementara tetap ada.

Default **NETWORK ONLY** memakai backend mock berstatus 6. Keberhasilan jaringan
belum berarti inferensi FPGA berhasil. Script tidak menyimpan password, tidak
mengabaikan verifikasi fingerprint SSH, tidak memprogram FPGA, dan tidak
mematikan server lain yang sudah menggunakan UDP 8080. Hentikan gateway/service
lama lebih dahulu bila ingin script ini mengelola sesi baru.

## Uji FPGA asli, masih satu perintah

Setelah link/network-only berfungsi, hentikan sesi dengan Ctrl+C. Pastikan image
UART benar, KEY1 dilepas, KEY0 sudah di-reset, dan USB-UART adapter lokal HPS
tersambung ke JP1. Kemudian:

```bash
python3 tools/connect_de10.py --hardware --baud 9600 --fpga-serial /dev/ttyUSB0
```

Jika terjadi timeout/error UART, lepas KEY1 dan reset KEY0 sebelum mencoba
ulang hardware. Script tidak dapat menekan tombol reset FPGA secara otomatis.

`--console` adalah port **di Jetson** untuk terminal Linux HPS.
`--fpga-serial` adalah port **di HPS DE10** untuk adapter lokal menuju FPGA.
Keduanya bukan link/perangkat yang sama, walaupun nama ttyUSB0 bisa kebetulan sama.
Jika adapter USB di HPS tepat satu, --fpga-serial dapat dihilangkan. Pemilihan
ambigu dihentikan, tidak ditebak. Mode hardware membutuhkan pyserial di HPS.
Expected: FPGA PASS 10/10, default input raw Q8.8 menghasilkan [-46,60,34].

## Syarat fisik dan software

- Kabel RJ45 Jetson?DE10 terpasang dan perangkat mendapat daya.
- MicroSD DE10 berisi Linux/BSP yang benar dan Linux HPS benar-benar boot.
- Untuk bootstrap pertama: USB-UART **console** DE10 disambungkan ke Jetson.
  USB-Blaster ke PC boleh tetap terpasang, tetapi bukan console Linux.
- Jetson: Python 3, iproute2, ping, OpenSSH client; pyserial untuk USB console.
- HPS: iproute2, SSH server/service dan akun login yang sudah disiapkan, tar,
  Python 3.8+. Gateway hardware juga memerlukan pyserial dan izin port serial.
- Akun harus mempunyai izin sudo/root untuk mengubah IP. Script meminta
  autentikasi normal, tidak melewati password atau memasang paket OS otomatis.

Jika masih `carrier=0` setelah bootstrap HPS, script berhenti dengan petunjuk
kabel/PHY/boot. Software tidak bisa memperbaiki kabel lepas, SD tanpa Linux,
atau layanan SSH/Python yang belum terpasang. Jangan memaksa fixed speed/duplex
sebagai pengganti perbaikan link fisik.

## Opsi diagnostik

```bash
# Hanya membaca interface; tanpa sudo, mutasi IP atau membuka console
python3 tools/connect_de10.py --check-only

# Pilih interface jika deteksi otomatis ambigu
python3 tools/connect_de10.py --interface enP8p1s0 --hps-interface eth0 --console /dev/ttyUSB0

# Paksa bootstrap console bila IP HPS salah, meskipun carrier sudah aktif
python3 tools/connect_de10.py --bootstrap-console --console /dev/ttyUSB0
```

Log gateway disimpan sebagai `igor_connect_<timestamp>_<suffix>.log` di root
workspace Jetson. Untuk log inferensi lengkap dan konfigurasi persisten, lihat
[eth_direction.md](../eth_direction.md). Script ini memakai konfigurasi IP dan
SSH gateway per sesi; tidak memasang service auto-boot.

## Validasi

`python -m unittest discover -s test -p test_connect_de10.py` memeriksa pemilihan
interface/console, penolakan identitas Jetson sebagai HPS, parsing marker serial,
password sudo, penanganan kegagalan dan mode check-only memakai fixture.
Versi mandiri juga diuji dari folder kosong tanpa repository, termasuk
pemasangan asset ulang dengan checksum yang sama. Regenerasi file mandiri
dengan `python tools/package_de10_connect.py` bila asset sumber berubah.
Ini pengujian software; bootstrap/login dan link fisik pada kedua board tetap
harus dicoba oleh operator. Tidak ada klaim perangkat fisik sudah terhubung.

## Jika carrier=1 tetapi console tidak terdeteksi

Link Ethernet sudah terbentuk; itu belum membuktikan IP HPS, boot Linux atau
SSH siap. Script terbaru melaporkan tahap tersebut secara terpisah. Periksa:

```bash
ip neigh show dev enP8p1s0
lsusb
sudo dmesg -w
```

Saat dmesg berjalan, colokkan port USB-UART console DE10 ke Jetson memakai
kabel data dan lihat apakah driver membuat ttyUSB/ttyACM. Jangan menggunakan
port USB-Blaster sebagai console. Jika tidak ada serial device sama sekali,
--console /dev/ttyUSB0 tidak akan membuat perangkat itu muncul. Periksa
konektor, kabel data dan pesan USB/driver terlebih dahulu.

Jika sudah mengetahui IP HPS pada subnet lain, berikan kedua alamat yang
sesuai dengan --hps-ip dan --jetson-ip. Jangan menganggap alamat ARP dari
Wi-Fi sebagai alamat DE10 pada kabel. Tanpa alamat HPS yang dapat dijangkau
atau console yang bekerja, script tidak dapat memasang konfigurasi pada HPS.

## Perbaikan otomatis driver USB console

Versi terbaru membaca VID/PID dari sysfs USB. Jika FT232R 0403:6001 terlihat
tetapi belum ada ttyUSB, script meminta sudo untuk `modprobe ftdi_sio`, menunggu
udev dan memeriksa port lagi. Tidak melepas driver lain atau membuat device node.
Jika hanya USB-Blaster/JTAG yang terlihat, script menjelaskan bahwa connector
tersebut bukan console. Jika FT232R tidak terlihat pada bus USB, memuat driver
secara acak tidak akan menyelesaikan enumerasi USB.

Konektor console DE10 harus masuk ke USB HOST **Jetson** agar terlihat pada
/dev Jetson. Jika console terhubung ke PC, buka console dari PC; Jetson tidak
akan melihat perangkat USB milik PC melalui kabel Ethernet. Port UART GPIO
Jetson seperti ttyTHS1 bukan pengganti USB-UART console tersebut.


<!-- END ORIGINAL DOCUMENT -->


---

## SOURCE: `docs/direct_uart_runbook.md`

SHA256: `d9dcf39ddef2efafe3c58daa02bc295ea23f6e3a7af90b5b12f6e0a7c6fd344c`

<!-- BEGIN ORIGINAL DOCUMENT -->

# Verified Jetson GPIO → FPGA inference

On 2026-10-18, production FPGABridge passed 98/98 real FPGA requests at
921600 baud, matching all expected fixed-point outputs. Mean RTT 4.594 ms,
max 5.920 ms. Ethernet to HPS separately passed 10/10 network-only requests.
See [full diagnosis](jetson_de10_diagnosis.md).

## Wiring and reset

| Jetson header | FPGA DE10 JP1 |
|---|---|
| pin 8 TX | pin 1 RX |
| pin 10 RX | pin 2 TX |
| pin 9 GND | pin 12 GND |

Use 3.3 V signals. Remove the temporary Jetson pin 8–10 loopback jumper.
Program the **Parallel8 921600** image. With KEY1 released, press/release
**only KEY0**. Expected idle: LED1 on, LED3–LED7 off. KEY1 is E-stop and
latches until KEY0 reset; LED3+LED4 means stop_active plus E-stop fault 1.
Do not disable that guard to obtain replies.

## Repeat the inference test, without motors

```bash
cd /home/toyotateamaitb/igor_ws
python3 src/igor_pipeline/scripts/uart_test.py --port /dev/ttyTHS1 --baud 921600 --iter 50 --timeout 1
```

Expected: 50/50, raw Q8.8 [-46,60,34], CRC-valid 11-byte replies.
Only one process may own ttyTHS1.

## Build and inspect the ROS launch

The session build/install is under /tmp and may disappear after reboot:

```bash
source /opt/ros/humble/setup.bash
source /tmp/igor-uart-install/setup.bash
ros2 launch igor_bringup bringup.launch.py --show-args
```

To make a normal workspace build instead:

```bash
source /opt/ros/humble/setup.bash
colcon build --base-paths src waypoint_list --packages-up-to igor_bringup igor_controller
source install/setup.bash
```

Bringup now exposes fpga_baudrate and fpga_timeout. The declared
waypoint_action dependency ensures the planner's action interface is built.

## Full hardware launch, after sensors/STM32 are connected

This command starts the motor driver. It has not been executed in this session.
First verify device paths, restrain/lift the robot, clear the FPGA E-stop latch,
and complete sensor/STOP acceptance before sending movement commands.

```bash
ros2 launch igor_bringup bringup.launch.py \
  algorithm:=cl_drl_cbf use_fpga:=true \
  fpga_port:=/dev/ttyTHS1 fpga_baudrate:=921600 fpga_timeout:=0.02 \
  mcu_port:=/dev/ttyACM0 lidar_port:=/dev/lidar \
  use_mock_serial:=false launch_planner:=false
```

The 20 ms inference deadline matches the target control period; test under
actual system load before claiming 50 Hz operation. Existing freshness and
fault STOP checks remain enabled. A 10 Hz LiDAR does not continuously satisfy
a 25 ms freshness lease; the physical sensor/control contract requires review
and testing rather than weakening the lease to force motion.

This direct UART route sends 74 processed observation features and receives
three AI residuals. Jetson performs filtering, kinematics and STM32 commands.
It does not send full raw scans to FPGA or run AI over Ethernet.

For Ethernet AI, HPS still needs a connection to fabric (the implemented
gateway uses a separate HPS-local USB-UART adapter and matching kernel driver).
Do not point production ROS at the network-only mock backend.


<!-- END ORIGINAL DOCUMENT -->


---

## SOURCE: `docs/info.md`

SHA256: `6e82812f5c9ceb1199ad784ad33a92d60a2c60129aea1b017afc37ac9398c369`

<!-- BEGIN ORIGINAL DOCUMENT -->

## How it works

This is a programmable digital protocol engine with four independent execution
contexts sharing 256 x 16-bit host-loaded program storage. A deterministic
round-robin scheduler grants one context per enabled clock, so each context
executes at most one instruction every four core clocks.

Each context has a program counter, X/Y registers, a receive shift register,
a wait counter, and a host-configured output ownership mask. Masks must be
disjoint. Instructions support immediate/literal loads, arithmetic and shifts,
conditional branches, synchronized GPIO reads, sampled serial bits, bounded
cycle waits, pin-level waits, push-pull outputs, open-drain outputs, and halt.
GPIO updates affect only the issuing context's assigned pins.

Protocol behavior is firmware rather than dedicated UART/SPI/I2C hardware.
The integrated RTL regressions demonstrate UART 8N1 transmit and receive,
SPI mode-0 byte transfers, and single-master I2C writes with ACK sampling,
NACK-to-STOP handling, and clock stretching. A combined program demonstrates
all four contexts operating concurrently. UART RX qualifies the start-bit
center and checks the stop-bit center. Framing errors set a host-visible
sticky context error before the receive program halts.

Program storage uses the IHP RM_IHPSG13_1P_256x16_c2_bm_bist SRAM macro
with one shared read port and masked byte writes. The concurrent demo uses
254/256 words. Local CMOS5L mapped logic plus the SRAM footprint totals
86868.7954 square micrometers, approximately 9.6% of the supplied core area. GitHub passed the
Tiny Tapeout SG13G2 GDS build, precheck, gate-level test, and viewer for commit
`269b380`: [recorded CI result](https://github.com/wlmoi/General-Purpose-Protocol-ASIC_JaneStreet/actions/runs/37646552561).
See [area evidence](AREA_TIMING.md) for the synthesis method and physical-flow status.
The current competition workflow targets CMOS5L using the official
`ihp-cmos5l` action and matching gate-level models.

## How to test

From the repository root, with Python 3.11+, Icarus Verilog, and `vvp` on PATH:

```text
python -m unittest discover -s test -p "test_*.py" -v
python -m tools.build_demo --output build/demo
```

The first command runs model/host tests and RTL regressions. RTL tests load
and read back the full program image through the external SPI pins, compare
execution against the Python model every clock, and decode protocol waveforms.
The second command generates `program.hex` and `contexts.json` for a four-context
demo. UART defaults target 115200 baud at a 50 MHz core clock. Use
`--clock-hz` and `--uart-baud` to generate firmware for the supplied clock
and attached UART peer. Select SPI and I2C timing for the attached devices.

Reset with `rst_n` low. Reset pauses the core, halts every context, clears
ownership masks, and releases GPIO. Program storage is not initialized by
reset: load every instruction and literal reachable by your program before
starting it. Configure pin masks and entry points while paused, start the
contexts, then enable execution. See [host interface](HOST_INTERFACE.md)
for the SPI register map and Python driver example.

`ena` pauses execution and releases physical GPIO when low. A software pause
preserves output levels/enables; a host STOP releases the selected contexts'
pins. HALT preserves outputs, allowing UART idle and SPI chip-select states.

## External hardware

The organizer describes digital pins with 3.3 V I/O on the Tiny Tapeout demo
board. The host uses `ui[0]` for CS_n, `ui[1]` for SCLK, `ui[2]` for MOSI,
and `uo[0]` for MISO, leaving all eight bidirectional pins for protocols.
Use a 3.3 V-compatible host and peripheral interfaces with a common ground.

The generated demo uses UART RX on `uio[0]`, UART TX on `uio[1]`, I2C SDA/SCL
on `uio[2:3]`, and SPI SCK/MOSI/MISO/CS_n on `uio[4:7]`. These are firmware
assignments, not fixed-function pins. UART here uses logic levels; other
physical interfaces require suitable external transceivers.

I2C requires external pull-ups on SDA and SCL to the compatible I/O supply.
Resistor values must be selected for bus capacitance, rise time, and sink-current
limits; the simulation's ideal pull-ups do not validate physical resistor
values. No other external component is required by the RTL tests.
See [GPIO and board wiring](GPIO.md) for the complete connection table.

## Design priorities and limitations

Organizer feedback prioritizes flexibility, architectural novelty, and
verification quality without fixed judging weights. UART, SPI, and I2C are
the required protocol coverage. See [organizer guidance](DESIGN_PRIORITIES.md).

The supplied firmware handles one byte/frame/transaction at a time. UART
parity, other SPI modes, I2C reads and multi-master
arbitration, automatic pin-wait timeouts, and streaming FIFOs remain future
work. A stuck pin wait can be interrupted using host STOP. Formal proof,
SRAM layout sign-off, detailed post-route area/timing analysis, and board
measurements remain outstanding. See [verification](VERIFICATION.md) and
[implementation](IMPLEMENTATION.md).


<!-- END ORIGINAL DOCUMENT -->


---

## SOURCE: `docs/jetauto_rectangle_test.md`

SHA256: `d95adfeda79bd4e538874710c8424b6717b8fd9c453696fc090f8a26f131f758`

<!-- BEGIN ORIGINAL DOCUMENT -->

# JetAuto wheel tests and 5 m × 4 m left-turn route

## Physical checks completed, 2026-10-18

- Identified STM32: `/dev/ttyACM0`, USB 1a86:55d4, serial 5917012181.
- Tested each wheel individually at 0.5 RPS for 0.75 s, STOP between channels.
  **User confirmed front-left, rear-left, front-right, rear-right moved in that
  order and all stopped.** Final STOP packets were sent.
- RPLiDAR `/dev/lidar` → `/dev/ttyCH341USB0`: health OK; ten physical scans
  captured, 1080 samples per scan. Measured inter-scan interval about 74 ms.
- STM32 passive five-second capture: **550 valid IMU frames**, 100 gamepad
  frames, five system frames; zero CRC errors.
- Source controller now stops for invalid/stale sensors, respects actual scan
  angles, rejects missing physical MCU rather than switching to mock, verifies
  serial write lengths, uses monotonic leases, and closes with STOP.
  Automatic reverse recovery is replaced by zero wheel speed because the rear
  path is not verified. Zero input cannot become residual-generated movement.
- Active-source scan validation now accepts the actual SLAMTEC ~359° coverage;
  it rejects NaN, invalid ranges and invalid/stale stamps.
- Real zero-command sensor→FPGA→controller preflight obtains healthy
  diagnostics, and all executed velocity commands remain exactly zero.

## Requested geometry

This is a rectangle: **5 m forward → left 90° → 4 m forward → left 90° →
5 m forward → left 90° → 4 m forward → left 90°**, ending with initial heading.

Two implementations are available:

1. `rectangle_route`: measured-pose version, waits for a real `/pose` source.
   The existing command-integrating demo pose is not measured localization.
2. `timed_rectangle`: explicitly requested no-localization test. Estimates
   each leg and quarter-turn by integrating the **controller's executed
   velocity commands**, not measured motion. Slip, calibration, steering and
   obstruction can change actual dimensions and closure. It does not prove
   a measured 5 m × 4 m path.

Timed defaults: 0.20 m/s straight, +0.30 rad/s turns, 0.5 s zero interval
between stages. Nominal motion is about 111 s plus pauses. Nonzero unexpected
reverse/lateral/right-turn commands, stale scans/diagnostics, scheduling gaps,
segment/total timeout, transport errors or close obstacles stop the run.

## Prepared command

The current session was built under /tmp; normal persistent build instructions
are in [direct_uart_runbook.md](direct_uart_runbook.md).

```bash
source /opt/ros/humble/setup.bash
source /tmp/igor-uart-install/setup.bash
ROS_LOG_DIR=/tmp/igor-rectangle-run python3 tools/run_timed_rectangle.py \
  --run --floor-ready \
  --output-dir docs/ethernet_validation/rectangle_NEW_RUN_NAME
```

Use a new output directory each time. Omitting `--run --floor-ready` performs
only a zero-velocity preflight. Stop with Ctrl+C; cleanup stops the route
publisher, sends zeros, closes the chassis controller and independently sends
three final STOP packets. An abrupt loss of Jetson power/USB is outside this
software STOP mechanism; the supervisor must have an immediate physical stop.

The robot must be in its normal driving position, with wheels on the floor,
first leg pointing along the clear 5 m side, and a supervised clear perimeter.
The 0.45 m all-around LiDAR clearance requirement is checked before motion.
Do not run other serial owners, teleop or waypoint publishers concurrently.

The physical LiDAR driver used is installed `rplidar_ros`; no synthetic scan
fallback is used. For this supervised low-speed test, sensor lease is **150 ms**
based on measured 74 ms scan updates. The default 25 ms lease remains the
bringup default. This is a test configuration, not a full braking certification.

## Latest route attempts

- First preflight rejected scans because the active source required overly
  exact 360° coverage; fixed and regression-tested against actual metadata.
- Second zero-command preflight obtained 22 healthy diagnostics but detected
  close returns; no route started, all commands zero, final STOP sent.
- User corrected the robot's orientation after LiDAR was scanning the floor.
- First motion-requested preflight obtained 30 healthy diagnostics, but detected
  a 0.284 m return. **Route did not start**, all commands remained zero,
  final STOP sent.
- Follow-up scan found 0.294 m at about +80° and 0.408 m at about −121°.
  Requested those nearby objects/people be moved beyond 0.5 m before retry.

Evidence is under `docs/ethernet_validation/jetauto_*`. Wheel physical outcome
comes from the user's observation; serial write success is not a motor ACK.
No completed floor rectangle is claimed by these preflight results.

## Requested expanded wheel-group test

`tools/test_jetauto_wheels.py` now supports four individual wheels, all six
unique pairs, and all four together: **11 pulses**, default 0.5 RPS for
0.75 seconds each, STOP and pause between groups. Right-side motor signs
remain mirrored. Plan uniqueness, group cardinality, packet lengths and CRCs
were checked without opening the serial port.

```bash
python3 tools/test_jetauto_wheels.py --groups singles pairs four \
  --run --wheels-raised \
  --output docs/ethernet_validation/wheel_groups_NEW_RUN_NAME.json
```

This command requires all wheels lifted, securely supported and clear. The user subsequently confirmed all four wheels lifted and clear. The expanded
sequence completed **11/11 command groups**, with final STOP sent. Capture:
[jetauto_wheel_groups_20261018_run1.json](ethernet_validation/jetauto_wheel_groups_20261018_run1.json).
The user confirmed **all 11 groups moved and stopped correctly**. Physical
acceptance is user-observed; the serial interface supplies no motor feedback.


<!-- END ORIGINAL DOCUMENT -->


---

## SOURCE: `docs/jetson_de10_diagnosis.md`

SHA256: `acc3e8a067fa8c1b43654230d3259105889bdbf7880a7820331003aae689e929`

<!-- BEGIN ORIGINAL DOCUMENT -->

# Jetson → DE10 diagnosis, 2026-10-18

## Updated result after HPS console access

**Ethernet is fixed and physically tested. Direct Jetson UART inference now
passes 98/98 production-bridge checks after clearing the FPGA E-stop latch.
The Ethernet-to-fabric gateway still requires an HPS-to-fabric connection
absent from the confirmed direct wiring.**

### Final direct-UART acceptance

With Parallel8 loaded and KEY1 released, resetting only KEY0 restored the
idle pattern (LED1 on, LED3–LED7 off). The next three UART tests returned the
exact expected Q8.8 [-46,60,34], CRC-valid response
`5a a5 02 06 d2 ff 3c 00 22 00 61`.

Then the actual production FPGABridge, mock=false, ttyTHS1/921600,
passed **50 fixed + 48 varied transactions across 16 fixtures: 98/98**.
Mean RTT **4.594 ms**, max **5.920 ms**, zero over 20 ms in this sample.
These are measured end-to-end UART times, not inferred FPGA cycle counts or
a real-time scheduling guarantee. The earlier CLI byte-at-a-time reader
measured 13.329 ms mean over three transactions; the production bridge reads
the response differently.

- [Hardware acceptance capture](ethernet_validation/jetson_fpga_bridge_20261018_acceptance.jsonl)
- [Latency summary](ethernet_validation/jetson_fpga_bridge_20261018_summary.json)
- [Direct UART run instructions](direct_uart_runbook.md)

Root causes addressed: HPS DHCP-only configuration on the isolated cable;
previously incorrect UART wiring; FPGA image/baud mismatch history; and an
active/latched E-stop, which intentionally suppressed UART replies. Jetson
UART loopback verified 512 exact bytes at both 115200 and 921600.

No physical LiDAR/STM32 was visible at the last check. No motor commands
were sent. Sensor freshness, actual control-loop timing under load, physical
fault STOP and motion acceptance remain outstanding.

- Console enumerated as FT232R `0403:6001`, stable Jetson path
  `/dev/serial/by-id/usb-FTDI_FT232R_USB_UART_B402QWPK-if00-port0`.
- Logged into HPS as `fpga`, verified ARMv7 Cyclone V SoCFPGA identity.
  Kernel: `6.12.100-armv7-fpga`; userspace Python 3.13.5. Device-tree
  compatibility reports `terasic,de0-atlas` and `altr,socfpga-cyclone5`;
  image/BSP provenance should be checked before replacing the kernel.
- Root cause: HPS interface **end0** used DHCP on a direct link with no DHCP
  server, leaving it at `169.254.243.36/16`. Added `192.168.50.2/24`.
- Jetson → HPS ping: **3/3**, mean **0.723 ms**. HPS → Jetson: **2/2**.
- SSH works; host public key verified through the USB console and pinned in
  `/tmp/igor_hps_known_hosts` for this session.
- Deployed gateway/codec under `/home/fpga/igor_ws` on HPS.
- Physical UDP network-only test: **10/10**, mean **1.639 ms**, max **2.465 ms**.
  Capture: [jetson_hps_network_20261018.jsonl](ethernet_validation/jetson_hps_network_20261018.jsonl).
  Production client rejected status 6 as required. Temporary mock gateway
  stopped after the test; no mock production service was installed.
- Saved Jetson NetworkManager profile `enP8p1s0`: static 192.168.50.1/24,
  autoconnect=yes, ipv4.never-default=yes. Saved HPS ifupdown config
  `/etc/network/interfaces.d/end0`: static 192.168.50.2/24, no gateway;
  original backed up as `/etc/network/end0.before-igor`. `ifquery end0` passes.
  Live link remains up; reboot persistence is configured but not reboot-tested.
- Installed pyserial 3.5 offline into `/home/fpga/igor_ws/.venv`, without
  changing system Python. Use `.venv/bin/python` for HPS UART/gateway commands.
  The generic connection script currently invokes system Python; its hardware
  mode needs system pyserial or an equivalent interpreter adjustment.
- User confirms Parallel8 **921600** image. Later clarification establishes
  that UART is wired directly from Jetson GPIO to FPGA JP1; there is no
  confirmed separate HPS-local USB-UART adapter.
  HPS still sees **only usb1/root hub**, no downstream USB device or plug event.
  Its only serial ports are ttyS0 (Linux console) and ttyS1 (not a verified
  route to the fabric). Do not use the console port for AI packets.
- Running kernel config: `CONFIG_USB_DWC2_HOST=y`, but
  **`CONFIG_USB_SERIAL` and `CONFIG_USB_ACM` are disabled**. No matching driver
  modules, build/source links, or kernel headers are installed. `modprobe`
  cannot supply a driver omitted from this kernel.

### Remaining steps for FPGA inference specifically over Ethernet

1. Check the adapter is connected to DE10 micro-USB OTG through a host/OTG
   cable, with suitable power; it must enumerate as a downstream USB device.
   Obtain adapter model/VID/PID. USB enumeration must work before driver binding.
2. Install/build a **board-compatible** kernel with `CONFIG_USB_SERIAL` and
   the actual adapter driver (FTDI_SIO, CP210X, CH341, etc.), or USB_ACM for a
   CDC ACM device. Matching source/config and boot/recovery procedure are
   needed before changing this custom HPS kernel. No kernel or bootloader was
   replaced during this session.
3. Once the adapter has a tty, grant `fpga` access to its actual device group,
   verify the JP1 TX/RX/GND wiring, and run known-vector UART validation at
   **921600** using the isolated interpreter.
4. Run fixed/matrix real FPGA Ethernet inference, fault injection, latency
   acceptance, then configure the real UART gateway service. Do not substitute
   the successful network-only test for FPGA acceptance.

## Initial measurements before HPS console access

- Host: AArch64, NVIDIA Tegra kernel `5.15.148-tegra`.
- Wired interface is **enP8p1s0**, not eth0.
- Ethernet carrier is **1**, link **1000 Mb/s full duplex**, autonegotiation on.
  This establishes a physical link to a peer, not the identity or Linux readiness
  of that peer.
- Jetson already has **192.168.50.1/24**. Route to 192.168.50.2 selects
  enP8p1s0 with source 192.168.50.1. Wi-Fi retains the default route.
- Three interface-bound pings to **192.168.50.2**: 0 replies, 100% loss.
- Neighbor entry for that address: INCOMPLETE, subsequently FAILED. No other
  known IPv4 neighbor was reported on the wired interface.
- TCP/22 connection times out. One validated network-only UDP/8080 request
  also times out: Requested=1, Attempted=1, Passed=0.
- `lsusb` shows hubs, keyboards and Bluetooth, **no DE10 FT232R console**,
  USB-Blaster or external USB serial adapter. No /dev/ttyUSB*, /dev/ttyACM*,
  or /dev/serial/by-id directory is present.
- NetworkManager's current enP8p1s0 profile has autoconnect=no. The current
  address should not be assumed to survive reboot. No OS/network-manager
  settings were changed during this diagnosis.

The initial failure was peer IP/L2 reachability. It precedes the gateway and
FPGA inference protocol. Possible causes include HPS Linux not booted, a
wrong HPS IP/interface, or the cable reaching another peer. Carrier alone
cannot distinguish these. No evidence supports blaming the Jetson PHY or
solving this by forcing link speed.

## Repository corrections

- ROS bringup default UDP endpoint now matches 192.168.50.2:8080.
- Temporary network helper selects enP8p1s0 when present, otherwise a unique
  physical wired interface; defaults to 192.168.50.1/24, uses address replace,
  and reports errors instead of suppressing them. It preserves other addresses
  and routes. Shell syntax checked; live mutation was unnecessary and not run.
- Regenerated standalone tools/de10_connect.py from current source assets;
  its embedded assets had different line endings from the checked-out files,
  causing the standalone/source equivalence regression to fail.
- README and pipeline_docs now point to current Ethernet instructions.
  test.md now describes actual UART framing and gateway commands.

## Verification on the Jetson

| Check | Result |
|---|---|
| Ethernet regression, real localhost UDP + simulated UART | 16/16 pass |
| Connection automation / standalone bundle | 18/18 pass |
| UART regression fixtures | 14/14 pass |
| Host/bridge/controller fail-closed regression | 29/29 pass |
| ROS Humble launch description construction and endpoint assertion | pass |
| Network helper bash syntax and launch Python compilation | pass |
| Physical DE10 UDP transaction | timeout, not accepted |

Ethernet regression needed execution outside the sandbox because sandbox
policy denies sockets. Its initial permission errors were environment errors.
ROS launch construction used ROS_LOG_DIR under /tmp because the sandbox does
not allow writing ~/.ros. No motors were commanded, no FPGA programmed, and no
hardware inference success is claimed. Host regression refreshed its source
hash evidence in fpga/evidence/current_host/results.json.

## Required next input and hardware steps

1. Connect the DE10 **USB-UART console** connector to a Jetson USB HOST port
   using a data cable. Supply the actual HPS Linux username; enter credentials
   interactively, rather than storing passwords in the repository. Alternatively
   use its console on another PC and provide boot output and `ip -br addr`.
2. Confirm a compatible HPS Linux microSD boots. From that console inspect
   `uname -m`, `ip -br link`, and `ip -br addr`. On the actual HPS wired interface,
   configure 192.168.50.2/24 and enable its existing SSH server. Merely loading
   the neural FPGA SOF does not supply these Linux services.
3. Retry ping and `python3 tools/connect_de10.py --user ACTUAL_HPS_USER`.
   This deploys/tests a network-only gateway; it is not hardware AI acceptance.
4. For actual inference, install the **HPS-local USB-to-3.3 V TTL UART adapter**
   specified in eth_direction.md. The supplied FPGA image has UART rather than
   a native HPS bridge. A console cable is separate from this adapter.
5. Program the matching Parallel8 image, test local fabric UART, then run
   fixed and matrix Ethernet inference and fault-injection acceptance tests
   from eth_direction.md. Use 921600 for latency testing; 9600 needs at least
   171 ms per exchange and cannot meet 50 Hz.
6. Once the link works, persist the existing wired profile with static address,
   autoconnect and never-default settings, and install the edited HPS service
   only after its manual hardware test passes.
7. Before motion, attach/verify LiDAR and STM32, measure full inference latency
   against the 20 ms control period, and check sensor freshness under actual
   scan rate. The controller's 25 ms freshness threshold and documented ~10 Hz
   LiDAR rate need acceptance testing; weakening guards does not establish
   safe operation. Complete a restrained motor STOP/fault test before routes.

The implemented payload is a 74-feature observation prepared on Jetson
(64 LiDAR features, six IMU values, nominal twist, heading). Full raw scans
are not sent. AI residuals return to Jetson for filtering/kinematics and STM32
motor commands. A native Ethernet/HPS-to-fabric memory path or raw-sensor FPGA
preprocessing would require additional hardware/software implementation.

## Follow-up after connecting the USB data cable

A subsequent inventory detects **09fb:6010 Altera DE-SoC** with two
vendor-specific USB interfaces. This is the programming/JTAG connection;
there is still no serial port in pyserial or /dev/ttyUSB*. The USB-UART console
connector must also be connected to reach HPS Linux. HPS username was supplied
as `fpga`; no password is recorded in this report or repository. Reading the
kernel log through noninteractive sudo was unavailable because sudo requires
local authentication; USB descriptors and sysfs were readable without it.

Reference: [Intel DE10-Nano setup guide](https://www.intel.com/content/www/us/en/developer/articles/guide/terasic-de10-nano-get-started-guide.html)
distinguishes the UART console from the embedded USB-Blaster programming cable.

## Direct Jetson GPIO UART test after wiring correction

User clarified that FPGA UART is connected to Jetson header pins, rather than
an HPS-local USB adapter, and confirmed correcting the previously wrong wiring.
The HPS USB kernel limitations apply only to the gateway adapter approach;
they do not block this direct UART path.

- Jetson exposes ttyTHS1 at serial@3100000 and ttyTHS2 at serial@3140000.
  Existing repository diagnostics select ttyTHS1 for header UART.
- User has dialout membership; ttyTHS1 opens successfully with exclusive access.
  nvgetty and serial-getty@ttyTHS1 are disabled/inactive; no competing owner
  was reported by fuser.
- Physical test: ttyTHS1, 921600 8N1, three known vectors, one-second deadline.
  **0/3 passed; every transaction received zero bytes.** Expected output was
  raw Q8.8 [-46, 60, 34]. Capture is
  [jetson_direct_uart_20261018_run1.jsonl](ethernet_validation/jetson_direct_uart_20261018_run1.jsonl).
- Requested user release KEY1 and press/release KEY0 to clear any latched
  FPGA fault from the former wiring error, then report LED7–LED4 before retry.
- No pinmux, boot configuration, console services or FPGA image was changed.
  No motor command was sent.

If reset does not restore communication, isolate Jetson TX/RX with a temporary
header loopback **after disconnecting both FPGA signal wires**, and/or measure
TX/RX with a logic analyzer. Do not join TX to RX while both boards drive the
line. Verify common GND and JP1 physical orientation. A successful UART test
would establish direct serial AI offload; it would not establish the separate
HPS-to-fabric leg needed for Ethernet AI offload.

### Retry after confirmed FPGA reset

After user confirmed reset, repeated three known vectors at ttyTHS1/921600.
Again **0/3 passed, zero received bytes on every frame**. Capture:
[jetson_direct_uart_20261018_run2.jsonl](ethernet_validation/jetson_direct_uart_20261018_run2.jsonl).
A reset alone did not restore communication. Requested an isolated Jetson
header pin 8–10 loopback, with both FPGA signal wires disconnected, and the
FPGA LED7–LED4 pattern. No loopback transmission will be attempted before the
user confirms the isolated jumper is ready.

### Isolated Jetson UART loopback passed

After user confirmed that FPGA TX/RX were disconnected and Jetson pins 8/10
joined, ran `tools/uart_diagnose.py --port /dev/ttyTHS1 --mode loopback`.
Both **115200 and 921600 baud passed**, returning all **512 bytes exactly**;
no background RX was observed. Capture:
[jetson_loopback_20261018_run1.json](ethernet_validation/jetson_loopback_20261018_run1.json).
This validates the selected Jetson UART/header TX/RX path at both rates.
The remaining no-response fault is outside the isolated Jetson loopback path;
FPGA wiring, shared ground, reset/E-stop, loaded image and FPGA operation still
need validation. Requested removal of loopback jumper, restoration of FPGA
wiring, reset, LEDs and confirmation of programming since last power-up.

Parallel8 RTL defines LED[7:4]=error_code, LED3=stop_active,
LED2=response_valid, LED1=rst_n, LED0=permit. Quartus/JTAG CLI tools were not
found on Jetson PATH, so the running SRAM image has not been identified or
reprogrammed in this session.

### FPGA retry after successful Jetson loopback

After user confirmed FPGA reconnection, repeated known-vector testing at
921600 baud. **0/3 replies**, each zero bytes. Capture:
[jetson_direct_uart_20261018_run3.jsonl](ethernet_validation/jetson_direct_uart_20261018_run3.jsonl).
Requested actual LED0–LED7 state and confirmation of the programmed file since
last power-up, rather than another identical retry.

The checked-out `fpga/bitstreams/igor_src_policy_parallel8.sof` and experimental
SOF are **132-byte Git LFS pointers**, not programmable bitstreams. Expected
real Parallel8 object: size 6,690,394 bytes, SHA256
`cb2e0de357a3865b4058f89d34b54f59ab8604db0865a7ceefff436bd6230b49`.
Neither git-lfs nor Quartus/JTAG CLI is installed on this Jetson. Do not use
the pointer file in Quartus. A real bitstream and programming tool are needed
if the loaded image must be restored. No programming action was attempted.

### Reported FPGA LEDs identify active/latched E-stop

User reported LED1, LED3 and LED4 lit, and clarified the board had previously
been programmed at 9600 baud but has now been changed to Parallel8.
For the Parallel8 RTL, this pattern is reset released (LED1), stop_active
(LED3), and error_code=1 (LED4). `igor_src_policy_uart.v` assigns code 1 on
E-stop and holds its UART transmitter in reset while E-stop is active.
This explains absent replies for that reported state, assuming the loaded
image matches this RTL. The current pattern after image change still needs
confirmation.

Requested KEY1 remain fully released, followed by pressing/releasing only
KEY0. Expected idle after reset: LED1 on, LED3–LED7 off. Do not transmit another
inference request until user confirms the state. If LED3/4 remain on after
that sequence, inspect KEY1/button signal or image/pin assignment rather than
bypassing E-stop in software or RTL. No safety logic was altered.

### ROS packaging validation after hardware inference acceptance

Exposed `fpga_baudrate` (default 921600) and `fpga_timeout` (default 0.3 s)
in bringup and forwarded both to the controller. Direct UART run instructions
explicitly select ttyTHS1/921600 and a 20 ms deadline; no freshness guards changed.
Added the missing waypoint_action dependency to igor_controller/package.xml.

ROS Humble colcon build passed for waypoint_action, igor_navigation,
igor_controller and igor_bringup (4 packages, 15.5 s). Installed controller,
bridge, planner and generated action imports pass without instantiating nodes.
Installed launch `--show-args` passes. Build/install/logs are under
/tmp/igor-uart-build, /tmp/igor-uart-install and /tmp/igor-uart-build-logs.
No ROS hardware nodes or motor drivers were launched.
The 98-record physical capture was revalidated for expected integers and
16 distinct fixture cases. Diff whitespace checks pass.

## Wheel/sensor checks and requested rectangle implementation

See [JetAuto rectangle test report](jetauto_rectangle_test.md) for subsequent
physical tests and run commands. User confirmed all four individually pulsed
wheels moved in the expected order and stopped. Ten physical LiDAR scans and
550 CRC-valid IMU frames in five seconds were captured. The live
sensor→FPGA→controller pipeline now reports healthy diagnostics while commanded
zero. Both measured-pose and explicitly requested no-localization rectangle
runners are implemented. Source controller/MCU fail-closed gaps discovered
during hardware bringup were corrected and tested.

The timed 5 m first / 4 m second / four-left-turn route was requested on the
floor, but its preflight blocked it on 0.284 m close LiDAR returns. It did not
drive the route. Final STOP packets were sent. A follow-up diagnostic found
returns around +80° at 0.294 m and −121° at 0.408 m; clearance clarification
is pending. A repeat individual wheel test was requested; waiting for wheels
to be lifted again before sending nonzero wheel pulses.


<!-- END ORIGINAL DOCUMENT -->


---

## SOURCE: `docs/uart_expected/README.md`

SHA256: `71833008401acb5578ec5acb08e3caeb52e31445203b5656dcb622aa2e470b02`

<!-- BEGIN ORIGINAL DOCUMENT -->

# Expected result UART Parallel8

Input sama dengan `src/igor_pipeline/scripts/uart_test.py`:
64 observasi LiDAR bernilai 0.8, diikuti 10 nilai 0.0.
Setelah kuantisasi, 64 nilai pertama adalah 205 (Q8.8), sisanya 0.

| Hasil | Expected |
|---|---|
| UART | 9600, 8N1, flow control off |
| Request | 153 byte: `5a a5 01 94` + `cd 00` sebanyak 64 + `00 00` sebanyak 10 + CRC8 |
| Output Q8.8 | -46, 60, 34 |
| Residual | -0.1796875, 0.234375, 0.1328125 |
| Respons lengkap | `5a a5 02 06 d2 ff 3c 00 22 00 61` |
| CRC8 respons | 0x61; mencakup opcode, length dan payload |
| Uji 50 frame | sent 50, received 50, dropped 0 |
| Total respons | 550 byte untuk 50 transaksi; bukan per detik |
| Idle/reset | Tidak ada byte respons |

Ketiga nilai adalah residual model, bukan setpoint motor. Input test tetap,
sehingga setiap respons harus sama. Protokol fabric tidak membawa frame ID.
RTT harus diukur saat run; contoh terminal tidak mengarang angka RTT.

`expected.json` menyimpan input/output lengkap, hex TX/RX dan hash model.
`request.bin` dan `response.bin` menyimpan paket biner.
`expected_terminal.txt` adalah contoh hasil sukses, bukan hasil pengukuran Jetson.
`rtl_check/simulation.log` mencatat hasil pengujian input ini di RTL produksi.

Regenerasi oracle: `python tools/generate_uart_expected.py`.


<!-- END ORIGINAL DOCUMENT -->
