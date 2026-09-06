# jtframe cores on MiSTer — the platform (level 0, board-agnostic) — the guide

The human rendition of `SKILL.md` in this directory: the same rules, the same
IDs, each followed by the INCIDENT that taught it. **GENERATED** by
`tools/gen_skill_guide.py` of the originating project from the documentation
paragraph every rule is anchored to — never hand-edited; regenerate there.
Origin: Project VAMPIRE SAVED — the full-roster Vampire Savior romhack on the real CPS-2 engine (FBNeo and MAME as instruments, a jtframe core on MiSTer). The incidents therefore name that project's game, builds,
gates and session tags (`14z-N`); the RULES do not. The rule is the reminder,
the incident is the fact. IDs are stable and never reused; a gap means the
rule stayed at the origin's board-specific level.

**To use this skill elsewhere:** copy this directory (`SKILL.md` + `GUIDE.md`)
into `~/.claude/skills/mister-jtframe-core/`. Nothing in it depends on the origin tree.

## 0.1 The separate-core mechanism

**[MJC-1]** **An extended core is a SEPARATE core directory**, `cores/<x>`, pulling shared RTL through `cfg/game.yaml`; the reference cores it derives from stay byte-untouched against the upstream tag (`git diff`, gated). A file is copied into the new core's `hdl/` ONLY when it must differ, and **the diff between the two core dirs IS the trust surface** — enumerate it, freeze each override's delta line by line, hold the fork's whole-tree `git diff --name-status` to a declared path list.

> **Incident** (`docs/project/mister_core.md` › *1. What we are building*):
>
> **The separate-core mechanism is jtcores' own, not something we invented.**
> `cores/cps2`'s `cfg/game.yaml` pulls the CPS-1 video/SDRAM/tilemap pipeline
> from `cores/cps1` and the QSound block from `cores/cps15`; `cores/cps15`
> exists the same way. A file is copied into `cores/cps2w/hdl` only when it
> must differ, and **the diff between the two core directories IS the trust
> surface**. As of slice D5 that diff is **fourteen files in `cores/cps2w/hdl`
> — thirteen `.v` (ten overrides of shared modules plus three new ones) and
> `pal_lut.hex`** — and one addition to jtframe, all enumerated and frozen
> line by line (§9; the whole-tree delta is 25 declared paths). (Was
> "twelve files as of D4" until 14z-113; D5 added the `jtcps2_decrypt.v`
> override.)

**[MJC-2]** **`jtframe files` deduplicates by FULL PATH.** Overriding a shared file means REMOVING it from the list that pulled it, and a file reachable only through a pulled `.yaml` costs INLINING that whole yaml minus the override — re-paid by hand at every uprev, and it compounds (one file at the first slice, twenty transcribed at the second). Afterwards `jtframe files sim <core>` must differ from the reference core's list by exactly (files out) + (files in).

