# S7 — the accelerator-only build

Status: on hardware since 2026-11-12 (section 3; the block-RAM build of
section 3a is on the card). The DDR3 build of section 3b is built and
simulated, **not flashed**.
Parents: [`gs_socket_s7_accelerator_scoping.md`](gs_socket_s7_accelerator_scoping.md)
(what the accelerator is) and
[`gs_socket_s7_fast_core_exploration.md`](gs_socket_s7_fast_core_exploration.md)
(§2d: why an accelerator-only card beside an a2p25; "Rung 5": the timing).

## 1. What it is

`a2mega_accel_138B.gprj` builds the a2mega 1.0a3 with the 138B SOM as a CPU
accelerator and nothing else:

- `hdl/twgs/gs_accel.sv`, the accelerator domain as one module: the socket
  PHY, the broker with the near memory and the two-clk step, the `F65C816`
  core with its microcode in block RAM, banks 00/01 and the ROM image in
  block RAM (128 KB each), and `gs_accel_romcopy`, which reads the ROM image
  through the socket.
- The ESP32 connector, for control and telemetry, with everything else it
  serves in the full build tied off.
- The slot side passive: level shifters on as inputs, the data bus never
  turned round, no /IRQ, /INH, /DMA or /RDY, the two daisy chains passed
  through. The one slot line the card can drive is /RESET, through the
  ESP32's reset hold, as in the full build.
- No framebuffer, DisplayPort, slot cards, slot ROM or I/O decode, or OSD.
  The DisplayPort balls are not ports of this top; they take the
  bitstream's unused-pin default (input with pull-up), as in the DP test
  builds. The DDR3 was left out the same way until section 3b, which gives
  it to the accelerator.

