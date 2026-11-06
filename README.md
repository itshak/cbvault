<h1 align="center">cbvault</h1>

<p align="center">
  <strong>Read ChessBase databases from Rust — 100% MIT.</strong><br>
  The classic <code>.cbh</code> family and <code>.cbv</code>/<code>.cbz</code> archives,
  with <a href="https://crates.io/crates/gigachess">gigachess</a> as the one and only
  chess core, a zero-allocation conversion sink for downstream engines and a streaming PGN exporter.
</p>

<p align="center">
  <a href="./LICENSE"><img src="https://img.shields.io/badge/License-MIT-yellow.svg?style=flat-square" alt="License: MIT"></a>
  <img src="https://img.shields.io/badge/chess%20core-gigachess-informational?style=flat-square" alt="Chess core: gigachess">
  <img src="https://img.shields.io/badge/status-alpha%20%2F%20in%20progress-orange?style=flat-square" alt="Status: alpha / in progress">
</p>

---

> **Not affiliated with ChessBase.** cbvault is an independent, MIT-licensed
> implementation. ChessBase file formats are the *input*. No ChessBase code is
> used, and no ChessBase data is redistributed. ChessBase is a trademark of its
> respective owner, used here only to name the file formats this library reads.
>
> The classic `.cbh` readers are built on **`cbformat` from
> [`oschess-cb-bridge`](https://github.com/asavis/oschess-cb-bridge)** (MIT,
> "Copyright (c) 2026 the oschess-cb-bridge contributors"), ported with
> attribution — ported files keep the upstream MIT notice, and every one is listed
> in [`docs/provenance.md`](docs/provenance.md) and
> [`THIRD_PARTY_NOTICES.md`](THIRD_PARTY_NOTICES.md). The `.cbv`/`.cbz` container
> and its codec were written from the published format facts alone. See
> [Provenance and licensing](#provenance-and-licensing).

> ## ⚠️ This library is a work in progress. Read this before you rely on it.
>
> The classic `.cbh` family is genuinely implemented and tested, and **`.cbv`
> archives now unarchive completely — every member, byte-identical to the
> reference extractor.** `.cbz` works, including every password length.
> **2CBH read support is in active hardening**: `.2cbh`/`.2cbg`/`.2cba`/`.2lid`,
> legal gigachess replay and PGN work on a 3.41M-game Mega 2026 test corpus.
> Full byte-accurate ChessBase gold validation is **not yet complete**. Rare
> annotations, multimedia, embedded quotations, and real-world Chess960 are
> not proved universally. See the [active release-hardening OpenSpec](openspec/changes/native-2cbh-release-hardening/proposal.md).
> The [What is not supported yet](#what-is-not-supported-yet) section below is
> specific and states exactly what is missing. Please read it before you decide
> whether this fits your use — a short README that overstates what works is worse
> than a longer one that tells the truth.

## Features

- **Classic `.cbh` family, fully read.** Headers, move records, annotations
  (comments, NAGs, glyphs, medals, quotations, evaluations, elapsed time), entity
  namebases, the `.flags` metadata, the `.cbj` wide index for sets over 4 GiB,
  Chess960 and set-up start positions, and PGN export. The mandatory set
  (`.cbh .cbg .cba .cbp .cbt .cbc .cbs`) is validated on open; optional members
  are reported, not required.
- **A conversion sink, not a format.** `GameSink` is told once per run what it
  needs — position keys, annotations — and is then handed one entirely borrowed
  `GameRef` per game, in ascending game-number order. Nothing is formatted, and a
  sink that only counts games touches the allocator **zero times per game**.
- **Ordered parallel conversion.** `convert_parallel` cuts the id space into
  8,192-record chunks, gives each worker its own buffers, and has one writer stage
  deliver chunks **in game-number order**. The sink sees the same games, in the
  same order, with the same payloads, at one thread or ten.
- **One chess core.** Move generation, legality, FEN/SAN/UCI, Chess960 and
  incremental Polyglot Zobrist hashing all come from
  [`gigachess`](https://crates.io/crates/gigachess). The internal move currency is
  its 16-bit `moves2` (`from | to << 6 | promo << 12`; castling is king→rook,
  `e1h1` / `e1a1`). There is deliberately no second chess implementation in this
  tree, and a CI job fails the build if one appears.
- **PGN export, sequential or Rayon-parallel, byte-identical either way.** Output
  is a strict superset of what ChessBase writes: reading stays liberal, writing
  stays standard. Against a 419,385-game ChessBase export, **407,350 games (97.1 %)
  match byte for byte**; the remaining differences are five deliberate,
  documented deviations plus a small residue.
- **`.cbv` archives unarchive completely — byte-for-byte, and ~9× faster than
  `uncbv`.** All four of the container's block modes are decoded, so all
  **3,871 of 3,871 members** and **100 % of the archive's 3.61 GB** come out,
  including the 512 MB `.cbh`, the 1.25 GB `.cbj`, `.cbg` and `.cba`. Every
  member is **byte-identical to the reference extractor's own output**, on all
  four test corpora. `.cbz` is fully supported, including all three password
  lengths.

  > **How the codec was written.** The only implementation that already decoded
  > these modes was GPL-3.0, so it could be *run* as an oracle but not linked or
  > copied. The codec was written from the **published format facts** — byte
  > layouts, algorithms and constants — and then verified against that reference
  > process's own output, byte for byte. The specification it was written from,
  > the review that gated it, and the member-by-member result are in
  > [`docs/research/03-clean-room-audit.md`](docs/research/03-clean-room-audit.md);
  > the format itself is in
  > [`docs/cbv-reference.md`](docs/cbv-reference.md). The licence, not the
  > format, was the obstacle.

  | | `uncbv` (GPL, oracle) | `cbvault` |
  |---|---|---|
  | extract the 1.74 GB reference archive | 67.68 s | **7.18 s** |
  | decoded throughput | 53 MB/s | **502 MB/s** |
  | members extracted | 3,871 / 3,871 | **3,871 / 3,871** |
  | bytes matching its output | — | **3,607,876,417 (100 %)** |
  | licence | GPL-3.0 | **MIT** |

  Measured on a 10-core Apple Silicon machine, both writing to disk; the
  reference's spread is reported as a range rather than a single number. Full
  method and caveats in
  [`.cbv` and `.cbz`](#cbv-and-cbz-the-whole-archive).
- **`.cbh` reading is faster than the MIT ancestor we ported from, on every
  path and every thread count.** Both tools at the same thread count on
  11,151,119 records: **`verify` 39.84 s vs 46.79 s** single-threaded
  (1.17×), **PGN export 79.26 s vs 118.47 s** single-threaded (**1.49×**) and
  **11.63 s vs 33.43 s** at ten threads (**2.87×**). The wins are deliberate —
  `play_fast` skips incremental Zobrist on the hot path, `Batch` reads move
  records in spans, and Rayon parallelises both. Memory is the one place the
  ancestor leads, and it is mapped pages rather than allocation: `info` costs
  2 MB, `peak_writer` reports 0 MB after all 11.1 M games, and `--no-mmap`
  holds the whole export in 28 MB for identical bytes. See
  [What is not supported yet](#what-is-not-supported-yet).
- **2CBH family: large-scale read support, strict parity in progress.** The
  `.2cbh` header, `.2cbg` move words, `.2cba` annotations, and `.2lid`
  entities decode through `gigachess`. The previous local ChessBase 18
  comparison covered 3,410,497 Mega Database 2026 games, with 99.895% matching
  under its non-strict token/heuristic exception comparator. This is **not**
  full byte-level gold parity or universal uncommon-annotation validation.
  A strict local oracle and fail-closed v2 interfaces are being hardened.
- **Read-only, permanently.** Nothing opens a source file for writing, nothing
  creates or deletes anything in a database's directory, and no extraction ever
  writes bytes the reader did not decode. Malformed input returns typed errors;
  it never panics.
- **Env-gated tests for real databases.** The reference numbers come from a
  licensed 11M-game database that is **not in this repository**. Tests that need it
  are gated and skip with a visible message.

## Status at a glance

| Area | State | Notes |
|---|---|---|
| `.cbh` records, `.cbj` wide index | **read** | zero-copy batches over the mapped file |
| `.cbg` move records, guiding texts | **read** | 16-bit `moves2` via `gigachess`; Chess960 and set-ups included |
| `.cba` annotations | **read** | comments, NAGs, graphics, medals, quotations, evaluations, elapsed time |
| `.cbe` entity strings, `.cbtt` text table | **read** | borrowed; no allocation per game |
| `.flags` metadata, `.cbp`/`.cbt`/`.cbc`/`.cbs` | **read** | namebases resolvable both ways (id→name, name→id) |
| `Database` façade, header listing, tag search | **read** | listing never opens the 1.25 GB moves file |
| Sink-based conversion, ordered parallel | **read** | `for_each_game`, `convert_parallel` |
| PGN export | **read** | sequential and parallel, byte-identical output |
| `.cbv` container | **read** | table parsed and validated for every member |
  | `.cbv` extraction, all four modes | **read** | 3,871 / 3,871 members, 100 % of bytes, byte-identical to the reference; 9.4× faster |
| `.cbz` | **read** | DES-ECB; three key rules (repeat / as-is / fold) verified against the reference's own samples |
| 2CBH container & moves | **read** | `.2cbh`, `.2cbg`, `.2cba`, `.2lid`; 16-bit `moves2` via `gigachess`; verified on 3.4M games |
| Boosters, derived accelerators | **not read** | tolerated and ignored, by design |
| crates.io release | **published** | v0.1.0; `cargo add cbvault` |

## Performance

Measured on an **Apple M1 Max (10 cores, 32 GB, macOS 27.0)**, `release` profile
(`lto = "fat"`, `codegen-units = 1`), against a **licensed 11,149,379-game
ChessBase database that is not part of this repository** (11,151,119 records; the
remainder are guiding texts and deleted records). **These numbers are not
reproducible from a clone** — they are reported so you can judge the design, and
the tests that gate them say so rather than reporting a false pass.

### Conversion (the sink walk)

`ns/ply` is per **main-line** ply; the set reports 869,502,060 main-line plies for
its 11,149,379 games (78.0 a game). Variations are walked and validated but not
retained, so they cost time and not memory.

| pass | wall | games/s | ns/ply | vs A | keys emitted |
|---|---|---|---|---|---|
| A — `moves` only (`play_fast`) | 44.72 s | 249,342 | 51.4 | — | 0 |
| B — indexed (`play_hashed`) | 46.87 s | 237,896 | 53.9 | +4.8 % | 880,651,439 |
| C — indexed, 1 worker | 46.90 s | 237,717 | 53.9 | +4.9 % | 880,651,439 |
| C — indexed, 2 workers | 26.22 s | 425,181 | 30.2 | −41.4 % | 880,651,439 |
| C — indexed, 10 workers | 11.50 s | 969,252 | 13.2 | −74.3 % | 880,651,439 |

Asking for position keys during conversion costs **4–8 % of a pass** — roughly 12×
cheaper than the ~47 s second pass over the source it replaces.

### Other flows

| measurement | one thread | ten threads |
|---|---|---|
| game list (headers + names) | 0.93 s, 12.0 M records/s | — |
| game list, cold page cache | 1.72 s | — |
| tag scan, `Elo >= 2000` | 1.36 s, 8.2 M records/s | 0.56 s, 20.1 M records/s |
| unindexed position replay | 43.78 s, **19.9 M plies/s** | 7.94 s, 109.6 M plies/s |
| `Database::open` | 0.00 s | — |

### Where the numbers do not meet their budgets

Two budgets are missed, and both are worth stating rather than burying:

- **The moves-only pass is 51.4 ns/ply against a 48.3 ns/ply budget — 6 % over.**
  The 48.3 measured the *decoder* alone; a conversion additionally resolves five
  entity ids per game, reads a 46-byte header record and hands over a `GameRef`.
  Over 869.5 M plies that is 2.7 s of the 44.7 s, which is what the tags cost.
- **The parallel conversion scales 4.1–4.4× on ten cores, against a 7× target.**
  That is memory bandwidth rather than the walk: the pass streams 1.25 GB of
  `.cbg` and 513 MB of `.cbh` through the memory map. Nothing in the walk is
  contended, and the single-threaded writer stage is not the limit.

A listing of 11.1 M games never opens the moves file — asserted two ways in the
test suite (by renaming `.cbg` away after open, and by doing the same for a tag
scan).

### PGN export

Whole-database export of the same set is **128.1–130.0 s single-threaded
(87,029 records/s)** and **19.7–20.6 s at ten threads**, byte for byte identical
output, against a **171.9 s (64,899 records/s)** pre-optimisation baseline. The
ancestor implementation this was ported from measured 141.5 s on the same machine.

## Installation

```toml
[dependencies]
cbvault = "0.1"
```

Or, to follow the repository rather than a published version:

```toml
[dependencies]
cbvault = { git = "https://github.com/itshak/cbvault" }
```

The `cbvault` crate pulls in `cbvault-format`, `cbvault-chess`, `gigachess` and
`rayon`. If you only want the byte-level readers — the classic `.cbh` family,
the 2CBH container, and the `.cbv`/`.cbz` containers — depend on
`cbvault-format` directly. To build the CLI:

```bash

The `cbvault` crate pulls in `cbvault-format`, `cbvault-chess`, `gigachess` and
`rayon`. If you only want the byte-level readers, depend on `cbvault-format`
directly. To build the CLI:

```bash
cargo install --git https://github.com/itshak/cbvault cbvault-cli   # the `cbvault` binary
```

Requires Rust 1.88+ (edition 2024). Memory mapping is on by default and is what
every number above was measured with; turn it off with:

```toml
[dependencies]
cbvault-format = { git = "https://github.com/itshak/cbvault", default-features = false }
```

Building without `mmap` still works; names are then reported with a typed error
rather than quietly copied.

## Usage

Every example below is compiled against the real API in this repository.

### Open a database and list its games

`Database::open` takes a base name **or** any member file, resolves its siblings
case-insensitively, checks the mandatory set, and reports which generation it
found. `headers()` walks the header records and **nothing else** — it never opens
the moves file, which is what keeps an eleven-million-game list inside two
seconds.

```rust
use cbvault::bridge::Database;

fn main() -> Result<(), Box<dyn std::error::Error>> {
    // A base name, or any member file: "Mega.cbh" and "Mega" both work.
    let db = Database::open("Mega Database 2025/Mega Database 2025")?;

    println!("{} generation, {} records", db.generation(), db.records());

    for entry in db.headers() {
        let entry = entry?; // a damaged record is an Err, not a panic
        println!(
            "{} {} - {}",
            entry.id,
            entry.white.as_str().unwrap_or("?"),
            entry.black.as_str().unwrap_or("?"),
        );
    }
    Ok(())
}
```

`Name::as_str()` returns `Option<&str>`: `Some` for every name the database
already stores as UTF-8, `None` for a name in another code page. To decode any
name, use `Name::decode_last` / `decode_first` with a reusable buffer.

### Convert a database through a sink

This is the main entry point. A sink says **once per run** what it needs, then
receives one fully borrowed `GameRef` per game in ascending order.

```rust
use cbvault::bridge::{self, Database, GameRef, GameSink};

/// The consumer's side: copy out of the borrow, keep nothing that points into it.
#[derive(Default)]
struct Row {
    id: u32,
    white: String,
    black: String,
    moves2: Vec<u16>,
}

#[derive(Default)]
struct Target {
    rows: Vec<Row>,
    failures: Vec<(u32, String)>,
}

impl GameSink for Target {
    fn game(&mut self, game: GameRef<'_>) {
        // `game.moves` is the MAIN LINE as 16-bit moves2. Variations are walked
        // and validated but not handed over.
        self.rows.push(Row {
            id: game.id,
            white: game.white.to_owned(),
            black: game.black.to_owned(),
            moves2: game.moves.to_vec(),
        });
    }

    // Ask for one Polyglot key per position of the main line, start first, so
    // `keys.len() == moves.len() + 1`. Costs 4-8 % of the pass and replaces a
    // second full pass over the source.
    fn wants_keys(&self) -> bool {
        true
    }

    // A damaged game never ends the walk and never panics. `bridge` re-exports
    // the error type, so this example needs no other crate.
    fn failed(&mut self, id: u32, error: &cbvault::bridge::Error) {
        self.failures.push((id, error.to_string()));
    }
}

fn main() -> Result<(), Box<dyn std::error::Error>> {
    let db = Database::open("Mega Database 2025/Mega Database 2025")?;
    let mut target = Target::default();

    // Sequential, on this thread:
    bridge::for_each_game(&db, &mut target)?;

    // Or across threads, in the SAME order, with the same payloads:
    let stats = bridge::convert_parallel(&db, &mut target, 8, bridge::DEFAULT_BATCH)?;

    println!("{} games, {} plies, {} failures", stats.games, stats.plies, stats.failures);
    Ok(())
}
```

`for_each_range(&db, first, last, &mut sink)` converts a slice of the id space, and
a `threads` value of 0 or 1 in `convert_parallel` falls back to the sequential
path.

**The sink contract, stated plainly:**

- `game()` is called from **one thread at a time**, in ascending game-number
  order, so a sink that owns a writer needs no lock.
- `GameRef` is **entirely borrowed**. A sink that keeps one past the call must
  copy what it wants. `moves` is the main line only.
- `keys` is empty unless `wants_keys()` returned `true`; when present,
  `keys.len() == moves.len() + 1` and the sequence equals what
  `gigachess::database::replay_moves2_hashes` returns for the same moves and
  start position.
- `start_fen` is `None` for the standard start, which is all but about 1,400
  games of the reference set and is therefore never rendered.
- `annotations` is `Some` only when `wants_annotations()` returned `true`;
  otherwise the `.cba` file is never opened at all.
- `failed()` receives the id and a typed error, and the walk continues.

`examples/convert.rs` in this repository is the full round trip: convert, read
back, and assert the tags, the `moves2` blob and every key sequence.

### Read one game

```rust
use cbvault::bridge::{Database, GameBuf};

fn main() -> Result<(), Box<dyn std::error::Error>> {
    let db = Database::open("Mega Database 2025/Mega Database 2025")?;

    let mut buf = GameBuf::new();
    buf.set_wants(true, true);           // keys and annotations
    let game = db.game_with(1, &mut buf, true)?;

    println!("{} plies, {} keys", game.moves.len(), game.keys.len());
    Ok(())
}
```

`GameRef` borrows both the database and the buffer, so it is valid only until the
next call with the same buffer. The moves it yields are the ones `for_each_game`
hands a sink for the same id, so a game view and a conversion cannot disagree.

### Tag search

A name resolves to **every** entity id it names, once; the scan then compares those
ids per record. `.cbp` is keyed by **last name**, so one key can have many records —
`find_players` is the right call for a search, and `find_player` (which returns one
id) is for a caller that only wants an answer.

```rust
use cbvault::bridge::{self, AllOf, Database, Filter, Range};

fn main() -> Result<(), Box<dyn std::error::Error>> {
    let db = Database::open("Mega Database 2025/Mega Database 2025")?;

    let ids = db.entities().find_players("Kasparov")?;

    // White is a Kasparov, rated at least 2800, played in or after 2010.
    // Every criterion narrows the others; an absent bound is open, not zero.
    let filter = AllOf::new()
        .and(bridge::any_player(&ids))
        .and(Filter::WhiteEloBetween(Range::at_least(2800)))
        .and(Filter::YearBetween(Range { from: Some(2010), to: None }))
        .filter();

    let found = bridge::scan(&db, &filter, 10)?;

    for m in found.matches() {
        println!("{} {} - {}", m.id, m.white.as_str().unwrap_or("?"), m.black.as_str().unwrap_or("?"));
    }
    println!("{:?}", found.stats());
    Ok(())
}
```

Also available: `WhiteEloBetween` / `BlackEloBetween` / `EloBetween`, `YearBetween`,
`Result`, `Round` and `Eco` — all comparisons of fields the 46-byte header already
holds, so none of them opens the moves file. `Filter::eco_text("B20")` parses the
text form a UI actually holds, and returns `None` for text that is not a code, so a
typo can be reported rather than becoming a predicate that matches nothing.

`GameRef::plies()` gives a game's exact ply count from the move stream the walk has
already read. Do **not** derive it from the header: `move_count()` is a `u8` capped
at 255 and counts *moves*, so `2 * move_count()` is wrong for any game with a set-up
start — silently.

The same predicate over the same range yields the same set at any thread count.
Note that ChessBase's tournament namebase is **not** a valid binary search tree,
so a descent that misses falls back to a verified scan of the 10 MB `.cbt`; a
name lookup happens once per query, never once per record.

### Export PGN

```rust
use std::path::Path;
use cbvault::pgn;

fn main() -> Result<(), Box<dyn std::error::Error>> {
    let stdout = std::io::stdout();
    let mut out = std::io::BufWriter::new(stdout.lock());

    // `threads` of 0 or 1 runs on the calling thread. The output is byte-for-byte
    // the sequential export's.
    let stats = pgn::export_parallel(Path::new("Mega Database 2025/Mega Database 2025"), &mut out, 8, 8192, 50)?;
    eprintln!("{} games, {} bytes, {} failures", stats.games, stats.bytes, stats.failures);
    Ok(())
}
```

`export_range`, `export_range_from` and `export_span` export a range; a `last` of
0 or below means "to the end".

### Read a `.cbv` archive

The container parses completely. Decoding is partial — see the caveat below.

This one example reads the container directly, so it needs the byte-level crate
rather than the façade:

```toml
[dependencies]
cbvault-format = { git = "https://github.com/itshak/cbvault" }
```

```rust
use cbvault_format::archive::Archive;

fn main() -> Result<(), Box<dyn std::error::Error>> {
    let archive = Archive::open("Mega Database 2025/Mega Database 2025.cbv")?;

    // The whole member table, validated against its own redundant copy, without
    // reading the 1.7 GB data pool.
    for member in archive.list() {
        let decodable = archive.can_decode(member)?;
        println!("{} ({} -> {} bytes) decodable: {}", member.name(), member.packed(), member.size(), decodable);
    }
    Ok(())
}
```

## CLI

The `cbvault` binary is a thin shell over the same library. All commands accept
`--json` for stable machine-readable output.

```text
usage:
  cbvault info   <db> [--games N] [--json]
  cbvault verify <db> [--threads N] [--batch-size N] [--limit-failures N] [--json]
  cbvault pgn    <db> [out] [--from ID] [--to ID] [--threads N] [--batch-size N] [--json]
  cbvault archive list <archive> [--password P] [--json]
  cbvault archive extract <archive> <dir> [--only NAME] [--threads N] [--password P] [--json]

## What is not supported yet

This is the section to read. Everything here is genuinely unfinished, with the
evidence for what was tried and why it did not work.

### `.cbv` and `.cbz`: the whole archive

A `.cbv` is a container of 3,871 named members — a database, its assets and its
thumbnails — each compressed independently. **All of it extracts**, and what comes
out is byte-for-byte what the reference implementation produces.

### The codec

A member's stream is a run of **blocks**, and each block names one of four
transforms:

| mode | transform | members (by first block) |
|---|---|---|
| `0x00` | **stored** — the payload verbatim | 2,228 |
| `0x01` | **LZ** — a 16-token-per-group token grammar | 68 |
| `0x02` | **Huffman** — a per-block 256-entry prefix code | 58 |
| `0x03` | **Huffman, then LZ** — holds every database file | 1,517 |

All four are decoded. The mode is a property of a **block**, not of a member, and
130 members mix them across their blocks — a reader that decides the mode once
per member is wrong on those.

Three details are load-bearing and each is easy to get wrong:

- the Huffman block's decoded length is **big-endian**, while every other length
  in the container is little-endian;
- a block's final symbol routinely ends in the **padding** of the last byte, so
  the exhaustion test is "past the end of the input", not "fewer than *n* bits
  left";
- the LZ back-reference window spans the **whole member**, not one block, and the
  copy is a unit copy — 34,300 back-references in the reference archive overlap
  their own destination.

The full field-by-field account is
[`docs/cbv-reference.md`](docs/cbv-reference.md), whose §10 states plainly what is
*not* established.

### Parity, measured against the reference process

| corpus | members | byte-identical | bytes compared |
|---|---|---|---|
| `twic1134.cbv` | 13 | **13 / 13** | 1,749,596 |
| reference archive | 3,871 | **3,871 / 3,871** | 3,607,876,417 (3.61 GB) |
| `small.cbz` — password `password` | 12 | **12 / 12** | 1,017 |
| `small2.cbz` — password `pass` | 12 | **12 / 12** | 1,017 |
| `small3.cbz` — password `my long password` | 12 | **12 / 12** | 1,017 |

Not a sample and not a spot check: every member of every corpus, compared against
the reference extractor's **own output**, and in the reverse direction too — files
it wrote that the member table does not name — because parity of the bytes is not
parity of the *set*.

### Performance, measured against both references

Both tables were produced on one 10-core Apple Silicon machine, from release
builds, doing **the same work on the same database** — verified by the ply counts
agreeing exactly.

#### `.cbh` verify, against `cbformat` — the like-for-like comparison

**Both tools at the same thread count**, on the 11,151,119-record database:

| threads | `cbtool` | `cbvault` | faster |
|---|---|---|---|
| 1 | 46.79 s | **39.84 s** | **cbvault 1.17×** |
| 2 | 23.91 s | **20.85 s** | **cbvault 1.15×** |
| 4 | 12.18 s | **10.42 s** | **cbvault 1.17×** |
| 8 | 6.47 s | **5.40 s** | **cbvault 1.20×** |
| 10 | 5.91 s | **4.93 s** | **cbvault 1.20×** |

**`cbvault` is faster at every thread count**, 1.15× to 1.20×, and the win grows
slightly with threads. The single-threaded figure matches this project's archived
budget of 1.24× on the machine it was originally recorded on
(`openspec/changes/archive/2026-09-28-maximum-single-thread-decode/NOTES.md`) —
it is what `play_fast` (skipping Zobrist on the hot path), batched span I/O and
Rayon were added to achieve, and it still holds.

An earlier table in this README put `cbtool` ahead at 8 and 10 threads. **That was
a measurement artefact, not a real regression**: those runs were made while
other benchmarks of mine were still running, and on an idle machine the same
command takes 4.93 s rather than 9.10 s. Every number above was taken with
nothing else on the machine.

> **An error this table corrects.** An earlier version of this README timed
> `cbtool verify` at 6.6 s against our 40.5 s and called the ancestor "6× faster".
> That was wrong: **`cbtool` defaults to one worker thread per CPU**, so an
> unqualified run silently used all ten, while ours was pinned to one. The
> archived baseline in `benchmarks/baseline.json` says so explicitly —
> `CBTOOL_THREADS=1` — and the README did not. **Matching output counts do not
> imply matching configuration.** Every row above pins `CBTOOL_THREADS` to the
> same value as our `--threads`.

#### `.cbv` unarchiving, against `uncbv`

The reference archive: 1.74 GB packed, 3.61 GB decoded, 3,871 members, all written
to disk.

| | time | peak RSS |
|---|---|---|
| `uncbv extract` | 67.68 s | 1,665 MB |
| `cbvault archive extract`, 1 thread | 16.45 s | 6,225 MB |
| `cbvault archive extract`, 2 threads | 8.18 s | 5,458 MB |
| `cbvault archive extract`, 4 threads | **7.18 s** | 6,363 MB |
| `cbvault archive extract`, 8 threads | 7.41 s | 6,505 MB |

**≈9.4× faster than `uncbv`** (67.68 s vs 7.18 s at 4 threads), at byte-identical
output (3,871 / 3,871 members). Past two threads the extraction is
memory-bandwidth-bound — four and eight threads tie — which is why the default
is four, not the core count. The peak RSS is transient decode buffers (a 1.25 GB
member decodes into a 1.25 GB buffer while its input is still held), not
retained state; `uncbv` is leaner (one member at a time) and 9× slower.

#### `.cbh` decoding, against `cbformat`

**An earlier version of this README compared the wrong two things.** It timed
`cbtool verify` against `cbvault verify` and reported the ancestor as 6× faster.
The ply counts matched, so it looked like a fair test — but reading the ancestor's
source shows it is not the same work:

```rust
// cbtool verify, crates/cbtool/src/main.rs
walk_tree(&moves, |_, _, _| {})   // <- empty callback: no move is ever played
```

`cbtool verify` **counts** plies; it does not replay them. Our
`MoveCounter::play` *is* invoked on every ply — that is how we detect en-passant
captures, promotion captures and null moves, which `cbtool` instead recovers by
**decoding the raw token bytes and pattern-matching them**:

```rust
for t in moves.tokens() {
    if let Token::Move(w) = t {
        match movetable::decode(w) { /* count en passant, promotion … */ }
    }
}
```

So the two `verify` commands are not identical jobs: `cbtool verify` is a
move-*record* check and `cbvault verify` is a move-*replay*. The table above is
still the fair comparison — both run their own full work at a matched thread
count — but it is worth knowing that ours does strictly more per ply.

#### Why the decoder stops scaling past about four workers

**It is neither the codec nor plain memory bandwidth — it is the shape of the
data.** Measured in three steps.

Decode-only, work handed out largest-first through one shared cursor:

| workers | seconds | MB/s | speedup | efficiency |
|---|---|---|---|---|
| 1 | 13.43 | 269 | 1.00x | 100 % |
| 2 | 6.88 | 525 | **1.95x** | **98 %** |
| 4 | 6.21 | 581 | 2.16x | 54 % |
| 8 | 6.16 | 585 | 2.18x | 27 % |
| 10 | 6.21 | 581 | 2.16x | 22 % |

Reading the pool out of the mapping scales to **55 GB/s**, so neither the disk nor
the file read is the limit.

**The cause is three enormous members.** Three of the archive's 3,871 members hold
**3.10 GB of its 3.61 GB**: the `.cbj` and `.cbg` at 1.25 GB each, and the `.cbh`
at 512 MB. Each is one indivisible unit of work, so the **longest single member
bounds the whole run** however many threads are added. Ten threads do not divide
a 1.25 GB member ten ways — they decode it once and then idle. That is exactly
what the efficiency column shows: the extra threads are not slower, they have run
out of work. A corpus of evenly sized members would keep scaling past four.

So `archive extract` defaults to **4 workers, not the core count**, and
`--threads` overrides it.

Releasing an oversized output buffer after each huge member, instead of carrying
1.25 GB for the rest of the run, recovered part of the loss past four workers:

| workers | before | after |
|---|---|---|
| 4 | 7.22 s | 7.07 s |
| 6 | 7.65 s | **6.99 s** |
| 8 | 7.63 s | **6.91 s** |
| 10 | 8.20 s | 7.14 s |

What buys the speedup in the first place: a two-level Huffman lookup table
(9-bit root, 6-bit secondary) instead of a bit-at-a-time walk, a 64-bit bit
buffer refilled eight bytes at a time, bulk literal copies, `memmove`
back-references, a zero-allocation hot path through one reusable `Scratch`, and
largest-member-first dynamic scheduling through a shared cursor.

### `.cbz` is fully supported

A `.cbz` is a `.cbv` whose every byte is enciphered with **DES in ECB**. There is
no plaintext header, no salt and no IV, which is what makes the container's own
header the password check.

The key is eight bytes, and the rule **depends on the password's length**:

| password length | key |
|---|---|
| exactly 8 | those eight bytes, unchanged |
| fewer than 8 | the password **repeated** until eight bytes are covered |
| more than 8 | **folded** — accumulator `i mod 8` is doubled, then XORed with byte `i` |

All three are verified against the reference's own three samples, one per rule,
and all three are now tests.

```console
$ cbvault archive list Mega.cbz --password 'my password'
$ cbvault archive extract Mega.cbz ./out --password 'my password'
```

A wrong password reports `wrong password`, not corruption — the file is not
corrupt, it is a well-formed container under a key the caller did not supply.
Checking costs **one eight-byte read**, so opening a 1.7 GB protected archive
never deciphers the file to find out; and because an ECB block depends only on
itself, each member is deciphered as it is read and extraction holds one member
at a time.

### How the codec was written, and how it is verified

`uncbv` is GPL-3.0, so it cannot be linked or vendored into an MIT library. The
obstacle was never the format — it was learning from a GPL implementation while
staying clear of its code. The codec was therefore written from the **published
format facts**: the container layout, the block framing and the two transforms,
stated as algorithms and constants rather than transcribed from any source.

Parity is then proved the only way a GPL project can be: by **running** it. The
reference is executed as a separate process and its output is compared byte for
byte with ours, in both directions — and on three `.cbz` samples too. Agreement
is required on every member of every corpus, so a partial match fails.

The specification the codec was written from, the review that gated it, and the
member-by-member result are in
[`docs/research/03-clean-room-audit.md`](docs/research/03-clean-room-audit.md).

`info` reports the record count and the namebase sizes. `verify` decodes and
replays every game, reporting typed failures. `pgn` writes PGN to `out` or to
stdout, so it pipes; **the export report always goes to stderr, so stdout stays
pure PGN**. `archive list` and `archive extract` read `.cbv` and `.cbz`
containers; `extract` never writes bytes it did not decode, and exits non-zero if
anything was skipped, so a partial extraction is never mistaken for a whole one.

```bash
cbvault info "Mega Database 2025/Mega Database 2025"
cbvault pgn "Mega Database 2025/Mega Database 2025" out.pgn --threads 8
cbvault archive list "Mega Database 2025/Mega Database 2025.cbv"
```


**PGN export on the full database.** Both tools at the same thread count, on
Mega Database 2025 (11,149,371 games, 883,141,297 plies, 9 named failures),
output to `/dev/null`, idle machine, measured 2026-10-01 back-to-back:

| threads | `cbtool` | `cbvault` | faster | `cbtool` RSS | `cbvault` RSS |
|---|---|---|---|---|---|
| 1 | 118.47 s | **79.26 s** | **cbvault 1.49×** | 72 MB | 1,770 MB |
| 2 | 69.71 s | **40.99 s** | **cbvault 1.70×** | 77 MB | 1,780 MB |
| 4 | 43.54 s | **21.34 s** | **cbvault 2.04×** | 83 MB | 1,794 MB |
| 8 | 31.94 s | **11.91 s** | **cbvault 2.68×** | 94 MB | 1,829 MB |
| 10 | 33.43 s | **11.63 s** | **cbvault 2.87×** | 98 MB | 1,850 MB |

**`cbvault` is faster at every thread count**, from 1.49× single-threaded to
2.87× at ten. Both spec budgets are met: the parallel one (**at most 25 s at 8+
threads, under 8 GiB**) at 11.91 s and 1,829 MB; the single-threaded one (**at
least 65,000 records/s**, i.e. at most 171.55 s) at 79.26 s, 2.2× inside it.

The same export with `--no-mmap --no-wide` (plain reads, no `.cbj`) holds
**28 MB at 1 thread (97.46 s)** and **101 MB at 8 threads (31.07 s)** — at the
ancestor's own memory level, still 3% faster than it at 8 threads. Output bytes
are identical in every mode.

This is the archived `pgn-export-sota-performance` work paying off: that change
recorded **171.9 s** single-threaded for exactly this database before the Rayon
pipeline and the zero-alloc formatting landed.

Two claims in earlier versions of this README were wrong, both from the same
mistake — **an unqualified `cbtool` run defaults to one thread per CPU**, so
every ancestor figure must be pinned with `CBTOOL_THREADS` to compare against a
`--threads` value:

- "the ancestor is 38.11 s, 2.5× faster than us" was a ten-core number against
  our one-thread run. Pinned, it is **118.47 s** and we are faster.
- "single-threaded PGN export is the one path where the ancestor leads" is also
  wrong: **we lead there too, by 1.49×**.

The export names its 9 failures (2 unreadable records, 7 un-writable games),
all rejected identically by `cbtool`; a game whose moves will not write is a
failure, never a counted game.


### Where we still trail the ancestor we ported from

`verify` is faster at 1, 2, 4, 8 and 10 threads (1.15×–1.20×) and PGN export is
faster at every thread count (1.49×–2.87×), so no path is slower any more. What
remains is **memory**, and it is a resident-set difference rather than a bug:

`cbvault` maps its database files, so a mapped page that has been read counts
towards RSS; the ancestor has **no mmap dependency at all** and `pread`s into
caller buffers, so its resident set stays at the size of those buffers. Measured
directly, on the same work:

| | peak RSS |
|---|---|
| `cbtool verify`, 1 thread | **13–14 MB** |
| `cbvault verify`, 1 thread | 1,520 MB |
| `cbtool info` / `cbvault info` | 2 MB / 2 MB |
| **`cat .cbg > /dev/null`** (reads all 1.25 GB, no mapping) | **1 MB** |

That last row is the important control: a process that reads the entire 1.25 GB
moves file shows **1 MB** of RSS, because file-backed pages of a read are the
**page cache**, not the process's memory, and they are evicted under pressure
rather than swapped. So our 1,520 MB is the same file-backed page cache —
evictable, shared between processes, and not ours to hold — while the ancestor's
14 MB is genuine, private, resident allocation.

**This is a real trade-off, and it costs us time as well as memory.** Mapping
should be faster than `pread`, and on this machine it is: 79.26 s against 97.46 s
single-threaded on the full export, a **1.23×** win. What the mapping does not
give us is a smaller *resident* footprint, because the kernel counts the pages
in whichever process touches them. A reader that wants a low RSS should `pread`
in windows — since `low-memory-footprint`, this reader does: `--no-mmap`
holds 28 MB single-threaded (101 MB at 8 threads) for identical bytes.

The `.cbj` is no longer mapped on bases below 4 GiB at all: its 1.33 GB of
offsets cannot add information where the 32-bit `.cbh` fields already hold
every address, so it is skipped (presence still reported) unless
`CBVAULT_WIDE=on` forces it. That is the whole of the drop from 3,044 MB to
1,770 MB in the table above; the old behaviour is one env var away for
measurement.

The one real allocation found on the export path was `Wide::offsets` reading 24
bytes per record through `DbFile::read`, which allocated a `Vec` — **11 million
times** on this database. It now reads into a stack buffer through the new
`DbFile::read_exact`, which is the same read without the allocation.


### 2CBH: read support validated on Mega Database 2026 only

- Native `.2cbh` headers, `.2cbg` moves, `.2cba` annotations and `.2lid`
  entities are handled by the generation-aware `Database::open` reader.
  Move legality, setups, synthetic Chess960, promotions and variations use
  `gigachess` only.
- The prior Mega Database 2026 / ChessBase 18 test checked **3,410,497 games**
  and reported zero decode/read failures, 97.135% comparator equality and
  99.895% after heuristic SAN exceptions. These were **not raw PGN byte
  equality** and did not prove lossless native-only annotation coverage.
- The active [strict 2CBH hardening change](openspec/changes/native-2cbh-release-hardening/proposal.md)
  requires explicit annotation errors, correct generation-aware sink/search
  APIs and a local executable golden comparison that must fail on every
  unapproved byte. **No private Mega golden rerun has yet been performed against
  the hardened implementation.**
- There is only **one available real v2 validation corpus**: Mega Database
  2026. Chess960 may be absent, and rare quotations, training annotations,
  multimedia and other native-only structures may be untested despite
  generated fixtures. These are explicit known coverage limitations.
- The prior 37,700 games/s is a local workload measurement; rebenchmark after
  the final fixes. Full-format support is not yet a verified release claim.

### Other gaps

- **No writers.** cbvault does not write target databases and defines no proprietary
  storage format: the sink is the whole contract. It does not write ChessBase data, ever.
- **No position index format.** It emits the keys; the consumer owns the index.
- **Boosters and derived accelerators are not read.** `.cbb`, `.cbgi`, `.cit`,
  `.cib`, `.cko` and `.cpo` are recognised and ignored by design; the reasons and
  the re-open criterion are in ADR-005 §4.
- **PGN is not parsed.** PGN is produced, not consumed, and the conversion path
  does not read PGN.
- **`Filter` has no "starts from a set-up position" predicate.** The bit is in the
  move record, and a tag search does not open the moves file. A consumer that needs
  it has the keys.
- **A game with variations costs one allocation each**, in the decoder's per-game
  variation stack. A database of games without variations allocates nothing per
  game. Fixing it needs a change in `cbvault-chess`.
- **No fuzzing has been done yet.**
- **The container layout is verified on one archive.** Whether the 173-byte
  member-table stride and the 128-byte name field hold for differently-built `.cbv`
  files is unverified. The reader *derives* the member count from the geometry
  rather than trusting a stated count, and rejects a table whose length is not a
  whole number of records.
- The `games` CLI command named in the binary's own module documentation **does not
  exist**; the four commands above are what is implemented.

## Testing

```bash
cargo test                                        # unit + integration suite
cargo test --workspace                            # the same, all crates
cargo clippy --all-targets -- -D warnings         # must be warning-free
cargo fmt --check
cargo bench --bench bridge                        # needs a real database
```

**The real-database tests are env-gated and skip visibly.** Tests that need a real
ChessBase database read `CBVAULT_TEST_DB` (and related variables) and, when it is
unset and the set is not present, print `SKIPPED: … This test did not run; it did
not pass.` The CI job runs with no database present, so those tests report as
skipped rather than green.

**No licensed database content is in this repository.** The database paths are
git-ignored, CI has no access to one, and nothing from one is committed. The
performance figures quoted above come from an 11.1 M-record set the maintainer
holds a licence for; the tests that consume it are gated on an environment
variable. If you own a ChessBase database you can point the variable at it and run
the full suite locally — that is your call and your licence, and this project will
never ask you to obtain one.

The public suite uses **fixtures generated by an in-repo, test-only builder**
(`cbvault-fixtures`, `publish = false`, never shipped) so the format round-trips
are exercised without any real data. Malformed-input tests assert typed errors
rather than panics. The PGN output is gated on **bytes** — a sequential/parallel
byte-equality test, and a gold comparison against a ChessBase export when one is
available (407,350 of 419,385 games match, 97.1 %).


## Architecture

Five crates, one direction of dependency, and one chess core:

| crate | what it is |
|---|---|
| `cbvault-format` | **Bytes.** Classic `.cbh`, 2CBH and the `.cbv`/`.cbz` containers: headers, records, namebases, codepages, containers. Knows no chess. |
| `cbvault-chess` | **Chess.** The only bridge between move tokens and `gigachess`: replay validation, `moves2` emission, Polyglot keys, the variation tree. |
| `cbvault` | **The façade.** `bridge` (`Database`, `GameSink`, `for_each_game`, `convert_parallel`, search), `pgn` (sequential and parallel writers) and `replay` (the verifier). |
| `cbvault-cli` | The `cbvault` binary: a thin shell over the façade. |
| `cbvault-fixtures` | Test-only builders of small ChessBase databases. `publish = false`; never shipped. |

The dependency edges run strictly downward, `cbvault-fixtures` is not a runtime
dependency of anything, and `gigachess` is the only implementation of chess rules
in the tree. The design decisions are written down as ADRs in
[`openspec/adr/`](openspec/adr/): zero-allocation hot paths, the measurement and
byte-level gates, the sink contract, and why tag search lives here while position
search is fed.

The full hand-off contract, with recipes and the measured numbers, is
[`docs/bridge.md`](docs/bridge.md).

## Documentation

| document | what is in it |
|---|---|
| [`SPEC.md`](SPEC.md) | our own statement of the on-disk facts, with one source note per fact and every unknown listed |
| [`docs/bridge.md`](docs/bridge.md) | the sink contract, read-only serving, search, measured numbers, known limits |
| [`docs/format-spec.md`](docs/format-spec.md) | the classic format field by field; §10 lists the five deliberate PGN deviations |
| [`docs/format-spec-cbv.md`](docs/format-spec-cbv.md) | the `.cbv` container, every fact with its evidence, and the negative results on the codec |
| [`docs/cbv-reference.md`](docs/cbv-reference.md) | the reader-facing reference for `.cbv`/`.cbz`: every field, all four block modes, and what is *not* established |
| [`docs/format-spec-uncbv.md`](docs/format-spec-uncbv.md) | the specification of the format's facts the codec was written from |
| [`docs/research/03-clean-room-audit.md`](docs/research/03-clean-room-audit.md) | the two-room barrier, the hygiene review, and the member-by-member parity result |
| [`docs/format-spec-2cbh.md`](docs/format-spec-2cbh.md) | the 2CBH format, with §10 stating what would close each unknown |
| [`docs/provenance.md`](docs/provenance.md) | per-module provenance: ported from `cbformat`, written from format facts, or original |
| [`THIRD_PARTY_NOTICES.md`](THIRD_PARTY_NOTICES.md) | attribution, dependencies, and the oracles used as tests only |
| [`AGENTS.md`](AGENTS.md) | the rules that must be followed before changing this tree |

## Provenance and licensing

**MIT, all of it.** See [LICENSE](LICENSE).

The on-disk format knowledge is a **port of `cbformat`** (MIT) from the
`oschess-cb-bridge` project, with attribution; ported files keep the upstream MIT
notices. Its internal chess layer was **replaced wholesale** by `gigachess`, so
there is no second chess implementation here. The `.cbv`/`.cbz` container and its
codec were written from the published format facts alone, and every claim is
verified against a reference implementation run as a **separate process** —
`uncbv` (GPL-3.0) is used only as a test oracle, never linked, vendored or
copied. See [`docs/research/03-clean-room-audit.md`](docs/research/03-clean-room-audit.md).

- **Facts-only references** (no code or text reused): Yarin's (Jimmy Mårdell's)
  `morphy` specifications, unlicensed — format facts only; and ChessBase's public
  help pages.
- **Test oracles only, never linked or copied**: `scidb` (GPL-2.0), `libcbh`
  (GPL-2.0), `uncbv` (GPL-3.0), `Source2Metal` (GPL-3.0), `cbh2pgn` (MIT),
  `FelixKling/cbh2pgn` (AGPL-3.0, avoided entirely).
- **No GPL code is linked, copied or distributed.** A CI job fails the build if a
  second chess implementation appears in the tree.

## Acknowledgements

The format work builds on two decades of community reverse engineering — in
particular **Yarin (Jimmy Mårdell)**, whose 2009 specification and modern `morphy`
documentation made every open CBH reader possible, and the **`oschess-cb-bridge`
authors**, whose MIT implementation is the direct ancestor of this port.

## Contributing

Contributions are welcome. Please read [CONTRIBUTING.md](CONTRIBUTING.md) — the
licensing rules and the zero-allocation hot-path rules are not negotiable — and
[CODE_OF_CONDUCT.md](CODE_OF_CONDUCT.md) before opening a pull request.

## License

MIT — see [LICENSE](LICENSE). ChessBase formats are the input to this library;
cbvault is an independent, MIT-licensed implementation and is not affiliated with,
endorsed by or connected to ChessBase. The `.cbh` readers are ported from
`cbformat` (MIT, `oschess-cb-bridge`) with attribution; the `.cbv`/`.cbz` codec
was written from published format facts. All table data is either generated at
runtime with fixed seeds or taken from public format specifications.

  are gated and skip with a visible message.