> **Incident** (`docs/platform/gotchas.md` › *jtframe's RTL plumbing (added 14z-107 (6), slice D1)*):
>
> - **OVERRIDING ONE SHARED FILE COSTS YOU THE WHOLE `.yaml` THAT PULLED IT,
>   AND IT COMPOUNDS (14z-107 (6) and (9)).** `jtframe files` deduplicates by
>   FULL PATH, so a core cannot both `get:` a yaml and override a file that
>   yaml pulls: the two copies of the module would both compile and the
>   override would not override. The only way out is to INLINE the pulled yaml
>   into the core's own `game.yaml` minus the overridden file. Slice D1 paid it
>   for `cores/cps15/cfg/qsound.yaml` (one file). Slice D2 paid it again for
>   `cores/cps1/cfg/common.yaml`, which pulls twenty files, so overriding TWO
>   of them (`jtcps1_sdram.v`, `jtcps1_prom_we.v`) meant transcribing the other
>   eighteen plus that yaml's `jtframe:` and `modules:` sections. **The bill
>   is not the override, it is the transcription — and it has to be re-paid by
>   hand at every uprev.** Budget it before deciding a file "must differ", and
>   check `jtframe files sim <core>` against the reference core's list
>   afterwards: the diff should be exactly (files out) + (files in) and nothing
>   else. It is also why a same-name override is worth its cost only when the
>   frozen line-by-line delta against the original is the thing you want to
>   review; a renamed module would avoid the yaml surgery entirely and lose
>   that.

**[MJC-3]** **A new jtframe module is pulled from the CORE's `game.yaml`** (`- from: sdram / get: - <file>.v`), never added to jtframe's shared family list — that list is included by every core. Put the file with its family so it diffs against its sibling, and assert its ABSENCE from the reference core's file list.

> **Incident** (`docs/platform/gotchas.md` › *jtframe's RTL plumbing (added 14z-107 (6), slice D1)*):
>
> - **ADDING A MODULE TO jtframe: pull it from the CORE, never from jtframe's
>   own shared list (14z-107 (9)).** `modules/jtframe/hdl/sdram/
>   jtframe_sdram64.yaml` enumerates the `ram1_Nslots` / `rom_Nslots` family
>   and is included by every core that uses the 64 MB SDRAM front end. Adding
>   a new family member's filename there is the obvious move and it is wrong:
>   it puts the module on EVERY core's compile list, including the reference
>   core the whole separate-core mechanism exists to keep untouched. Put the
>   file with its family (so it can be diffed against its sibling) and pull it
>   from the core's `game.yaml` with `- from: sdram / get: - <file>.v`, the
>   same way `cores/cps1/cfg/common.yaml` pulls `jtframe_romrq.v`. Assert the
>   absence, not just the presence: `test_mister_wide_gate` 5b greps the
>   REFERENCE core's file list for the new module and fails if it is there.

**[MJC-4]** **The fork's delta is mirrored in-tree as a PATCH SERIES**, one file per fork commit, regenerated by the setup script and byte-compared against `git format-patch` WITHOUT the git signature line (each git writes its own). A pin bump is never pushed ahead of the fork commit it names — a fresh clone's `git submodule update` breaks.

> **Incident** (`docs/platform/mister.md` › *Where things are*):
>
> | pinned here | submodule `emu/jtcores` (branch `vampire-saved`); `tools/setup_jtcores.sh` checks the pin, inits the five modules the cps2 yaml chain pulls, and regenerates `emu/jtcores-patches/` as a PATCH SERIES, one file per fork commit (`modules/jtframe/target/pocket` is a PRIVATE ssh submodule — never init it) |

**[MJC-5]** **An extended profile is NOT a macro.** The new core's `macros.def` differs from the reference core's by `CORENAME` only — the profile is the runtime bit of §0.2, so one bitstream runs both machines.

> **Incident** (`docs/platform/mister.md` › *How the CPS-2 core is put together (read 2026-08-22)*):
>
> `cfg/macros.def` (cps2): `include ../../cps1/cfg/common.def`, `CPS2`,
> `GAMETOP=jtcps2_game`, `CORENAME=JTCPS2`, `JTFRAME_SDRAM_LARGE`,
> `JTFRAME_HEADER=44`, `JTFRAME_IOCTL_RD=128`, `JTFRAME_DIPBASE=16`,
> `JTFRAME_DIAL`, `CPS1_NOOBJ`, `JTFRAME_OSD_TEST`, MiSTer: `JTFRAME_MR_DDRLOAD`.
> cps2w's `macros.def` differs by `CORENAME=JTCPS2W` only — and it stays that
> way ON PURPOSE: **the WIDE profile is NOT a macro.** See "The runtime profile
> gate" below.

**[MJC-6]** **A new core missing a `$readmemh` file the reference core carries (a palette LUT, a PROM image) renders BLACK and nothing warns** (`%Warning` in a wall of warnings). Every `*.hex` the reference core carries must exist byte-identical in the new core's `hdl/`, and `*.hex` is in jtcores' `.gitignore` — force-add it.

> **Incident** (`docs/platform/gotchas.md` › *jtframe's RTL plumbing (added 14z-107 (6), slice D1)*):
>
> - **A NEW CORE WITHOUT `hdl/pal_lut.hex` RENDERS A BLACK SCREEN, AND
>   NOTHING WARNS.** `cores/cps2w` shipped without it and cost four
>   50-minute simulation runs to find. The chain: `jtcps1_pal.v:62`
>   instantiates `jtframe_ram #(.SYNFILE("pal_lut.hex"))`; `jtframe_ram`
>   resolves that by BARE NAME, and `jtsim` supplies it by symlinking
>   `$CORES/<core>/hdl/*.hex` into the sim directory — so every core that
>   instantiates `jtcps1_pal` carries its own copy (cps1, cps15 and cps2 all
>   do). Missing, `$readmemh` fails with a `%Warning` in a wall of warnings,
>   the LUT reads back zero and `red/green/blue` are pinned to 0. Measured:
>   the reference core rendered 12 changed frames in 640 (frame 465 mean
>   brightness 146); the new core rendered exactly one, mean 0.
>   **And `*.hex` is in jtcores' own `.gitignore`**, so `git add` refuses it
>   silently — the file must be force-added. Gate:
>   `tests/test_mister_wide_gate.sh` 3g requires every `hdl/*.hex` the
>   reference cores carry to exist in the new core's `hdl/`, byte-identical.

**[MJC-7]** **A pin is a tree; a grep proves a fact about the tree you grepped.** "Feature X does not exist" from a grep over the pinned checkout is a claim about the pin, not about the framework (the 128 MB tier exists upstream, not at the pin). Budget an uprev honestly: paths move, `game.yaml` → `files.yaml`, `-inputs` takes a `.cab` script that orphans `sim_inputs.hex`, the translator and both sim gates.

> **Incident** (`docs/project/mister_core.md` › *4. The one escape, and why it is the fallback*):
>
> > **A retraction worth carrying, because it is the ordinary lesson in a new
> > place.** 14z-106 recorded "NO XL SDRAM tier exists" from a grep over
> > `modules/jtframe` that returned zero hits. That was **true at our pin and
> > false as a claim about jtframe**. A grep proves a fact about the tree you
> > grepped, and a pin is a tree.

## 0.2 The runtime profile bit

**[MJC-8]** **Profile selection is a RUNTIME bit in the MRA header**, decoded by one profile module into one wire that every gated site takes — not an `ifdef`. A stock MRA on the extended `.rbf` runs a stock machine BY CONSTRUCTION, which is what turns "untouched by construction" from an inertness argument into a property of the circuit.

> **Incident** (`docs/platform/mister.md` › *The runtime profile gate: MRA header byte 41 (slice D1, measured 14z-107)*):
>
> Maintainer ruling, 2026-08-23: the profile is selected at RUNTIME from a
> spare MRA header bit, not by an `ifdef`. The consequence is the point —
> **stock `vsavj` on `jtcps2w.rbf` runs with the widened behaviour CLEAR**, so
> CLAUDE.md rule 1 v2's "profile-gated so stock `vsavj` is untouched BY
> CONSTRUCTION" is a fact on FPGA rather than an inertness argument.

**[MJC-9]** **Find the free header byte by reading the CONSUMER's decoder** — the bytes that fall through every branch of the core's header-write module — not the comment that says which are reserved.

> **Incident** (`docs/platform/mister.md` › *The runtime profile gate: MRA header byte 41 (slice D1, measured 14z-107)*):
>
> - **Which byte, and why it is free.** `jtcps1_prom_we.v` consumes header
>   bytes 0-7 (the four region start words), 8-39 (`is_cps`, the CPS config
>   registers, `REGSIZE=24` + `START_HEADER=16`) and 40 (`JOY_BYTE = 6'h28`);
>   44-63 are the CPS-2 key (`CPS2_KEYS = 26'd44`). Bytes **41-43 fall through
>   every branch of its decoder and are ignored**, which is what the file's own
>   comment at `:52-54` ("6 are actually used and 10 are reserved") is
>   describing. `JTFRAME_HEADER=44`, so byte 41 exists in every CPS-2 `.rom`.

**[MJC-10]** **`[header] fill=0xff` FORCES active-low polarity.** The fill must mean "profile off", or every stock MRA the core emits changes and the twin breaks. (jtframe's own `JOY_BYTE` has exactly this shape.)

> **Incident** (`docs/platform/mister.md` › *The runtime profile gate: MRA header byte 41 (slice D1, measured 14z-107)*):
>
> - **ACTIVE LOW, and that is forced rather than chosen.**
>   `cores/cps2/cfg/mame2mra.toml` declares `[header] fill=0xff`, so an
>   unwritten header byte is `0xFF`; the stock `vsavj` MRA emitted by cps2w has
>   to stay byte-identical to cps2's. Only a polarity in which the FILL means
>   "profile off" can do that. jtframe's own `JOY_BYTE` has exactly this shape
>   (0xFF = joystick mode 3; the games that want mode 0 write `fc`).
>   So: **byte 41 bit 0 CLEAR = CPS-2 WIDE**, and the WIDE MRA writes `fe`.

**[MJC-11]** **Scope the header row with `setname=`** (`RawData` embeds `Selectable`) so no other MRA gains a byte, and MEASURE the byte end to end in both `.rom` files — the fill value in the stock image, the written value in the extended one.

> **Incident** (`docs/platform/mister.md` › *The runtime profile gate: MRA header byte 41 (slice D1, measured 14z-107)*):
>
> - **How the row is scoped.** `RawData` embeds `Selectable`
>   (`src/jtframe/mra/types.go`), so `{ setname="vsavjw", offset=41, data="fe" }`
>   scores 3 for that set and 0 for everything else — no other MRA gains a byte.
>   Measured end to end: the stock `.rom` byte 41 is `0xFF` and the WIDE
>   `.rom`'s is `0xFE` (`tests/test_mister_mra_map.sh`).

**[MJC-12]** **It is a STATIC configuration bit**: written only while the ROM streams with the core in reset, constant for the whole of play, on the SDRAM clock net — nothing to synchronise. The decoder re-defaults at the first byte of every download, ignores `ioctl_ram`, and is inert for every other address.

> **Incident** (`docs/platform/mister.md` › *The runtime profile gate: MRA header byte 41 (slice D1, measured 14z-107)*):
>
> - **Clock domains, so it is not asked later.** The decoder runs on the game
>   port's `clk`, which jtframe documents as "always matched to the SDRAM
>   clock" (`jtframe_common_ports.inc:5`) and which on a `JTFRAME_CLK96` core
>   like CPS-2 is the same 96 MHz net the QSound block's `clk96` is. Even if it
>   were not, `wide_en` is a STATIC configuration bit: it is written only while
>   the ROM streams, with the core (and the QSound DSP, `qsnd_rst`) held in
>   reset, and is constant for the whole of play. There is nothing to
>   synchronise.

**[MJC-13]** **`[parse] sourcefile` is a SECOND profile gate, in the mapping tool.** A machine entry tagged with a sourcefile the reference core's regex list does not match is INVISIBLE to it — the reference core cannot even BUILD the extended download image, so a census leg written on it fails on purpose.

> **Incident** (`docs/project/mister_core.md` › *8. How the profile is switched on, and why it is a runtime bit*):
>
> **A second profile gate operates one layer up, in the mapping tool.**
> `[parse] sourcefile` is a regex list matched against the machine's source
> file, so the WIDE machine entry tagged `sourcefile="capcom/cps2w.cpp"` is
> **invisible** to a core declaring `sourcefile=["cps2.cpp"]`. Measured:
> `jtframe mra cps2` emits 316 MRAs and none of them is the WIDE set;
> `jtframe mra cps2w` emits 8. The reference core cannot even *build* the WIDE
> download image — which is how the census gate's leg B was written wrong and
> caught on its first run.

**[MJC-14]** **Gate at BOTH ends — source and destination.** When the destination select already ANDs the profile wire, an ungated source would be inert anyway; gating the source too makes the extra bit PROVABLY zero rather than harmlessly ignored, and makes the expression exhaustively testable on its own.

> **Incident** (`docs/project/mister_core.md` › *8. How the profile is switched on, and why it is a runtime bit*):
>
> **The obj promote is gated at BOTH ends and that is deliberate.** `gfxc_sel`
> already ANDs `wide_en`, so an ungated promote would still have been inert —
> bank 4 would select the same slot as bank 0. Gating it at the source as well
> makes the third bank bit *provably zero* with the profile clear rather than
> *harmlessly ignored*, which is the difference between rule 1 v2's "untouched
> by construction" and an inertness argument. It also makes the promote
> exhaustively testable on its own (§9).

**[MJC-15]** **An elaboration-time parameter cannot be gated** (`SLOTn_OFFSET`, port widths). Each ungated relocation or widening is DECLARED, argued to have no behavioural surface (identical data at identical CPU addresses; the extra bit driven to 0 by a gated expression), and MEASURED inert core-vs-core on stock content — never hidden.

> **Incident** (`docs/project/mister_core.md` › *8. How the profile is switched on, and why it is a runtime bit*):
>
> **The one ungated change is declared rather than hidden: the bank-0
> re-pack.** `SLOTn_OFFSET` are elaboration-time parameters and cannot switch
> at run time, so VRAM/ORAM/WRAM/Z80 move unconditionally on CPS-2. That is a
> RELOCATION with no behavioural surface — the 68k sees identical data at
> identical 68k addresses, VRAM/ORAM/WRAM are never downloaded at all, the Z80
> region's download and read take the same constant, and bank 0 is the one bank
> carrying `JTFRAME_BA0_AUTOPRECH=1`, so its per-access latency is
> address-independent and no row-locality pattern can shift. It is also the one
> D2 claim that is **measured** rather than constructed, by
> `tests/test_mister_wide_inert.sh`.

## 0.3 SDRAM: tiers, slots and placement laws

**[MJC-16]** **At jtcores v1.7.3, 64 MB is PHYSICAL, not a setting**: the bank-core table stops at `AW 23`; the ROW/COW ternary has no `AW=24` arm, so an `AW=24` build never drives `addr[9]` and every address aliases with `addr ^ 0x200` — quiet per-512-word corruption, not a build error; the MiSTer target assigns 13 A / 2 BA / 1 nCS pins; no single chip is bigger than 64 MB.

> **Incident** (`docs/platform/mister.md` › *The SDRAM ceiling at our pin: 64 MB is PHYSICAL (measured 14z-107)*):
>
> At `v1.7.3` the 64 MB tier is not a default with a wider one behind it — it
> is the largest map the pin can address, and every link in the chain says so.

**[MJC-17]** **`JTFRAME_SDRAM_XL` (128 MB) is upstream-only, two chips on one module selected by nCS POLARITY, and lives ONLY in the `JTFRAME_SDRAM_CACHE` branch.** The macro validator does not require CACHE alongside XL, so setting XL on an explicit-slot core (one with no `cfg/mem.yaml`) compiles, validates and silently produces the aliased map. A tier macro is not a tier — check which controller the macro's logic lives in.

> **Incident** (`docs/platform/gotchas.md` › *`JTFRAME_SDRAM_XL` without `JTFRAME_SDRAM_CACHE` aliases SILENTLY (14z-107)*):
>
> Upstream jtframe's 128 MB tier is real (`SDRAMW=24`,
> `modules/jtframe/target/mister/hdl/jtframe_emu.sv:175-181`), but the
> controller that KNOWS about it exists only on one side of a fork.
> `hdl/jtframe_board_sdram.v:158` branches on `JTFRAME_SDRAM_CACHE`: the
> `ifdef` arm instantiates `jtframe_burst_sdram` (`:164`), which carries the XL
> logic (`localparam XL = AW == 24`, the two-chip select on nCS polarity); the
> `else` arm instantiates `jtframe_sdram64` (`:225`), which was **never taught
> XL** — its `init`/`rfsh` instances leave `.chip()` unconnected
> (`jtframe_sdram64.v:265,279`), and its bank
> module's geometry is `localparam ROW=13, COW = AW==22 ? 9 : 10;` — a two-arm
> ternary with **no arm for AW=24**.

**[MJC-18]** **On a DE10-Nano the dual-SDRAM pin set and the ANALOG I/O board are mutually exclusive** (`sys_analog.tcl` and `sys_dual_sdram.tcl` claim the same pins). Any route needing two physically separate modules gives up a CRT field test.

> **Incident** (`docs/platform/mister.md` › *The SDRAM ceiling at our pin: 64 MB is PHYSICAL (measured 14z-107)*):
>
> **Consequence worth stating plainly: on a DE10-Nano the dual-CHIP SDRAM
>   path and the ANALOG I/O board are mutually exclusive.** That is not
>   academic here — the field test in the ruling at the top of this file is
>   Jammix -> CRT, i.e. analog video. Any 128 MB route that needs two
>   physically separate modules is also a route that gives up the CRT field
>   test. The two-chips-on-ONE-module route below does not have this problem:
>   it uses the single SDRAM socket and the same 13 address pins.

**[MJC-19]** **A jtframe 8-bit SDRAM slot caps at `SDRAMW`, and past it the BUILD FAILS**: `{ {SDRAMW-AW{1'b0}}, … }` is a replication count that goes negative ("Replication value of < 0 … not legal"). A byte-addressed region wider than 8 MB needs ANOTHER SLOT in another bank, never a wider `AW`.

> **Incident** (`docs/platform/gotchas.md` › *jtframe's RTL plumbing (added 14z-107 (6), slice D1)*):
>
> - **An 8-bit SDRAM slot CANNOT be widened past `SDRAMW`, and the failure is
>   a BUILD failure.** `modules/jtframe/hdl/sdram/jtframe_romrq_bcache.v:74` is

**[MJC-20]** **Offsets are ADDs** (`sdram_addr = offset + …`), elaboration-time, word-granular, with no power-of-two alignment requirement — placement is arbitrary at word granularity, and a relocation is un-gateable ([MJC-15]).

> **Incident** (`docs/project/mister_map.md` › *5. THE MAP*):
>
> Offsets in the RTL are 23-bit **word** constants (`jtcps1_sdram.v:158-164`
> for bank 0's family, per-slot `SLOTn_OFFSET` for the read side); the tables
> below give bytes and the word constant. jtframe applies offsets as an ADD,
> not an OR — `jtframe_romrq_bcache.v:74`
> `sdram_addr = offset + { …, addr_req >> (DW==8) }` — so placement is
> arbitrary at word granularity, with no power-of-two alignment requirement.

**[MJC-22]** **THE SAME ART HAS THREE SIZES — live bytes < address footprint < declared region — and only the DECLARED REGION consumes an SDRAM bank**, because the MRA downloads the whole region, art or no art. Ask which of the three a number is before spending it; a wrong figure has been published from each of the first two. Growth INSIDE a region is free; growth OF a region is immediately fatal.

> **Incident** (`docs/platform/gotchas.md` › *A CPS-2 tile code IS its SDRAM address — and the SAME ART HAS THREE SIZES (14z-107, third size added 14z-107 (9))*):
>
> 3. **And the size SDRAM actually SPENDS is a THIRD number: the DECLARED
>    REGION** (added 14z-107 (9), found by the whole-image census). The MRA
>    downloads the whole `[rom]` region the machine entry declares, so each
>    8 MB group-C obj bank reserves its full 8 MB whatever the art does inside
>    it — the footprint does not shrink the reservation. The placement map had
>    sized those two banks by their FOOTPRINT and claimed **0.708 MB** of slack
>    in the 64 MB tier; the census says **0.125 MB, with SDRAM bank 1 EXACTLY
>    FULL**. So one roster's art has three sizes: **live bytes 6.39 MB <
>    address footprint 15.45 MB < declared region 16 MB** — and this project
>    has published a wrong figure derived from each of the first two.
>    **Ask which of the three a number is before you spend it.** The two
>    consequences point opposite ways and both matter: growth INSIDE the
>    declared region is free (a new tile above the current ceiling overflows
>    nothing), and growth OF the region is immediately fatal (a fifth group-C
>    member has nowhere to go — bank 1 has zero free and bank 0 has
>    131,072 B).

**[MJC-23]** **Bank arbitration is strict `ba0 > ba1 > ba2 > ba3`** (`BAPRIO=1`), so moving a stream between banks is a SCHEDULING change as well as a placement. Only bank 0 carries `JTFRAME_BA0_AUTOPRECH`, so on banks 1-3 an ACTIVE means a row MISS while bank 0's is 100% by construction — read "acc" and "row-miss %" as different quantities. A bank's all-miss ceiling is 123,825 transactions/frame (STW 13 clocks at 96 MHz).

> **Incident** (`docs/platform/mister.md` › *The per-bank SDRAM traffic profile (measured 14z-107)*):
>
> **Read "acc" as READ+WRITE commands and the percentage as the ROW MISS
> rate.** They are different quantities because only bank 0 sets
> `JTFRAME_BA0_AUTOPRECH`: on banks 1-3 `jtframe_sdram64_bank.v:170`
> (`row_match = match && actd && !AUTOPRECH[0]`) skips both the PRECHARGE and
> the ACTIVE when a request hits the open row, so an ACTIVE there means a row
> MISS. Bank 0's 100% is by construction, not by thrashing.

**[MJC-24]** **Measure bank headroom BEFORE choosing a placement** — accesses/frame, row-miss rate, data-bus %, `SDRAM reads clashed` — on the reference core with stock content (the bound), then on the new core with the new image (the design). A stream with no row locality (a sample player that round-robins channels, ~98% miss) has nothing for a repack to spoil; tile fetches come in runs and do.

> **Incident** (`docs/project/mister_core.md` › *Why bank 1 can take the load*):
>
> Object graphics and sound samples now share a bank, which sounds like the
> kind of decision that ruins frame timing. **It was measured before it was
> chosen** (`tests/audit_sdram_bank_load.sh`, stock `vsavj`, 2,800 frames;
> figures per video frame, in-match phase, re-derived 14z-107 (7)):

**[MJC-26]** **A download-side `?:` chain has a fall-through arm more regions reach than you think**, with WRAPPED region-relative addresses. Qualify every new condition with its own region's `is_*`; a signal correct only because its write-enable happens to be low is a defect waiting for a refactor, and the census cannot see it.

> **Incident** (`docs/platform/gotchas.md` › *jtframe's RTL plumbing (added 14z-107 (6), slice D1)*):
>
> - **A DOWNLOAD-SIDE `?:` CHAIN HAS A FALL-THROUGH ARM THAT MORE REGIONS
>   REACH THAN YOU THINK (14z-107 (9)).** `jtcps1_prom_we.v`'s `prog_ba` ends
>   in a bare `2'd1`, which is reached by the QSound region AND by the CPS-2
>   firmware region (`is_qsnd`). The region-relative addresses it computes are
>   WRAPPED SUBTRACTIONS outside their own region — for the firmware region
>   `pcm_addr` happens to have bit 23 SET — so a new condition written as
>   `pcm_addr[23] ? ba0 : ba1` silently re-banks the firmware too. It writes
>   nothing there (`prog_we` is 0 for `is_qsnd`), so it would never have been
>   observable. Qualify the condition with its own region's `is_*` anyway:
>   **a signal that is correct only because its write-enable happens to be low
>   is a defect waiting for a refactor**, and the census cannot see it.

## 0.4 Gated RTL: widths, decodes and the ledger

**[MJC-29]** **A widened bus is only as wide as its NARROWEST port, and Verilog says a width warning at most.** A widened bank field crossing several module boundaries truncates silently anywhere left at its old width, and the failure is a PICTURE (stock art for every promoted sprite), which looks like a content bug. Assert every declaration on the path by name; budget the override files a width costs.

> **Incident** (`docs/platform/gotchas.md` › *jtframe's RTL plumbing (added 14z-107 (6), slice D1)*):
>
> - **A WIDENED BUS IS ONLY AS WIDE AS ITS NARROWEST PORT, AND VERILOG SAYS
>   NOTHING (14z-107 (10), MiSTer slice D3).** The CPS-2 object bank goes from
>   2 bits to 3 in `jtcps2_obj_scan`, but the value crosses FOUR module
>   boundaries on its way to SDRAM — `jtcps2_obj_scan` -> `jtcps2_obj` ->
>   `jtcps1_obj_draw` -> `jtcps1_video` -> `jtcps1_sdram`. A port left at
>   `[1:0]` anywhere in that chain TRUNCATES the top bit, and Verilog's answer
>   to a 3-bit signal driving a 2-bit port is a width WARNING at worst. The
>   failure that produces is not a build error, it is a PICTURE: every tenant
>   sprite silently fetches vanilla art from bank 0 or 1, which looks like a
>   content bug and sends you to the romset. Three of slice D3's four override
>   files exist for nothing but this, and
>   `tests/test_mister_wide_gate.sh` 8c asserts all six declarations by name.

**[MJC-30]** **Validate a bit's MEANING against a second implementation, never against a commented-out guess in the reference RTL** — read the emulator's device model for what a latch or bank register actually loads, and make the gate re-read those lines every run so the evidence cannot rot. Record what you deliberately do NOT fix (a latency the reference core lacks) as a reference-core difference for the comparison that would see it.

> **Incident** (`docs/platform/mister.md` › *The QSound bank bit IS `dsp_ab[7]` (validated against MAME's LLE device, 14z-107)*):
>
> The width fix rests on this and `jtcps15_sound.v:416-417` shows the original
> author was unsure: it carries a commented-out alternative
> `{ dsp_ab[2:0], dsp_ab[4], dsp_ab[5], dsp_ab[6], dsp_ab[7] }`, a 7-bit
> permutation that drops `ab[3]` entirely. MAME's low-level QSound device
> settles it (`emu/mame/src/devices/sound/qsound.cpp`, the `QSOUND_LLE` build
> this project's oracle uses):

**[MJC-31]** **A read-only decode extension must be checked against EVERY other decode in its window** (a write-only port qualified `!RnW` collides with nothing); the wait-state boundary ships in the SAME slice as the decode or the extension runs at a different bus timing; and every slot `AW` moves with the address width or the top bit is dropped silently by a narrower port.

> **Incident** (`docs/project/mister_map.md` › *Everything else `jtcps2_main.v` decodes, and whether it collides*):
>
> **The objcfg port decodes a whole megabyte, not sixteen bytes** — the RTL is
> looser than the hardware here — but because it is qualified with `!RnW`, a
> *read* anywhere in `$400000-$4FFFFF` asserts nothing today and would assert
> only `rom_cs` after the change. So there is no read collision at all, and a
> write still reaches only `objcfg_cs`.

**[MJC-33]** **Keep a LEDGER of every gated site** (expression, file, slice) and a gate that re-reads each one VERBATIM, with exhaustive benches over the whole input space in both profile states wherever a site is a pure function (65,536 vectors for a 16-bit one), and a must-fire for each: gate bypassed, byte moved, polarity flipped, a one-width perturbation.

> **Incident** (`docs/project/mister_core.md` › *8. How the profile is switched on, and why it is a runtime bit*):
>
> **The consequence is the point.** Stock `vsavj` on **our** RBF runs with the
> bit clear, so every gated expression collapses to the reference core's,
> character for character. CLAUDE.md rule 1 v2's *"profile-gated so stock
> `vsavj` is untouched BY CONSTRUCTION"* is a fact about the circuit on FPGA,
> not an inertness argument — exactly as the driver flag makes it one on FBNeo.
> **Nine sites are gated as of slice D5**, and `tests/test_mister_wide_gate.sh`
> re-reads every one of them verbatim:

**[MJC-36]** **What breaks a finished core, in order of likelihood**: growth of a declared region (nowhere to go); a re-freeze of the romset (CRC-only lookup, [MJC-64]); regeneration of the machine catalogue dropping the added entry ([MJC-63]); an upstream uprev ([MJC-7]); `JTFRAME_SDRAM_XL` without the cache lanes ([MJC-17]).

> **Incident** (`docs/project/mister_core.md` › *11. What would break it*):
>
> * **A fourth graphics group, or any growth of the declared group-C region.**
>   Bank 1 has **zero** free and bank 0 has **131,072 B**. A fifth group-C
>   member, or widening the region past 16 MB, overflows immediately and there
>   is nowhere for the excess to go. Note the asymmetry §5 sets up: art may
>   grow freely *inside* the existing 16 MB — a code above `0xEE73` or `0xFFDB`
>   costs nothing — but `audit_mister_map_fit` will still go RED, because those
>   extents are FROZEN and a moved extent has to be re-derived and re-frozen
>   deliberately rather than absorbed.

## 0.5 The simulation lane and its instruments

**[MJC-37]** **Simulate in a SCRATCH CLONE outside the repo, never inside the pinned submodule** — jtsim writes `obj_dir/`, bank dumps, frames and `rom.bin` into the core dir. Nothing ROM-derived lands in the tree (`.rom`, bank images: refuse an out-dir inside it). A tmp reaper can hollow a clone with `.git` intact and random files missing: heal from the clone's own store (`git ls-files --deleted`, `git checkout -- .`) and re-clone at the pin only when the store is hollow too. **One clone is ONE simulation at a time** (it holds the run's inputs, dumps, probes and compiled model): a parallel lane is one clone per job slot, and a clone provisioned from nothing must be PROVEN able to simulate — a heal test on a hollowed clone, whose modules survive, is not that proof.

> **Incident** (`docs/platform/mister.md` › *Recipe: the simulation lane on macOS (measured 14z-106, works)*):
>
> 1. `brew install go coreutils gnu-sed xmlstarlet verilator imagemagick`
>    (jtframe's bash tooling needs GNU `realpath --relative-to`, `sed -i`,
>    `stat -c`, `date -d`; `getset.sh` needs xmlstarlet; frame output needs
>    ImageMagick `convert`).
> 2. `tools/setup_jtcores.sh` — pins `emu/jtcores`, inits the modules the
>    cps2 yaml chain pulls (`fx68k jt12 jt51 jteeprom jtdsp16`; never the
>    private `pocket` target), builds the Go tool. **Simulate in a SCRATCH
>    CLONE of the fork, never inside `emu/jtcores`** — jtsim writes
>    `obj_dir/`, `sdram_bank?.bin`, `frames/`, `rom.bin` into
>    `cores/<core>/ver/game/`, which would dirty the pinned submodule.
> 3. ROM access for the MRA tool: `mkdir -p ~/.mame/roms` and SYMLINK
>    `vsav.zip`, `vsavj.zip` and `qsound.zip -> qsound_hle.zip` (it holds
>    `dl-1425.bin`) from `$ROMDIR`. Outside the tree; nothing copied.
> 4. Environment (what `setprj.sh` exports; it needs `python`, so export by
>    hand): `JTROOT=<clone> JTFRAME=$JTROOT/modules/jtframe CORES=$JTROOT/cores
>    ROM=$JTROOT/rom RLS=$JTROOT/release JTBIN=$RLS MRA=$RLS/mra
>    POCKET=$JTFRAME/target/pocket MODULES=$JTROOT/modules MAME=$JTROOT/doc/mame`
>    and `PATH=<gnubin dirs>:$PATH:.:$JTFRAME/bin`.
> 5. `jtframe mra cps2w` (binary at `$JTFRAME/src/jtframe/jtframe`) → the
>    MRAs in `release/mra/` AND `rom/vsavj.rom` (46,407,744 bytes, sha1
>    `f9dc2987…`) — the `.rom` is ROM content: scratch only. **Since
>    14z-107 (5) do not do this by hand either:** `ROMDIR=...
>    tools/mister_mra.sh --core cps2w [--wide build/m3b_merged16] --out <dir
>    outside the repo>` (the current freeze's build — `m3b_m … *(the paragraph continues in the origin doc)*

**[MJC-39]** **The download CONSUMES input lines** (`sim_inputs.next()` fires from t=0 with the core in reset): shift the script by the transfer length, keep every frame number ABSOLUTE, and a bigger image has a LONGER transfer so every absolute frame moves. Assert the transfer length from the run's own `ROM file transfered (frame N)` line, never from a constant.

> **Incident** (`docs/platform/gotchas.md` › *jtframe's RTL plumbing (added 14z-107 (6), slice D1)*):
>
> - **THE WIDE DOWNLOAD IS 197 FRAMES LONGER THAN THE STOCK ONE, AND EVERY
>   ABSOLUTE FRAME NUMBER IN THE LANE MOVES WITH IT (14z-107 (10)).**
>   `sim_inputs.hex` advances on every LVBL fall, download frames INCLUDED,
>   so a replay is shifted by the transfer length: 462 frames for `vsavj.rom`
>   (46,407,744 B) and **659** for `vsavjw.rom` (66,265,152 B). A `--frames` or
>   `--offset` computed for the stock image starts the WIDE replay ~200 frames
>   early and every anchor derived from it is wrong — quietly, because the game
>   still boots and still reaches a select screen. `tools/run_sim_jtcps2.sh`
>   picks the right constant from `--wide` and prints it;
>   `tests/audit_sdram_bank_load.sh` shifts its four phase boundaries and then
>   ASSERTS the transfer length from the run's own "ROM file transfered (frame
>   N)" line rather than trusting the constant.

**[MJC-40]** **A macro named for what you want is not evidence that it does it — read the module that consumes it.** `JTFRAME_SIM_IODUMP` dumps the EEPROM on some cores; `JTFRAME_SAVESDRAM` exists only in the Verilog model the Verilator lane never instantiates; `-stats` is dead for three stacked reasons and its reporter prints rounded rates and running averages that cannot be differenced.

> **Incident** (`docs/platform/gotchas.md` › *`JTFRAME_SIM_IODUMP` on CPS-2 dumps the EEPROM, not RAM (14z-107)*):
>
> Reading emulated work RAM out of a Verilator run therefore needs a harness
> hook, not a macro that already exists (ours: `JTFRAME_SIM_WRAMDUMP`, fork
> commit `553dd56`, `docs/platform/mister.md`). The general lesson is the
> 14z-71 one in a new place: **a macro named for what you want is not evidence
> that it does it — read the module that consumes it.**

**[MJC-41]** **A dump hook addresses SDRAM, not the CPU bus — a memory-map change INVALIDATES it, and a placement slice IS a memory-map change.** Derive the constant from the RTL or select it per core, PRINT which one the run used, and grep for the literal whenever a region moves. A stale offset does not error, look empty or look constant (VRAM is a plausible 64 KB of changing bytes) — it reads as "the profile is not inert".

> **Incident** (`docs/platform/gotchas.md` › *jtframe's RTL plumbing (added 14z-107 (6), slice D1)*):
>
> - **THE SIM's RAM-DUMP HOOK ADDRESSES *SDRAM*, NOT THE 68k BUS — AND SLICE D2
>   MOVED WORK RAM (14z-107 (9)).** `JTFRAME_SIM_WRAMDUMP_OFF` is a BANK BYTE
>   OFFSET. On the reference core `RAM:$FF0000-$FFFFFF` is bank 0 byte
>   `0x600000`; on `cores/cps2w` the D2 bank-0 re-pack put it at `0x648000`,
>   and `0x600000` there is **VRAM**. Dumping the stale constant does not error,
>   does not look empty and does not look constant — VRAM is a perfectly
>   plausible 64 KB of changing bytes — so `tests/test_mister_wide_inert.sh`
>   went RED in **101 frames of 101** with the RTL completely innocent, and it
>   read exactly like "the profile is not inert". **The general rule: any
>   instrument that names a PHYSICAL address is invalidated by a memory-map
>   change, and a memory-map change is precisely what a placement slice is.**
>   Grep for the constant when you move a region. `tools/run_sim_jtcps2.sh` now
>   selects the offset from `--core` and PRINTS which one it used, so the run's
>   own log says what it dumped.
>   Worth keeping for the shape of it: the gate that went red was measuring the
>   right thing badly, and the two ways to tell them apart cost nothing — the
>   SDRAM census (which compared the same core's image against the map and
>   passed) and the run's own banner.

**[MJC-42]** **Check NON-CONSTANCY before anything else on a new dump path**: an all-zero buffer agreed with real work RAM on 99.2% of sampled bytes. Prove byte order on LIVE data (1-2 bytes differ the right way round, hundreds the wrong way), never by assumption.

> **Incident** (`docs/platform/gotchas.md` › *`jtsim -setname` re-downloads every run — and on CPS-2 you must download anyway (14z-107)*):
>
> **THE NEAR-MISS WORTH RECORDING:** the preloaded run's all-zero dumps agreed
> with MAME's work RAM on **99.2% of sampled bytes**, because most of a 64 KB
> work-RAM image is zero. "High agreement" is not evidence of a live oracle;
> the first check on any new dump path is **is it non-constant** — two frames
> of the same run must differ. (CLAUDE.md §4: verdict logic is itself tested.)

**[MJC-43]** **Assert the DUMP SET is complete** — every frame of the window, exact length, the address in the name — before any comparison. A comparison that GLOBS a directory cannot fail on a missing dump; it silently changes which frames the anchor search sees.

> **Incident** (`docs/platform/mister.md` › *The work-RAM oracle: `JTFRAME_SIM_WRAMDUMP` (measured 14z-107)*):
>
> **The lane as one command:** `tools/run_sim_jtcps2.sh <replay.rpl> <outdir>
> [--frames N] [--wram FIRST LAST] [--core cps2|cps2w]
> [--frame-output off|fork|collect]`, with `ROMDIR` and
> `JTSIM_SCRATCH` in the environment. Every step is idempotent (clone, symlinks,
> Go build, MRA, seed), it prints the sha1 of everything it reads, and it
> REFUSES an out-dir inside the repo (rule 7) or a scratch clone inside it.
> **Since 14z-107 (7) it also asserts the DUMP SET** — every `--wram` run ends
> with `tools/check_wram_dumps.py`, which requires every frame of
> [FIRST..LAST] to exist, at exactly the requested length, with the requested
> address in its name, and fails the run otherwise. That check exists because
> `tools/compare_fields.py` GLOBS a directory: a dump that is never written
> does not fail a comparison, it silently changes WHICH frames the anchor
> search sees. The gates run the same tool on any dump directory they did not
> produce (`test_mister_sim_anchor.sh` runs it on the MAME leg too,
> with `--contiguous` available for a directory of unknown extent).

**[MJC-44]** **A harness that DRIVES a port asserts every bit of it, modelled or not, and an active-low port defaults to PRESSED.** Verify an input path against the GAME's own input mirror on a second implementation running a known input, never against the harness's source (`SimInputs` held two buttons per player down for every run at v1.7.3).

> **Incident** (`docs/platform/gotchas.md` › *jtframe's RTL plumbing (added 14z-107 (6), slice D1)*):
>
> … ng bits 9:8
>   away — and the constructor seeds `joystick1..4 = 0xff`, which
>   `parse_inputs()` never corrects for players 2-4. `jtcps2_main.v:266-268`
>   wires `joystick1[9:7]` into `in1[2:0]`, `joystick2[8:7]` into `in1[5:4]`
>   and `joystick2[9]` into `in2[14]`, so on any 6-button core all four of
>   those buttons were pressed from the first line of `sim_inputs.hex` to the
>   last. Only EOF released P1's (`next()`'s else-branch restores `0x3ff`),
>   which meant a SHORTER input file changed the inputs — the opposite of
>   what a truncation should do; P2's were never released at all.
>   **THE GENERAL LESSON: a harness that DRIVES a port is asserting every bit
>   of it, including the ones it does not model — and an active-low port
>   defaults to PRESSED.** "The harness has 4 buttons" was the natural
>   reading and it was wrong by two buttons per player.
>   **How it was measured, and this is the reusable part:** a MAME
>   differential located the game's own input mirror (hold `p1=56` for six
>   frames on `05_timeout_idle`, diff whole work RAM at the onset →
>   `RAM:$FF8058`/`$FF805A` for P1 and `$FF805C`/`$FF805E` for P2, bit 0x40 =
>   button 6, 0x20 = button 5, live from MAME frame ~92). The pre-fix
>   simulation's `$FF8040-$FF8070` block is **byte-identical to MAME running
>   the same ROM with P1 and P2 buttons 5+6 physically held**, and to MAME's
>   no-input leg after the fix. Do not verify a harness against its own
>   source; verify it against a second implementation running a known input.
>   Found 14z-107 (7) while auditing the lane and deliberately NOT fixed
>   there (the fix moves the frozen §4 anchor, which has to be re-measured on
>   purpose); fixed and re-frozen 14z-107 (8). Historical consequence, now
>   closed: the MAME leg and the sim leg of `test_mister_sim_anchor.sh` were
>   not running identical inputs. … *(the paragraph continues in the origin doc)*

**[MJC-45]** **Derive an input bit map from the port's bit ORDER, then confirm it against the mirror; two data points cannot distinguish a swap from a reversal — probe every direction.** The sim input path is only ever as tested as the last replay that used it; a "refused" feature and a "held" one look the same from the counters.

> **Incident** (`docs/platform/gotchas.md` › *THE SIM HARNESS'S DIRECTION BITS ARE REVERSED — all four, end for end (measured in full 2026-08-24, 14z-108)*):
>
> **THE TRAP IS NOT THE BUG, IT IS THE HALF-MEASUREMENT.** 14z-107 (12) saw only
> Left and Down (they are the only directions `36_pick_tenant_cell` presses) and
> inferred a two-bit SWAP leaving Up and Right untouched, from the translator's
> docstring. That inference fitted both data points and was WRONG: Up arrives as
> Right. **A two-bit fix would have left half the defect in the tree and the
> gate would have frozen it.** Two data points cannot distinguish a swap from a
> reversal; the four-direction probe replay exists so the question is never
> asked from two again.

**[MJC-46]** **Frame output OFF for any state oracle.** The harness forks a child per changed frame; a child that `exit()`s rewinds the parent's input file (shared file description), so the simulated controller replays once per fork and the picture moves the CPU. A red cross-implementation anchor is root-caused CORE-VS-CORE (an inertness gate, invariant to the corruption) before RTL is blamed; the anchor gate is an oracle, not an inertness instrument.

> **Incident** (`docs/platform/gotchas.md` › *jtframe's RTL plumbing (added 14z-107 (6), slice D1)*):
>
> - **A FORKED CHILD THAT CALLS `exit()` REWINDS ITS PARENT'S INPUT FILE —
>   and that is how a Verilator core's PICTURE moved its simulated CPU
>   state.** RESOLVED 14z-107 (7); this entry used to say the path was open.
>   `exit()` runs the C stdio cleanup, which `fclose()`s every open C stream;
>   **libc++'s `std::basic_filebuf` is a `FILE*` underneath**, so a child
>   closes the copy it inherited of the parent's `std::ifstream`; and POSIX
>   makes `fclose()` on a seekable READ stream reposition the underlying file
>   description to the stream's logical position — a description SHARED with
>   the parent. The parent's next buffer refill then re-reads lines it had
>   already consumed. In jtframe's harness that stream is **`sim_inputs.hex`**,
>   the simulated controller, and `test.cpp`'s `video_dump()` forks one child
>   per CHANGED frame — so **the number of times the input script was replayed
>   followed the PICTURE.** That is the entire "video sensitivity": a core
>   missing `hdl/pal_lut.hex` renders black, forks about once, and therefore
>   runs a DIFFERENT input script from a core that renders the game.
>   **Controls, all measured** (cps2w, stock vsavj, `05_timeout_idle`, 681
>   dumps per leg, frames 2000-2680; full log `build/fork_rewind_14z107.log`):
>   frame output OFF, LUT present vs absent — **BIT-IDENTICAL, 681/681**. … *(the paragraph continues in the origin doc)*

**[MJC-47]** **Anything that parses a jtsim log de-duplicates by the reporter's own timestamp, requires cumulative counters MONOTONIC, drops torn rows and says how many** — a torn line parsed to a peak of 13,624% of the physical ceiling. Name the implausible value BEFORE the run.

> **Incident** (`docs/platform/gotchas.md` › *jtframe's RTL plumbing (added 14z-107 (6), slice D1)*):
>
> - **The same cleanup DUPLICATES LOG LINES.** `exit()` in the child also
>   flushes a COPY of the parent's buffered `stdout`, so a `$display` line
>   appears once per child (measured: 212 copies in a fork-mode jtsim log
>   against one with frame output off). Anything that PARSES a jtsim log has
>   to cope — `tests/audit_sdram_bank_load.sh` de-duplicates by the
>   reporter's own `t=` timestamp and requires it to be strictly increasing.

**[MJC-48]** **An SDRAM read probe has slots in PAIRS on purpose**: some arm the windows under test, the others arm windows that MUST see traffic, so a zero is evidence about the core and not about the probe. Units are burst BEATS, not ACTIVATEs — divide by burst length before comparing with the stats reporter. Windows are DERIVED from the RTL constants ([MJC-41]). **Look a probe up by the BANK it watches, never by slot number** — slots are numbered in the order the windows are given, and a lookup by the wrong number reports a counting probe as dead.

> **Incident** (`docs/platform/mister.md` › *THE SDRAM READ PROBE: watching the core FETCH (measured 14z-107, fork commit 12)*):
>
> - **Four slots, not two, and the reason is the instrument's own honesty.**
>   Two of them arm the windows under test and two arm windows that MUST see
>   traffic (the vanilla object banks). Without the second pair a zero on the
>   first pair would be ambiguous between "the core did not fetch" and "the
>   probe does not count" — and this lane has produced four false verdicts
>   from instruments already. **And a probe is looked up by the BANK it watches, never by slot number** (14z-134): the driver numbers slots in the ORDER the `--rdprobe` windows are given, `test_mister_qsound_ext` armed bank 3 third and read `RDPROBE SUMMARY 3` — a slot that does not exist — so a probe that had counted 171,491,620 reads was reported dead on the release run.

**[MJC-49]** **The control shape is two legs differing by ONE BYTE — the profile byte.** Build it even when the verdict is a counter: the first thing it produces is a picture that cannot be misread (the legal screen vs a field with only the logo), which is the cheapest proof the bit is live.

> **Incident** (`docs/platform/mister.md` › *The cheapest proof that the profile bit is live: LOOK AT THE SCREEN*):
>
> Worth keeping for the shape of it: a two-legged experiment whose legs differ by
> one byte is worth building even when the verdict is a counter, because the
> FIRST thing it produced was a picture that could not be misread.

**[MJC-50]** **The census asks what is IN memory; the probe asks what was READ.** `test.cpp` dumps all four banks once, the instant a FULL download ends, with the core still in reset — the image is pure download, and a census costs the download and nothing else (`--post-frames`, `--keep-banks`). Its must-fire: a 1 KiB shift of any placement constant must be rejected.

> **Incident** (`docs/platform/mister.md` › *THE SDRAM IMAGE CENSUS: reading the download back out (measured 14z-107)*):
>
> - **`test.cpp` dumps all four banks, once, the instant a FULL download
>   ends.** `test.cpp:915` `if( dwn.FullDownload() ) sdram.dump();`, and
>   `SDRAM::dump()` writes `sdram_bank0-3.bin` (4 x 16 MB under
>   `_JTFRAME_SDRAM_BANKS`) into `cores/<core>/ver/game`. Because it fires at
>   the end of the transfer and the core is held in reset until then, the image
>   is PURE download: nothing the 68k does has happened yet.
>   `tools/run_sim_jtcps2.sh --keep-banks` collects them; without it the tool
>   still deletes them, because 64 MB of ROM-derived litter per run was the
>   reason they were being deleted in the first place.

**[MJC-51]** **A simulation model can be a DIFFERENT PART from the one the design targets, and it will not tell you** (the SDRAM model dropped the top address bit and aliased the upper half of every bank). **Do not infer a bit-level fix from a SIZE** — "22 of 23 bits" says how many are missing, never which; read the line that drives the pins.

> **Incident** (`docs/platform/gotchas.md` › *The Verilator SDRAM model dropped the TOP address bit — and the obvious fix was wrong (14z-107)*):
>
> **THE TRAP, and it is the general lesson: the missing bit was NOT the one the
> size arithmetic points at.** "13 row + 9 column = 22 bits, so widen the column
> to 10 bits (`<< 10`, `& 0x7fffff`, `0x3ff`)" is the natural reading, and it
> would have folded the TOP address bit onto `addr[9]` and produced a
> different wrong map. `jtframe_sdram64_bank.v` maps the address like this:

**[MJC-52]** **THE INSTRUMENT PROTOCOL**: (1) separate the AUTHOR from the VERDICT — measure in one scope, judge in another; (2) prove an instrument FIRES on a known positive, FAILS on a known negative, and name its IMPLAUSIBLE value before its first real use; (3) an instrument that names a PHYSICAL CONSTANT must assert it. For a green: ask what would have to be true for it to be green WRONGLY. Every instrument defect in this lane was caught by a cheap mechanical check, none by re-reading the work.

> **Incident** (`docs/project/gotchas.md` › *THE INSTRUMENT PROTOCOL (adopted 14z-107 (11), maintainer-directed)*):
>
> **Paid for six times in one arc, and the class is older than the arc** (see
> "half the Lua instruments stage inputs one frame off" and "success while the
> instrument was not the one being claimed", both above). The maintainer's
> direction, 2026-08-24: tighten how agent-driven instrumentation works, choose
> the mechanism on the facts, and prefer scoping for context and efficiency.

**[MJC-53]** **VRAM is NOT a cross-implementation video oracle** — two unrelated implementations legitimately hold different palette and tilemap bytes (the palette by half), on stock content too. The display list the CPU BUILDS is; pixels need an instrument nobody has yet; and a 1P replay's CPU opponent differs between legs, so compare the subset your profile LABELS and REPORT the remainder, never assert it.

> **Incident** (`docs/project/mister_core.md` › *12. The holes — what has never been tried*):
>
> | **Video compared against MAME** | **FIRST COMPARISON MADE 14z-108, on the DATA rather than the pixels.** VRAM `$900000-$93FFFF` (palette + scroll tilemaps — what DETERMINES the frame) dumped from both at the frozen anchors: **the CPS-A/CPS-B video registers were documented the same session** (`atlas/ram.md`, "CPS-2 VIDEO REGISTERS") and the diff re-cut along the real layer map: **scroll1 22.3% differing, scroll3 2.9%, scroll2 17.7%, and the PALETTE 52.7%** — with `layer_control 0x2d0e`, i.e. **all three scroll layers ENABLED**. Row-scroll and every UNCLAIMED region (204,800 bytes, and not zero) are byte-identical. **An earlier reading of this that called the identical 128 KB "scroll tilemap" was WRONG — no layer base points there; it is unclaimed VRAM.** So the differences are in LIVE surfaces. **THE LEGACY CONTROL SETTLES IT: NOT OURS.** The same comparison on STOCK `vsavj` with the legacy replay `05_timeout_idle` gives the SAME pattern and magnitudes (scroll1 35.4%, scroll3 3.8%, scroll2 15.1%, palette 51.2%, row-scroll and unclaimed 0%) — on vanilla content, with the roster nowhere in sight. So this is a GENERAL MAME-vs-jtcps2 implementation difference and says nothing about the profile. **The useful negative result: VRAM is NOT a viable cross-implementation video oracle** — two unrelated implementations legitimately differ there, the palette by half, so the surface cannot distinguish a port defect from an implementation difference. A future video oracle needs rendered frames, the OBJ list, or the post-conversion palette. Row-scroll and all unclaimed VRAM are byte-identical in BOTH runs, so the transfer and dump paths are sound. PIXELS are still never compared, and **the two committed select-screen images do not change that.** **AND THE SUCCESSOR SURFACE WAS FOUND AND IT AGREES — 14z-109, THE OBJ LIST.** That row above names "the OBJ list" as a candidate; it was tried and it WORKS, because the OBJ list is what the 68k BUILDS rather than something each implementation stages its own way. ORAM is dumpable on both (MAME by address; the core because D2 maps it to SDRAM bank 0 byte `0x640000`), and `tools/oram_obj_records.py` walks it into the same records `tests/lua/obj_records_dump.lua` prints from the live machine — **byte for byte, 1153/1153 lines, verified before any core data was read**. **THE TRAP, AND IT IS NOT VRAM'S:** a 1P replay's CPU opponent is the SOUND-STATE-FED LOTTERY (`atlas/ram.md:99`), so the two legs fight DIFFERENT opponents and the raw lists cannot be compared whole — at the tenant anchor the totals are 40 vs 129. An OBJ list cannot be filtered "by P2" the way `fields_m2a.tsv` is, because sprites carry no owner. **BUT OUR OWN CONTENT IS LABELLED: y bit 12, the CPS-2 Turbo promote (slice D3), is set on exactly the group-C sprites this port adds and on nothing vanilla can emit.** **RESULT AT THE FROZEN TENANT ANCHOR (MAME 2886 / sim 3546): the promoted subset is 31 entries on BOTH legs, ORDERED AND FIELD-FOR-FIELD IDENTICAL, and the 19-bit tile addresses slice D3 computes are the SAME SET, `0x4b0c4-0x4ecda`.** That is the first cross-implementation agreement this project has on a video-determining surface, and it is on the content the port exists to add — the promote, the group-C redirect and the 3-bit bank, confirmed end to end against an unrelated codebase. The unpromoted remainder (9 vs 98) is the lottery and is REPORTED, never asserted. Gate: `tests/test_mister_obj_oracle.sh`. **Still not pixels: this is the sprite LIST, not the rendered frame.** |

**[MJC-54]** **Never edit a running shell script** — `sh` reads by byte offset and a comment-only edit derails a 55-minute gate at its last step. Freeze `tests/` and `tools/` for the whole of a long run; if you slip, REVERT THE EXACT BYTES immediately. A WORKTREE copy under execution is the same file to the process reading it — the rule is about the running process, not the checkout.

> **Incident** (`docs/platform/gotchas.md` › *Editing a shell script WHILE it runs corrupts the running execution (14z-107)*):
>
> `sh` reads a script incrementally and keeps a BYTE OFFSET into the file. Edit
> the file while it is executing and the offset now points into the middle of a
> different line: the still-running shell resumes at a token boundary that never
> existed. **Paid AGAIN 14z-134 on a WORKTREE copy of the same driver** — the process reading a file does not care which checkout it lives in; a leg of the fresh-clone census died at `line 496: syntax error` after its simulation because the worktree's `run_sim_jtcps2.sh` had been edited under it. Paid for here on a 55-minute gate — `tools/run_sim_jtcps2.sh` had run
> its 2,880-frame Verilator simulation to completion, and then died on

**[MJC-55]** **`pgrep -f` waiters match their own command line and never exit.** Wait on a recorded PID (`kill -0`) or a marker file the job writes; sweep leftover `obj_dir/sim` processes at session end.

> **Incident** (`docs/project/gotchas.md` › *`pgrep -f` WAITERS MATCH THEMSELVES AND NEVER EXIT (paid: 2026-08-24, 14z-107, four times in one task)*):
>
> `until ! pgrep -f "<pattern>"; do sleep 30; done` **never terminates.** The
> shell running the loop has the pattern in its OWN command line, so `pgrep -f`
> finds it, and the waiter waits for itself forever. Long MiSTer simulation runs
> are exactly where this is reached for, and exactly where an unbounded hang is
> most expensive — one leg of a four-leg measurement can burn an hour before
> anyone notices the waiter, not the simulation, is what is stuck.

**[MJC-56]** **A fixture whose meaning depends on the build is a CLAIM about the build** (a replay named for what it picked three freezes ago). Confirm the rig on the fast implementation (minutes on an emulator) before paying for the simulation (an hour), so a zero from the sim is a finding about the core and not about the replay.

> **Incident** (`docs/project/gotchas.md` › *A REPLAY'S NAME IS A CLAIM ABOUT THE BUILD (paid: 2026-08-24, 14z-107)*):
>
> **The rule.** This is the sibling of "identify moves by measured EFFECTS,
> never the script's input name" (14z-102), one level up: **an artifact whose
> meaning depends on the build is a CLAIM about the build, and needs asserting
> like any other.** A replay named for a character is exactly as trustworthy as
> a hardcoded `0x600000` — see THE INSTRUMENT PROTOCOL's rule 3, which this
> instance generalises from instruments to fixtures. The cheap assertions
> already exist and were not consulted: the expectation class
> (`tests/expected/donovan-m11/11_pick_donovan.masked` is a LEGACY class, not a
> tenant one) and `tests/test_select_arrays.sh:85`, which says in words
> "11_pick_donovan … ending on Jedah".

## 0.6 Synthesis and release of a bitstream

**[MJC-57]** **Quartus in Docker: keep `--network host`** (without it `quartus_map` segfaults in the licence host-id code and LIES that it ran out of memory at 3% usage); **clone NON-recursively, `checkout` the pin, THEN `submodule update --init --recursive` with `GIT_TERMINAL_PROMPT=0`** (`--recursive` resolves submodules against the default branch, which registers a repo that does not exist, and git hangs forever on a credential prompt); **build the REFERENCE core FIRST** so a failure is attributable.

> **Incident** (`docs/platform/mister.md` › *3. build — the CONTROL FIRST, deliberately*):
>
> **FOUR LOAD-BEARING DETAILS, none cosmetic:**
> 1. **`git clone` is NOT `--recursive`, and `git checkout 7b9a0d2d` comes
>    BEFORE the submodule pass.** `--recursive` resolves submodules against the
>    DEFAULT BRANCH, and jtcores master registers `modules/jt539`, which does
>    not exist — git then hangs FOREVER on a credential prompt with no error.
>    The fix is ORDERING, not a flag. (`docs/platform/gotchas.md`.)
> 2. **`GIT_TERMINAL_PROMPT=0`** turns any other dead repository from a silent
>    stall into a fast failure.
> 3. **`--network host` or `quartus_map` SEGFAULTS** in FlexLM's host-id path —
>    and reports it as a MEMORY error at 487 MB peak against 15 GB free
>    (`docs/platform/gotchas.md`).
> 4. **Build `cps2` FIRST.** It is the reference leg: without it a timing
>    failure on `cps2w` cannot be attributed to our slices. Ordering it first
>    also means a flow failure cannot be misread as a `cps2w` result.

**[MJC-58]** **Fit and timing are SEPARATE verdicts.** Never report "closes timing" from one run: sweep seeds and state the SPREAD and MEDIAN against the reference core on the same toolchain; an extended core that straddles zero slack while the reference does not is the finding, not the pass.

> **Incident** (`docs/platform/gotchas.md` › *`xjtcore.sh` RETRIES UNTIL A SEED PASSES, SO A GREEN BUILD CERTIFIES A PLACEMENT AND NOT A DESIGN (measured 2026-08-25, 14z-108, n=12)*):
>
> 1. **Never report a jtcores build as "closes timing" from one run.** Sweep
>    seeds and state the SPREAD and the MEDIAN, not the draw you got.

**[MJC-59]** **`xjtcore.sh` calls `jtseed`, which retries `--seed $RANDOM` and BREAKS ON FIRST SUCCESS.** A green build certifies "one placement was found that closes", never "this design closes with margin" — it hides FRAGILITY, not correctness. **A failing seed still emits an `.rbf` indistinguishable from a good one, and a sweep overwrites the published path with whatever ran last: verify the hash before flashing.**

> **Incident** (`docs/platform/gotchas.md` › *`xjtcore.sh` RETRIES UNTIL A SEED PASSES, SO A GREEN BUILD CERTIFIES A PLACEMENT AND NOT A DESIGN (measured 2026-08-25, 14z-108, n=12)*):
>
> **BE PRECISE ABOUT WHAT THAT HIDES — the first draft of this entry was
> stronger than the evidence.** It does NOT mean the flow ships failing
> bitstreams. At the measured per-seed failure rate the chance all four draws
> fail is about 1%, so **roughly 99% of invocations produce a gate-passing
> `.rbf`**. What it hides is **FRAGILITY, not correctness**: the artifact
> handed to you is a CHERRY-PICKED PLACEMENT — the first of up to four random
> draws that happened to close. **A green run certifies "one placement was
> found that closes"; it never certifies "this design closes with margin".**
> Those are different claims and only the second is a basis for building on.

**[MJC-60]** **Failing paths that RESHUFFLE between seeds mean a marginal CONE, not a slow path.** Attribute against the fitted netlist (`report_timing`): a cone inside shared `jtframe_sdram64` at an SDRAM address pin is the framework's, not any slice's. Spending margin back is a DESIGN decision under the extension's governance, never a seed hunt, and a single-seed slack is not headroom a later slice may assume.

> **Incident** (`docs/platform/gotchas.md` › *`xjtcore.sh` RETRIES UNTIL A SEED PASSES, SO A GREEN BUILD CERTIFIES A PLACEMENT AND NOT A DESIGN (measured 2026-08-25, 14z-108, n=12)*):
>
> 4. Failing paths that RESHUFFLE between seeds indicate a marginal CONE, not
>    a slow path. At n=12 the worst path was a different register on nearly
>    every seed (`post_act`, `in_busy`, `br`, `st[0]`, `actd`, `rfsh|help`)
>    landing on `sdram_a[7]`, `[8]` or `[11]`, and **the number of failing
>    paths outside `jtframe_sdram64` was ZERO across all twelve** — verified
>    by grepping every negative-slack row of every seed, not by sampling.
>    Fixing that is a design change, not a seed hunt.

**[MJC-61]** **A jtcores bitstream carries a `%y%m%d` build datestamp**: the same seed reproduces the PLACEMENT and TIMING exactly and a DIFFERENT hash on a different day. **The hash identifies the ARTIFACT, the seed identifies the RESULT** — never read a hash mismatch as a failed reproduction; check the seed and the reported slack.

> **Incident** (`docs/platform/gotchas.md` › *A jtcores BITSTREAM CARRIES A BUILD DATESTAMP, SO THE SAME SEED REBUILDS TO A DIFFERENT HASH ON A DIFFERENT DAY (measured 2026-08-25, 14z-108)*):
>
> **THE RULE THAT FOLLOWS: THE HASH IDENTIFIES THE ARTIFACT, THE SEED
> IDENTIFIES THE RESULT.** Never read a hash mismatch as a failed reproduction
> — check the SEED and the reported SLACK instead. This is the same shape as
> the green-build trap above: two different claims that look like one.

**[MJC-62]** **Release policy: a shipped bitstream is built from a NAMED seed (`jtcore <core> -mister --nodbg --seed <S>`), never an `xjtcore.sh` draw**, with seed, slack, sha256, build date and fork pin recorded beside it. The bitstream is a BUILD RESOURCE on its own cadence: it lives ONCE under `release/bitstreams/<seed>/` with a `CURRENT` pointer, is hash-verified into every release by the packager (which REFUSES a mismatch), and is never overwritten and never copied release-to-release — a new bitstream is a new seed directory and a `CURRENT` bump.

> **Incident** (`docs/project/release_format.md` › *The rule*):
>
> * **MiSTer ships the MRAs the release was verified with, the `.rbf` itself
>   and its RECORD (`BITSTREAM.txt`: seed, slack, sha256, build date, fork
>   pin, field history)** — ruled tracked in-tree, "as would any BPS or
>   xdelta". **The bitstream is a BUILD RESOURCE with its own cadence**
>   (unchanged 14z-108 → 14z-113 while the romset moved four times), so it
>   lives ONCE, canonically, under **`release/bitstreams/<seed>/{jtcps2w.rbf,
>   BITSTREAM.txt}`** with **`release/bitstreams/CURRENT`** naming the seed
>   every release packages from (maintainer, 2026-08-28: "a common build
>   resource, itself rebuildable with the correct environment, so that every
>   release includes it — never copied from another release"). The packager
>   resolves `CURRENT` (or `--bitstream DIR`), verifies the file's sha256
>   against the record and REFUSES on mismatch, then copies both into
>   `mister/`. A rebuilt bitstream (new seed, slice or pin) gets its own
>   directory and a `CURRENT` bump — never an overwrite: a timing-failing
>   seed emits an indistinguishable `.rbf`, and the same seed rebuilds to a
>   different hash on a different day, so the record IS the identity. The
>   `[STOCK CONTROL]` MRA is included and labelled "run when the bitstream
>   changes".

## 0.7 MRA and `.rom` generation mechanics

**[MJC-63]** **A set must exist in `$JTROOT/doc/mame.xml`** — jtframe's own REDUCED, committed, GENERATED catalogue, not a MAME `-listxml` dump. An uprev or `jtframe mra --reduce` regeneration can drop an added entry and nothing warns; the MRA simply stops being emitted. Gate its existence.

> **Incident** (`docs/platform/mister.md` › *HOW THE MRA AND THE `.rom` ARE MADE (measured 14z-107)*):
>
> - **A set must exist in `$JTROOT/doc/mame.xml`** — jtframe's own REDUCED
>   machine catalogue, committed in the repo, not a MAME `-listxml` dump.
>   `jtframe mra` streams it (`mamegame.go:167-250`) and everything else keys
>   off what it finds there. A romset with no machine entry produces no MRA,
>   whatever the TOML says. **Hazard worth naming: that catalogue is a
>   GENERATED file upstream** (`jtframe mra --reduce <mame.xml>`), so a future
>   uprev or regeneration can drop an entry we added. Nothing warns; the MRA
>   simply stops being emitted. `tests/test_mister_mra_map.sh` fails with
>   "cores/cps2w did not emit the WIDE MRA at all" if that happens, and
>   `tools/gen_vsavjw_xml.py` re-emits the entry.

**[MJC-64]** **`mra2rom` locates every zip member by CRC32 and by NOTHING ELSE** (`name` appears only in the warning text). FBNeo and MAME resolve by name and merely warn on a hash mismatch — so a driver's SENTINEL CRCs work there and produce NO `.rom` here. **An MRA is pinned to the exact bytes of one romset build**: a rebuild that moves one CRC moves the catalogue entry, the `parts=` row, a fork commit and the pin.

> **Incident** (`docs/platform/mister.md` › *HOW THE MRA AND THE `.rom` ARE MADE (measured 14z-107)*):
>
> - **`mra2rom` locates every zip member by CRC32 and by NOTHING ELSE**
>   (`mra2rom.go:163-172`: it walks the zips comparing `file.CRC32`; the
>   `name` attribute is used only in the warning text). **This is a real
>   divergence from FBNeo and MAME**, which resolve by name and merely warn on
>   a hash mismatch — which is why this project's WIDE members carry SENTINEL
>   CRCs in both of those drivers and why content there can change freely. On
>   MiSTer a sentinel means `Warning: cannot find file … in zip` and no `.rom`.
>   Consequence: **an MRA is pinned to the exact bytes of one romset build.**

**[MJC-65]** **The zip search path is a HARD-CODED `$HOME/.mame/roms/<name>.zip`** with no flag. Stage a PRIVATE `$HOME` per run; never write into the user's.

> **Incident** (`docs/platform/mister.md` › *HOW THE MRA AND THE `.rom` ARE MADE (measured 14z-107)*):
>
> - **The zip search path is a HARD-CODED `$HOME/.mame/roms/<name>.zip`**
>   (`mrazip.go:23`), so the tool's output is a function of the invoking
>   user's home directory and there is no flag for it. `tools/mister_mra.sh`
>   stages a PRIVATE `$HOME` per run instead of writing into the user's — and
>   it had to, because the stock leg and the WIDE leg then needed DIFFERENT
>   `vsav.zip` files (the merged build patched `vm3.13m/15m/17m/19m` into its
>   own parent). **CORRECTED 14z-112: builds no longer pack a parent — the four patched members live INSIDE `vsavjw.zip` and BOTH legs use the PRISTINE dump, so one SD card can carry this profile and stock Vampire Savior.** The private `$HOME` staging stays: `jtframe`
>   still hard-codes its lookup path.

**[MJC-66]** **`parts=` puts every part of a `width>8` region inside ONE `<interleave>`, resolved to the FIRST finger claiming each lane and truncated to the SHORTEST** — three members with the same map silently collapse to the first. Use one REGION per differently-mapped group, with a generic `{ name=…, skip=true }` row for every other set, because **a region with no config at all still emits its `<!-- … starts at … -->` comment** and breaks a byte-identity twin. `parse_parts` does not apply `reverse`: spell the final map string.

> **Incident** (`docs/platform/mister.md` › *HOW THE MRA AND THE `.rom` ARE MADE (measured 14z-107)*):
>
> - **`parts=` puts EVERY part of a region inside ONE `<interleave>` when
>   `width > 8`** (`corerom.go:462-479`), and `interleave2rom` resolves each
>   output byte lane to the FIRST finger claiming it (`mra2rom.go:238-249`).
>   So `parts=` can express a multi-member 16-bit region only if the members'
>   maps are DISJOINT (Pang!3's four 64-bit lanes are; three CPS-2 QSound
>   members all carrying `map="12"` are not — they silently collapse to the
>   first, truncated to the shortest). The way out is one region per
>   differently-mapped group, with a generic `{ name=…, skip=true }` row so
>   every other set skips it — **a region with no config at all still emits
>   its `<!-- … starts at … -->` comment**, which is enough to break a
>   byte-identity twin.

**[MJC-67]** **Region-start arithmetic has three silent traps**: the generator's `pos` counts the key region while the RTL's `bulk_addr` does not (they agree only because every start is 1 KiB-aligned — keep it so); the header start word is 16 bits of `start >> 10` and an oversized start is written WRAPPED with no warning; the game-side `ioctl_addr` is 26 bits (64 MB) even where the target carries 27. `rom_len` never shrinks a region — it still advances `pos` by the full file.

> **Incident** (`docs/platform/mister.md` › *HOW THE MRA AND THE `.rom` ARE MADE (measured 14z-107)*):
>
> - **Region starts in the MRA comments are the generator's `pos`, which
>   INCLUDES the 20-byte `key` region; the RTL's `bulk_addr` does not.** On
>   CPS-2 every region therefore starts at `<1 KiB-aligned> + 0x14`, and the
>   `>> 10` header word is right only because `0x14 < 1024`. Measured on the
>   stock `vsavj` MRA: `maincpu` at `0x14`, `audiocpu` at `0x400014`,
>   `qsound` at `0x440014`, `gfx` at `0xC40014`, `firmware` at `0x2C40014`.

**[MJC-68]** **`jtframe mra -n` is the ROM-free mode**: no zips opened, `md5="None"`, the XML a pure function of the catalogue plus the core's TOML — what a structural gate wants.

> **Incident** (`docs/platform/mister.md` › *HOW THE MRA AND THE `.rom` ARE MADE (measured 14z-107)*):
>
> - **`jtframe mra -n` skips ROM generation entirely** — no zips are opened,
>   `md5="None"`, and the MRA XML becomes a pure function of `doc/mame.xml`
>   plus the core's TOML. That is the ROM-free mode a structural gate wants.

**[MJC-69]** **An MRA part that does not resolve is `0xFF`-FILLED, never refused**, so a half-resolved set "runs" and shows nonsense. Check every part resolves against the EXACT zips the card will carry, before anything ships.

> **Incident** (`docs/project/mister_field.md` › *2. Before the board: the bundle and its control*):
>
> 1. **Verify the `.rbf` hash before flashing** — a timing-failing seed emits an
>    indistinguishable bitstream (`platform/gotchas.md`). The record is
>    `BITSTREAM.txt`: seed 18269, sha256 `46fc74af…`, 3,111,944 B.
> 2. **Every MRA part must resolve against the EXACT zips on the card.**
>    jtframe fills an unresolved part with `0xFF` rather than refusing, so a
>    half-resolved set "runs" and shows nonsense. `tools/check_mra_parts.py`
>    / `tests/test_mra_parts.sh`: WIDE 31 of 31 parts, STOCK CONTROL 22 of 22,
>    both against the pristine `vsav.zip` (since 14z-112 the build packs no
>    parent; the patched group-A members live inside `vsavjw.zip`, so one card
>    carries this profile AND stock Vampire Savior — field-confirmed
>    2026-08-28).
> 3. **Never test without the control.** The 14z-108 bundle shipped ONE MRA;
>    14z-109 added `[STOCK CONTROL]` before it was run: stock `vsavj` on the
>    SAME `jtcps2w.rbf` with the profile byte left at the `0xFF` fill — the
>    emulator superset invariant on silicon, not a second core.
>    STOCK boots + WIDE fails -> the problem is OURS (highest-value report).
>    STOCK fails too -> not ours: the bitstream, the SDRAM module, the card or
>    the video chain. Since the bitstream, not the romset, is what this
>    control certifies, it needs running once per NEW `.rbf` (seed, slice or
>    pin), not per romset release — **RULED so by the maintainer 2026-08-29
>    (14z-118): keep it in every release's `mister/`, run it when the
>    bitstream changes, off the per-release checklist; seed 18269 is covered
>    by the 14z-113 pass until the next synthesis** *(this sentence read
>    "recommendation; the maintainer asked, did not rule" until then)*.

## 0.8 What is NOT known — state it, never hide it

**[MJC-72]** **The 128 MB module's chip-select polarity is inferred from jtframe's RTL, never seen on a schematic.** If XL is ever taken, confirm the module in hand first.

> **Incident** (`docs/project/mister_core.md` › *12. The holes — what has never been tried*):
>
> | **The 128 MB module's chip select** | the XL fallback (§4) assumes the module inverts chip 1's `/CS`. That is INFERRED from jtframe's RTL, never seen on a schematic. If XL is ever taken, confirm which module is in hand first. |

**[MJC-73]** **Timing closure is a SEED LOTTERY**: a shipped `.rbf` is a passing DRAW from a distribution some of whose seeds fail, not a privileged build — say "commonly", not a fraction from one sweep, and quote the seed with the artifact.

> **Incident** (`docs/project/mister_core.md` › *12. The holes — what has never been tried*):
>
> | **SYNTHESIS — does it CLOSE TIMING** | **NO, NOT RELIABLY (14z-108 seed sweep, n=12).** `cps2w` twelve seeds span **-0.545..+0.396 with FOUR FAILING**, median **+0.038**; `cps2` five seeds span **+0.144..+0.665 with NONE failing**, median **+0.431**. The BEST cps2w seed is worse than the MEDIAN cps2 seed, cps2's WORST beats eight of twelve cps2w seeds, and two cps2w "passes" clear by under **10 picoseconds**. Failure rate 4/12, 95% CI ~14-61% — say "commonly", not "a third". The FAILs are **jtframe's own timing gate** on runs Quartus reported as "Full Compilation successful, 0 errors". **`xjtcore.sh` calls `jtseed 4`, which retries and BREAKS ON FIRST SUCCESS — and be precise about what that hides: NOT correctness (~99% of invocations produce a passing `.rbf`) but FRAGILITY. A green run certifies "one placement was found that closes", never "this design closes with margin".** Every failing path is in `jtframe_sdram64` at an SDRAM address pin and RESHUFFLES between seeds: the marginal thing is that controller's ADDRESS-GENERATION CONE as a whole, shared infrastructure the fork does not touch — **not WIDE's own logic**. Never verdict (b): the control closed on every seed tried. Does not block shipping (we distribute a prebuilt `.rbf` and the baseline is a passing draw) but **+0.066 is not headroom a future slice may assume**. **A FAILING SEED STILL EMITS AN `.rbf`** — verify the hash before flashing. |