Clocks: the 50 MHz crystal; `clk_logic` (the board PLL's 54 MHz) for the
connector; `clk_gs` for the accelerator, from `gowin_gs_pll`, **the S6 socket
PLL, unchanged: 110 MHz**, so the core steps at **55 MHz**. (With the DDR3,
section 3b, the build is at 105 MHz and 52.5 MHz steps.)

> The decision recorded on 2026-11-12 was "108 MHz", made on the statement
> that S6's PHY had run on hardware at 108 MHz. It ran on this PLL, which is
> 110 MHz (50 MHz × 22 / 10; `hdl/a2mega_138b.sdc` constrains it at
> 9.091 ns); "108" is the nominal figure in the PHY's comments and the clock
> of the simulation bench. The build keeps the hardware-proven PLL and PHY
> rather than introduce a new PLL recipe for 2 %. Say so if a true 108 MHz
> is wanted; the same design closes there as well (probe `_n8`).

## 2. Control and telemetry

Through the connector's GS window, with the firmware the S6 build already
has (`gs`, `gs set <idx> <val>`, `gs trace` on telnet). Nothing in the
firmware was changed for this build.

| window register | S6 meaning | here |
|---|---|---|
| 0 CTRL | arm, sweep, listen, trace bits, clear | bit 0 arm, bit 2 listen, bit 7 clear, as S6 (the firmware's auto-arm drives it); the other bits do nothing |
| 2 | address-delay sweep | the same |
| 3 | data-hold sweep tap | nothing |
| 29 | trace trigger address, low | the accelerator's requests (below) |
| 30 | … high | nothing |
| 31 | … bank | **must hold `A5`**, or register 29 is ignored |

Requests in register 29:

| bit | name | effect |
|---|---|---|
| 0 | FAST | local steps at 55 MHz. Needs CARDMEM. |
| 1 | CARDMEM | the card's memory is the memory of record. In native mode its byte goes to the core and is compared with the socket's (the verify count). |
| 2 | CXROM | internal `$C100–$CFFF` firmware served from the image. Taken when the core is in reset or held (so: at /RES, or set it with COPY). |
| 3 | COPY | 0 → 1: read the ROM image through the socket. The core is held between two steps for about 46 ms. |

Bits 0–2 take effect only once an image has been copied since power-up.
**With register 29 at 00, or without the key, the card is S6 on the new
core: every step a socket cycle, every byte from the socket.** That is the
state after power-up, and after `gs trig` (which writes `FF FF FF` to
29–31: no key).

Telemetry is the S6 window with two fields carrying something else:

| field in `gs` | here |
|---|---|
| status, cycles, stalls, BE-low, PHI2 period and high time, last address | the same |
| hold mismatches | verify count |
| hold samples | `{mode, 5A}`; mode: bit 7 ROM image valid, 6 copy busy, 5 core held, 4 fast, 3 card memory, 2 cxrom |

`gs trace` prints 64 lines; here line *n* is telemetry word *n* (read
`bank:addr data` as one 32-bit number): 0 core steps, 1 socket cycles for
the core, 2 posted writes, 3 clks waited for the write buffer, 4 local
reads in place, 5 local reads that waited, 6 `{verify count, 00, mode}`,
7 address of the last verify mismatch, 8 `{copies, 00, sum of the image's
bytes mod 65536}`, 9 `{shadow, CYAREG, SLTROMSEL, STATEREG}`, 10 the other
switches, 11 PHY bus cycles. LEDs (active low): heartbeat, socket ours,
core running, fast.

## 3. A bring-up ladder (proposal)

Each step is observable before the next is taken. All four steps were run
once on 2026-11-12 (below), without video and with the machine idling.

1. **S6 equivalence.** Power up beside the a2p25; let the firmware arm as
   it does for S6; register 29 untouched. The machine should behave exactly
   as with the S6 bitstream. This is already new on hardware: the
   `F65C816` core, the broker's native mode and the 110 MHz core clock
   domain (S6's core ran on PHI2).
2. **Key and copy.** `gs set 31 0xA5`, `gs set 29 0x08`. Mode shows copy
   busy, then ROM image valid; word 8 gives the image's byte sum, to be
   compared with the sum of a dump of that machine's ROM. The machine
   pauses for about 46 ms.
3. **Card memory, native.** `gs set 29 0x0A`. The core now takes the card's
   bytes; the verify count must stay 0. A count that moves gives the
   address in word 7.
4. **Fast.** `gs set 29 0x0B`. LED 3 on; words 0 and 1 show steps running
   ahead of socket cycles.

Things to know before step 3:

- Banks 00/01 on the card hold what the core has **written since the
  socket was armed**. Anything else differs from the machine's RAM: RAM
  written before a re-arm without a power cycle, RAM written by slot DMA.
  Step 3 is where that shows.
- /RES during a copy cuts it short (image not valid; copy again). A warm
  reset keeps a valid image and the card's RAM.
- The step that was held and every byte in the near memory are not trusted
  after a copy: the near memory is emptied before the core goes on.

### First hardware run, 2026-11-12

ROM 01 IIgs, the card alone (no a2p25: no video, no boot device), slot
powered, firmware of Sep 13 2026 arming as for S6 (mode 4). Bitstream sha256
`48c06bbc…c8c04baa`, source 857d136c, flashed over USB with read-back verify.
Read over telnet with `gs`, `gs events` and `gs trace`.

| step | what was done | result |
|---|---|---|
| 1 | power-on, register 29 untouched | startup beep, then the ROM's no-device beep. Signature `5A`, mode 00. The core ran the ROM to the "No device connected!" screen and sat in its sliding-apple loop (FF:A55E–A5AA, polling `$C019`); 280 M steps, one socket cycle each, 0 stalls. Event log: release, arm 36 ms later, no /RESET fall afterwards |
| 2 | `gs set 31 0xA5`, `gs set 29 0x08` | mode 80, 1 copy, image sum `7EE8` = the sum of a ROM 01 image; the machine carried on |
| 3 | `gs set 29 0x0A` | mode 88; verify count 0 after 76 M cycles |
| 4 | `gs set 29 0x0B` | mode 98; rates over 12.7 s of wall clock: 3.566 M steps/s, 0.510 M socket cycles/s for the core, 1.020 M PHY cycles/s, 2.55 M local read hits/s, 0 misses, 119 posted writes/s (the loop's two text-screen writes per frame); 0 stalls; the core stayed in the same loop |

What this does and does not show:

- The loop is bound by the bus, not by the core: each pass reads `$C019`,
  a slow soft switch, so it runs 7 steps per socket cycle and one socket
  read per two Mega II cycles (a native pass takes four). It is no measure
  of the 55 MHz step rate: the longest local run in it is six steps.
- Fast mode has no byte-for-byte check, and there was no video. The
  evidence that the core stayed right is that it stayed in the loop, with
  the expected two forwarded writes per frame.
- Nothing but the idle loop has run: no program, no disk, no interrupts
  beyond what the ROM enables at that screen, no reset while fast.
- The telemetry words are read a byte at a time and are not latched: a
  word can be off by `0x100` or `0x10000` when a carry lands mid-read. Read
  twice before trusting a difference.

### With the a2p25 in slot 3, the same day

The same card and bitstream, an a2p25 in slot 3 for video and storage (a
USB stick on its hub), Marble Madness booting from the stick.

| step | result |
|---|---|
| power-on, two cards holding /RESET | the a2mega let go at 450 ms, the a2p25 held the line until 8.49 s (waiting for its stick), the firmware armed 26 ms after the rise; no /RESET fall afterwards. The game boots and plays on the new core: 2.07 M steps/s, one socket cycle each, 0 stalls |
| `gs set 29 0x08` with the game running | 1 copy, sum `7EE8` again |
| `gs set 29 0x0A` | verify count 0 after 95 M cycles, about 3.3 M bytes served by the card and compared |
| `gs set 29 0x0B` | the game keeps playing, with no artifacts and its music at tempo, but **slower**: 1.449 M steps/s against 2.077 M native. 1.184 M socket cycles/s for the core in 2.367 M PHY cycles/s: one idle cycle behind every cycle of the core |

Two things this showed:

- **The game runs from banks 02 and 03.** The card holds banks 00/01 and
  the ROM; expansion RAM on the card is S7d. Only about 3 % of the game's
  cycles are reads the card can serve, so fast mode has little to give it.
  Speed shows on software that lives in banks 00/01: eight-bit programs.
- **A defect: in fast mode a socket step behind a socket step waited a
  whole PHI2 cycle behind an idle one.** The sequencer decides a fast-mode
  step in its third clk; the PHY issues in the second. Fixed in the source
  after this run (scoping doc §10.5); the card still carries the build
  without the fix (aoz). The idle loop's "one socket read per two Mega II
  cycles" above is a different thing and stands: there the core runs six
  local steps between two reads, and an idle cycle is already on the bus
  when the next read is known.

A benchmark, the same evening, the same build (aoz, without the fix): a
TML Pascal program that times six tests at the machine's speed, waits for
the speed to be changed, and times them again. Times in 60ths of a second;
fast mode was switched on at its prompt (copy, card memory with a verify
count of 0, then fast).

| test | base | fast mode | ratio |
|---|---|---|---|
| 10 iterations of the sieve | 413 | 437 | 0.95 |
| selection sort of 500 strings | 1159 | 1060 | 1.09 |
| 100 iterations of a floating-point test | 475 | 49 | 9.7 |
| 15,000 Gamm units (floating-point mix) | 1545 | 314 | 4.9 |
| 10 iterations of Fibonacci calls | 2021 | 1794 | 1.13 |
| 5,000 iterations of integer math | 1564 | 1083 | 1.44 |

The program rates the floating-point test at 26 MHz and the Gamm mix at
13 MHz against a base it takes as about 2.5 MHz; its average is 8.5 MHz.
The split is the memory map again. The floating-point work is done by
SANE in the ROM, on a stack and direct page in bank 00: all the card's.
The sieve, the sort and the calls are the program's own code and data in
expansion RAM: every step a socket cycle, and with this build's defect a
socket step behind a socket step waits a cycle, so the sieve came out
slower than base.

**The same benchmark on fx2, the build with the fix** (flashed 19:38 the
same evening; the same machine, cards and firmware; the base pass run
again and within one tick of the first on every test):

| test | base | aoz, fast | fx2, fast | fx2 ratio | the program's MHz |
|---|---|---|---|---|---|
| 10 iterations of the sieve | 413 | 437 | 322 | 1.28 | 3.24 |
| selection sort of 500 strings | 1159 | 1060 | 805 | 1.44 | 3.63 |
| 100 iterations of a floating-point test | 476 | 49 | 41 | 11.6 | 31.35 |
| 15,000 Gamm units | 1546 | 314 | 253 | 6.1 | 16.25 |
| 10 iterations of Fibonacci calls | 2020 | 1794 | 1417 | 1.43 | 3.59 |
| 5,000 iterations of integer math | 1564 | 1083 | 863 | 1.81 | 4.57 |

The program's average went from 8.49 to 10.44 MHz. Every test is faster
than on aoz, by 1.20 to 1.36, and none is below base. At the program's
prompt the core takes 0.844 M socket cycles a second of the same 1.86 M
(aoz: 0.668 M), and steps 12.4 M times a second (aoz: 9.7 M). The build
ran the boot, the ROM copy (sum `7EE8`) and card memory (verify count 0)
as aoz did.

After fast mode has run, register 29 must not go back to 00 without a
reset: the machine's copy of banks 00/01 is stale by design. `0x0A` is the
way back to PHI2 pacing, and its verify count then means nothing.

## 3a. Banks 02/03 in block RAM (2026-11-12, not flashed)

`gs_accel` has a parameter `EXP_BANKS`, 0 or 2, and the board top sets 2:
expansion banks 02 and 03 in block RAM, beside banks 00/01 and on the same
terms. They follow every write of the core from the moment the socket is
armed; with card memory on they are the memory of record, and in native
mode each byte they give the core is compared with the socket's (the same
verify count). A stopgap for S7d's DDR3: 64 more blocks, 243 of 340.

- **Two banks, not four**, because the near memory's tag (`NEAR_KW = 4`:
  A14–A17) reaches bank 03 and no further. Four would want a wider tag
  and a new floorplan for the near blocks.
- **The machine must have banks 02/03 itself** (a memory card in a ROM 01
  machine). The card does not add memory the machine lacks.
- **A step in banks 02/03 is three or four clks, not two**: the first-clk
  cheap view covers banks 00/01 and the ROM only, so these steps are
  decided from the full decode. About 27 to 37 MHz against 55.
- Telemetry word 12 is `EXP_BANKS` (2 on this build, 0 on aoz and fx2).

**The far memories now have two clks in each direction.** The first build
with the 64 extra blocks failed 44 paths by up to 0.482 ns, everywhere:
the banks and the ROM image are 192 blocks all over the die, and three of
their paths were still single-clk, pulling the broker and the core apart.

| path | before | now |
|---|---|---|
| read data, blocks → the broker's `alt_q` | one clk | two: the broker waits a clk longer on a far read (`FAR_CLKS = 2`) and does not look at the data in the clk after its launch |
| RAM write, the broker's registers → blocks | one clk | through one more register per data bit in `gs_accel`: the write lands a clk later |
| read and write enables | one register to every block | a copy per data bit (`RA_COPIES = 8`) |

A step served by the near memory is unchanged. The late write is safe
because the broker cannot launch a far read until three clks and more
after it makes a write; the bench stops any run in which a read is
launched within two. In simulation the far data reads wrong in the clk it
is not yet valid, in the bench's model and in `gs_accel`, so a broker that
looked early would show. Cost: 60,000 steps of the test program take
9.455 ms against 9.444.

Verification: the suite is 102 runs, 14 of them with `gs_accel` holding two
banks and compared pin for pin with the bench's design in every clk
(native, paced, fast, toggling, with internal slot firmware, warm resets, a
machine with six expansion banks behind it, dense RDY stalls, and a ROM 01
boot): 247,013,471 clks; over all 49 runs with the module beside the
design, 535,896,565 clks. The test program runs code from bank 02 and, because
everything it wrote there stayed in the near memory, pushes those entries
out and reads the bytes back from the expansion blocks themselves, onto
the socket. Six mutations of the new logic, all detected (three were not
until that test existed). A bench fault found on the way: the final
comparison of the card's RAM could be taken in the clk the last step's
write was landing.

Timing, three placements of the committed source:

| build | failing | worst slack |
|---|---|---|
| fe1 (the far paths as they were) | 44 | −0.482 |
| **fe2, the committed source** | **0** | **+0.007** |
| fep1 (a telemetry constant changed) | 0 | +0.003 |
| fep2 (changed again) | 0 | +0.012 |

In fe2 the far data has 8.96 ns of slack on its two-clk path; the step
paths are where they were (core → core +0.21, near memory → core +0.08).
Size: 6,764 logic cells, 3,468 FF, 243 block RAMs. Build stamp
`20261112202241`, bitstream sha256 `6761a20a0f4d85f3…974a5dfb27`.

**On hardware** (flashed 21:10 the same evening; telemetry word 12 reads 2;
ROM copy sum `7EE8`; card memory at PHI2 pace for 17 s, about 24 M bytes
served and compared, verify count 0; then fast). The same benchmark:

| test | base | fx2, fast | fe2, fast | fe2 ratio | the program's MHz |
|---|---|---|---|---|---|
| 10 iterations of the sieve | 413 | 322 | 318 | 1.30 | 3.28 |
| selection sort of 500 strings | 1159 | 805 | 795 | 1.46 | 3.68 |
| 100 iterations of a floating-point test | 476 | 41 | 38 | 12.5 | 33.83 |
| 15,000 Gamm units | 1546 | 253 | 240 | 6.4 | 17.14 |
| 10 iterations of Fibonacci calls | 2020 | 1417 | 1401 | 1.44 | 3.64 |
| 5,000 iterations of integer math | 1564 | 863 | 853 | 1.83 | 4.63 |

The program's average went from 10.44 to 11.03 MHz: one to seven percent
per test. The two banks work (nothing wrong in 24 M compared bytes, a
clean run), and they are not where this program lives: with the program
waiting at its prompt the socket shows accesses to bank 04, twice in some
fifty samples, and none above it. Where a program is loaded on this
machine was the thing not known, and two banks do not reach it. Not
sampled while a test was running.

## 3b. Expansion memory on the DDR3, at 105 MHz (2026-11-13, not flashed)

The benchmark of section 3a runs from bank 04: sampled at PHI2 pace (every
step on the socket), 70 % of the steps of its sieve, sort, call and integer
tests are in bank 04 and 30 % in bank 00; four of 1,062 samples are in bank
7F. Two banks of block RAM stop one short. This build puts every expansion
bank, 02 to 7F, in the board's DDR3 - S7d as the scoping doc has it.

**What is in the build.** The full build's DDR3: its PLL block
(`board_plls`, the clock chain calibration was proven with), its reset
sequencer and calibration watchdog, `DDR3_Memory_Interface_Top`,
`ddr3_ports` and `ddr3_port_cdc`, with the accelerator as the only client
(port 1 is tied off). In the accelerator's clock: `gs_accel_exp`, one queue
of writes and reads in program order, and in the top a byte-to-word
adapter (the arbiter's words are 32 bits; a read's byte lane is kept until
its word comes back). `gs_accel` is built with `EXP_DDR = 1`,
`EXP_BANKS = 126`, `NEAR_KW = 9`.

**The near memory tags every bank.** Its entry is the byte, the tag as it
was (two bits that say ROM and "A12 moved", and A14–A17), and A18–A22. The
first fourteen bits are read with the core's next address, in the same
fourteen blocks as every build before this one, and they are all the
first-clk decision needs. RAM above bank 03 is marked in the two bits that
were {ROM, A12 moved}: both set, a pair nothing else uses (ROM is {1, 0},
and nothing moves A12 above bank 03). A step of the cheap view is never in
those banks, so its entry matches exactly when the old fourteen bits match.
The five high address bits are in five blocks of their own, read a clk
later at the step's address - a register - and written a clk after the
rest of the entry; only the registered full compare uses them, and it has
the time. A first version spent a fifteenth bit ("an address bit above A17
is set") in the first-clk compare; this one costs that compare nothing.

**Waiting for the memory.** A near miss in an expansion bank queues a read
and waits for it: a fast step in place (the broker's count stands while
`lm_rwait_i`), about 25 clks in the bench's model. A PHI2-paced step cannot
stand still, so its socket cycle is not taken as complete until the byte is
there; the cycle - a read of RAM - is issued again meanwhile. It may not
take the socket's byte instead: after fast mode the machine's copy is
stale (a first version did, and a toggling run stopped at once). Writes go
into the same queue; when it is within six entries of full every fast step
that could write there waits at its strobe.

**Granted only when it is safe.** Card memory needs the DDR3 calibrated and
a queue that has never overflowed, as well as a ROM image. If the DDR3
does not come up, the card is S6 on the new core and stays so. Telemetry
word 12 is `{EXP_DDR, queue overflowed, memory ready, EXP_BANKS}`: `057E`
on a good start. The DDR3's sequencer state and retry count are in the
firmware's debug registers, as in the full build.

**The card's copy is what the core wrote since the socket was armed**, as
for banks 00/01. The DDR3 does not start at zero. In PHI2-paced card-memory
mode every byte the near memory gives is compared with the socket's, and
so is every byte fetched from the DDR3 (the verify count).

**A defect found on the way, never built into a bitstream that ran.** When
the queue was nearly full the broker held a fast step at its strobe. A
step whose socket request had been raised ahead (the early request of
section 3) was held too, its socket cycle completed with the step still
undecided, and the cycle would have been issued twice. The bench did not
fill the queue often enough to show it. It does now: `+wbforce` forces
"nearly full" in long bursts, and a check stops the run if a step's socket
cycle completes before the step is decided. Six of six such runs failed
before the fix and pass after it: a step whose request is already at the
socket is not held by the queue.

**Verification (simulation).** The broker suite, 140 of 140 runs;
the decode sweep (981,101,952 vectors), the replica benches and both
socket benches pass on the same source. The bench's
memory answers reads 8 to 39 clks late and is not always ready
(`gs_exp_mem_sim`; `+xlat`, `+xgap` make it slower than the core writes);
both the bench's design and `gs_accel` beside it have one, and the pins
are compared in every clk. New in the test program: banks 04 and 08
against bank 00 at one near-memory index; a 96-byte block move into bank
02; a reset dropped on a step that is waiting for its byte (`+resetx`).
Seven mutations of the new logic: six detected (the marking of high banks
among them); the seventh (a byte that comes back to a step a reset removed
is not dropped) changes nothing at any latency the DDR3 could have - the
byte is back before the reset is over - and stays as a safeguard. The S6
pin comparison is off in PHI2-paced runs of this configuration: a cycle
issued again is not S6. Nine runs are at 105 MHz (`b105_2s`).

**Timing: 110 MHz did not hold, 105 MHz does.** The rule is three
placements of one source with no failing path, against a clock uncertainty
of 0.5 ns (so "+0.03" below is 0.53 ns of real margin, and a small negative
number is a path that works with less than the margin asked for). Seven
rounds of the source:

| round | what changed | failing paths (worst slack, ns) in each placement |
|---|---|---|
| 1 | first build | 560 (−2.529) |
| 2 | the queue's "nearly full" and "waiting" as registers | 0 (+0.019), 97 (−0.281), 20 (−0.092) |
| 3 | the queue registered at both ends; high tag bits written a clk late | 0 (+0.018), 0 (+0.028), 88 (−0.986) |
| 4 | the {1, 1} marking in place of a fifteenth tag bit | 43 (−0.391), 26 (−0.152), 98 (−0.753) |
| 5 | the PHY's enable as a register; the queue in one block RAM | 11 (−0.031); the others not built |
| 6 | one write-enable register for the far memories; dead register copies removed | 80 (−0.513), 8 (−0.131), 0 (+0.038) |
| 7, 110 MHz | the defect's fix; cycle completion from registers a clk ahead | 140 (−1.788), 138 (−1.497), 1 (−0.075) |
| **7, 105 MHz** | **the same source, `ACC_CLK_105`** | **0 (+0.029), 0 (+0.037), 0 (+0.028)** |

At 110 MHz the same source lands anywhere from one path 0.075 ns short of
the margin to 140 paths 1.8 ns short, by placement. The DDR3's controller
sits on the left edge of the device and the socket on the bottom and lower
right; the accelerator is pulled between them, and its paths are mostly
wire (5 to 7 ns of 8.5). The failing families differ from placement to
placement (the core's two-clk loop through the near memory, the far
memories' write side, the PHY's enable to the broker), which is the sign
of a design at the edge and not of one bad path. So the build as committed
runs the accelerator at **105 MHz: 52.5 MHz steps**, from a second PLL
recipe (`gowin_acc_pll`, 50 MHz × 21 / 10), selected by `ACC_CLK_105` in
`accel_only_defines.v`; `gen_sdc.py` reads the same line for the period.
Comment the line out and regenerate the constraints for 110 MHz. The
block-RAM build of section 3a (on the card today) closed at 110 MHz and
is unchanged by this.

Changes made for timing that are in every build from now on, each exact
and checked in simulation where it is a register standing for a function:
the PHY's `enabled` is a register (asserted equal to the old function in
every clk); the ROM copy's two terminal comparisons are registered flags;
the broker's cycle-completion conditions are registered a clk ahead of the
PHI2 fall event (asserted equal at every fall event); the far memories'
write enables come from one register; the queue is one block RAM (this
device has no distributed RAM, so a small memory is otherwise built from
registers).

Size: 11,131 logic cells, 11,416 FF, 192 of 340 block RAMs (the two banks
of section 3a are gone; the near memory is 14 + 5 blocks; the queue is
one). Build k0: stamp `20261113103322`, bitstream sha256
`4aad21337ff394c4…b620fb41072f`.

**Not known, not done.** Whether the DDR3 calibrates in this build on the
card: nothing but the full build has run it. The socket PHY has run on
hardware only at 110 MHz; at 105 MHz its points are the same counts of a
clk 4.8 % longer (in simulation at 100, 105, 108 and 110 MHz). The round trip's real length.
What a program's working set does to a 16K-entry cache of single bytes when
a miss costs 25 clks and brings one byte (the arbiter returns a 32-bit
word, of which three bytes are dropped). Not run on hardware.

## 4. What is verified, and what is not

Verified in simulation (the broker suite, `hdl/twgs/sim/broker`):

- `gs_accel` runs beside the bench's hand-wired design on the same socket
  inputs, and **every output pin is compared in every clk** (`ACCEL_SHADOW`),
  in native, paced, fast and toggling modes, with interrupts, RDY stalls, a
  BE pause, warm resets, at 100, 105, 108 and 110 MHz. ROM 01 boot at 110 MHz:
  50,850,536 clks, no difference; over the suite's 79 runs with the module
  beside the design (2026-11-13), 814,174,211 clks.
- The ROM copy (`+mode=copy`): the image starts empty, the design runs
  native from the socket, copies 131,072 bytes through the socket, empties
  the near memory and goes on in fast mode. The image is compared with the
  machine's ROM byte for byte; the test program gives its results; the ROM
  01 boot reaches the same step hash (`6012b76169ecc820`) and the identical
  128,393-write stream as every other mode.
- Fault injection on the new logic (the hold, the copy, the flush, the
  module's memories and grants): 12 of 16 detected. The four that are not:
  the write enable's timing and which copy of the address a near-memory
  block reads (nothing a zero-delay simulation can see), the bank test on
  RAM writes (no expansion memory here), and the tag the flush writes when
  the held step's address is in ROM (it is then the same tag; the bench
  checks it directly when it is not). Four of the twelve needed two things
  the bench gained for them: a second copy made from fast mode, mid-cycle,
  and checks that a copy ends with the near memory empty and the held step
  not trusting its byte. That run also showed the flush is needed: 207
  entries read from the empty image were in the near memory at the first
  copy.
- The suite is 88 runs, all passing; the CPU lockstep bench is unchanged by
  this build.
- The early socket request (scoping doc §10.5): a test of code and 16-bit
  data in a Mega II bank, also called from the interrupt-enabled loop; a
  bench property that no idle cycle is issued in front of a socket-only
  step; two runs with a RDY stall every second and every fifth PHI2 cycle.

Timing (138B, 0.5 ns setup uncertainty; constraints generated by
`hdl/accel_probe_138b/gen_sdc.py`, floorplan and pins by `gen_floorplan.py
accel`):

| build | failing | worst slack | `clk_gs` (110 MHz) reaches | `clk_logic` (56.25 MHz) reaches |
|---|---|---|---|---|
| ao3 | 0 | +0.012 | 110.07 MHz | 71.8 MHz |
| aop1 (a telemetry constant changed) | 0 | +0.016 | 110.19 MHz | 73.9 MHz |
| aop2 (changed again) | 0 | +0.030 | 110.18 MHz | 79.1 MHz |
| **aoz, the source of 857d136c (on the card)** | **0** | **+0.002** | **110.02 MHz** | 72.8 MHz |

With the early socket request (§10.5 of the scoping doc); fx2 is on the card:

| build | failing | worst slack |
|---|---|---|
| fx1 (the request with two RDY terms it did not need) | 6 | −0.062 |
| **fx2, the committed source** | **0** | **+0.008** |
| fxp1 (a telemetry constant changed) | 0 | +0.047 |
| fxp2 (changed again) | 0 | +0.006 |

fx1's six failures were spread over paths that were already at the edge
(none in the new logic); taking the two terms out, which simulation showed
change nothing, took their load off the sequencer's registers.

No setup or hold violation in any of the four, and they are four
placements: every build of this project carries its own build stamp, so
no two netlists are the same. Step paths of aoz: core → core +0.22, core →
near address +0.04, near memory → core +0.07, clock enable into the core
+0.39. As in the probe, the slacks are small because the tool stops when
the constraint is met; the probe's 116 MHz build (114.3 MHz reached) is the
measure of margin, and it has not been repeated on this build. A first
build without the near memory's floorplan failed by 0.8 ns: the floorplan
is part of the design.

Size: 6,591 logic cells (5,737 LUT, 854 ALU), 3,177 FF, 179 of 340 block
RAMs (fx2: 6,571 logic cells, 3,178 FF, 179 block RAMs). At synthesis the accelerator is about 4,100 of the LUTs and the
connector about 1,500.

Not verified, not done:

- **The top level is not simulated.** `accel_only_top.sv` is wiring: PLLs,
  the connector with its tie-offs, two-flop crossings, the key compare,
  the slot pins. The slot side's passivity is by inspection of that file.
- The firmware (Sep 13 2026) arms and controls it, alone and beside an
  a2p25 (section 3); nothing else of the firmware has been looked at
  against this build (its DDR3-ready input is tied high; volumes, video, USB and DP
  status read as nothing).
- The build with the early socket request has run on hardware for one
  boot and one benchmark (section 3); nothing longer.
- No speed control or Zip / TransWarp registers (S7e), no ROM 3.
- The reset rule's gateware sequencer (`gs_socket_arm_seq`) is not in this
  build; arming is timed by the firmware, as in S6.
- The timing probes were not rebuilt after the broker gained the hold
  (they tie it off); their recorded results are those of commit `caa48d98`.
- Open from before: the write of a step completing in the clk /RES is
  seen is not exercised by the bench.

## 5. Building

    GPRJ=a2mega_accel_138B.gprj RESOURCE_BASELINE=none tools/build.sh a2mega all

The a2mega directory holds many projects: always name the project, and
check the build stamp (`CORE:` line) before trusting a hardware test.
Regenerate the constraints with `python3 hdl/accel_probe_138b/gen_sdc.py`
and `python3 hdl/accel_probe_138b/gen_floorplan.py accel`.

Provenance of k0 (the DDR3 build at 105 MHz, section 3b): sources = the
commit that adds this paragraph; the same tool and device; build stamp
`20261113103322`; bitstream sha256 `4aad21337ff394c4…b620fb41072f`.

Provenance of fx2 (the early socket request, on the card): sources = the
commit that adds this paragraph; the same tool and device; build stamp
`20261112184610`; bitstream sha256 `cc7d3cb5a33f90d8…2476b571f5`.

Provenance of aoz: sources = the commit that adds this page; Gowin
V1.9.12.01, GW5AST-LV138PG484AC1/I0 device version B; build stamp
`20261112104329`; bitstream sha256 `48c06bbc72bca6da…7cb8c04baa`. The
bitstream options are the 138B full build's (`impl/a2mega_138B_process_config.json`
copied, with the probe's place and route options).
