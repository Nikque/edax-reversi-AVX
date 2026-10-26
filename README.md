# Edax 4.5.5 nikque

A maintained fork of [Edax 4.5.5 (okuhara/edax-reversi-AVX)](https://github.com/okuhara/edax-reversi-AVX), the Othello engine. It fixes bugs in book learning and book handling, adds book analysis and maintenance commands, and makes book learning faster on many-core PCs. Books made with upstream Edax 4.5.5 can be used as they are.

[日本語](#日本語) · [Download](https://github.com/Nikque/edax-reversi-AVX/releases/latest) · [Manual](manual/en/README.md) · [Release notes](RELEASE-NOTES.md) · [Tests and measurements](docs/validation/)

## Download and run

1. Download the ZIP from the [latest release](https://github.com/Nikque/edax-reversi-AVX/releases/latest) and unpack it.
2. Open the `bin` folder and start the executable for your system from **inside that folder** (Edax looks for `data/eval.dat` in the current folder).

| System | Executable in `bin/` |
|---|---|
| Windows x64 | `wEdax-x86-64.exe` (any CPU), `-v3` (AVX2), `-v4` (AVX-512) |
| Windows x86 / ARM64 | `wEdax-x86.exe`, `wEdax-x86-sse.exe` / `wEdax-arm64.exe` |
| Linux x64 / x86 | `lEdax-x86-64` (any CPU), `-v3`, `-v4` / `lEdax-x86` |
| macOS | `mEdax-arm64` (Apple silicon), `mEdax-x64-modern` (Intel) |
| Android | `aEdax-arm64-v8a`, `aEdax-armeabi-v7a` |

If you are not sure which CPU features you have, use the version without `-v3`/`-v4`. The ZIP also contains the libedax libraries (`.dll`, `.so`, `.dylib`) for GUIs and tools such as [nikque GUI](https://github.com/Nikque/nikque-gui) and [edax_runner](https://github.com/Nikque/edax_runner).

Getting started: [Manual, chapter 2](manual/en/02-quick-start.md).

## Versions

There are three lines. They share the same commands, settings and book format.

| Line | What it is | Where |
|---|---|---|
| **v4.5.5-nikque.N** | The main line: bug fixes and new book commands, with the upstream evaluation (`eval.dat`) | Branch `edax-4.5.5-fixes` (default). Latest release |
| **v4.5.5-eval2.N** | nikque + a new evaluation function (adds mobility; about +17 to +22 Elo against upstream `eval.dat`). Scores differ from the nikque line | Branch `eval2`, releases `v4.5.5-eval2.N` |
| **newedax** | The eval2 line ported to C++23, same results | [Nikque/newedax](https://github.com/Nikque/newedax) |

Each eval2 and newedax release includes all changes of the nikque release it names (for example, eval2.10 = nikque.22 + eval2).

## Main changes from upstream

- **Book learning fixed**: `book deviate` could crash or lose positions (a dangling pointer); `book merge`, `book fix` and book saving were made safe (temporary file, damaged records rejected).
- **New learning commands**: `book deviate2` / `book deviate3` (limits on loss per move and in total).
- **Faster learning on many cores**: several book positions are expanded at the same time (`book-expand-tasks`, `book-store-tasks`); with 32 threads at level 18, up to about 4.7 times faster.
- **Less memory**: about 50 bytes per book position (58 before).
- **Book analysis and maintenance**: `book moveinfo`, `book missing`, `book bestlines`, `book reduce` and others (used by nikque GUI).
- **17 other fixes** in file I/O, time control, PGN/GGF and protocols (XBoard, GTP, NBoard).

The complete list is in the [release notes](RELEASE-NOTES.md).

## Build

- **Windows** (Visual Studio 2022, Developer Command Prompt): in `src`, run `nmake -f NMakefile vc-x64-v4` (other targets are in `src/NMakefile`; `build-win-v4.cmd` builds the v4 executable). The release executables use the PGO targets (`vc-pgo-x64-v4`, `vc-pgo-x64-v3`, `vc-pgo-x64`, and `vc-pgo-x86-sse`, `vc-pgo-x86` from an x86 prompt), except ARM64.
- **Libraries**: Windows `nmake -f NMakefile vc-lib-x64` (`-v3`, `-v4`); Linux and others `make libbuild ARCH=<x86-64|x86-64-v3|x86-64-v4> COMP=gcc OS=linux`. See [manual 12.2](manual/en/12-integration.md).
- **Other platforms**: the [release-binaries workflow](.github/workflows/release-binaries.yaml) builds Linux, macOS and Android; `package-release.py` assembles the ZIP.
- The 32-bit Linux build (`lEdax-x86`) needs an i486 or later CPU. The upstream 32-bit macOS `mEdax-x86` is not included: current Xcode SDKs cannot link a corrected i386 binary.

## License

GPL-3.0 ([LICENSE](LICENSE)), as upstream. `bin/data/eval.dat` and `bin/data/book.dat` are taken unchanged from the upstream v4.5.5 release. If you redistribute the executables, keep the source and the license available.

This fork was developed with ChatGPT-6 Astra / Sol and Claude Opus 5.5.

---

## 日本語

オセロのエンジン [Edax 4.5.5（okuhara/edax-reversi-AVX）](https://github.com/okuhara/edax-reversi-AVX) の修正版です。book の学習と扱いの不具合を直し、book の解析・整理のコマンドを足し、多コアの PC で book の学習を速くしました。元の Edax 4.5.5 で作った book をそのまま使えます。

[ダウンロード](https://github.com/Nikque/edax-reversi-AVX/releases/latest) · [マニュアル](manual/ja/README.md) · [修正一覧](RELEASE-NOTES.ja.md) · [テストと実測の記録](docs/validation/)

### 使い始め方

1. [最新の Release](https://github.com/Nikque/edax-reversi-AVX/releases/latest) の ZIP をダウンロードして展開します。
2. `bin` フォルダーを開き、**そのフォルダーの中から**実行ファイルを起動します（Edax は今いるフォルダーの `data/eval.dat` を読みます）。

Windows なら、まず `wEdax-x86-64.exe` を使ってください。AVX2 対応の CPU なら `-v3`、AVX-512 対応なら `-v4` が速くなります。ほかの OS の実行ファイルは上の英語の表のとおりです。

詳しくは [マニュアル 2 章「起動と最初の対局」](manual/ja/02-quick-start.md) を見てください。

### 3 つの系列

コマンド・設定・book の形式は 3 つとも同じです。

| 系列 | 内容 | 置き場所 |
|---|---|---|
| **v4.5.5-nikque.N** | 本線。不具合の修正と book のコマンドの追加。評価関数（`eval.dat`）は元のまま | ブランチ `edax-4.5.5-fixes`（既定）、最新の Release |
| **v4.5.5-eval2.N** | nikque に新しい評価関数を足したもの（着手可能数を追加。元の `eval.dat` に対して約 +17〜22 Elo）。評価値は nikque と異なる | ブランチ `eval2` |
| **newedax** | eval2 を C++23 に移したもの。結果は同じ | [Nikque/newedax](https://github.com/Nikque/newedax) |

eval2・newedax の各版は、対応する nikque の版の変更をすべて含みます（例：eval2.10 = nikque.22 + eval2）。

### 元の Edax からの主な変更

- **book の学習の不具合を修正**：`book deviate` が解放済みのメモリを読み、学習が止まったり局面が抜けたりすることがありました。`book merge`・`book fix`・book の保存も安全にしました（一時ファイル経由、壊れたレコードを拒否）。
- **学習のコマンドを追加**：`book deviate2`・`book deviate3`（1 手ごと・合計の損失で範囲を指定）。
- **多コアでの学習を高速化**：複数の局面を同時に展開します（`book-expand-tasks`、`book-store-tasks`）。32 スレッド・level 18 で最大約 4.7 倍。
- **メモリの削減**：book の 1 局面あたり約 50 バイト（以前は約 58 バイト）。
- **book の解析と整理**：`book moveinfo`・`book missing`・`book bestlines`・`book reduce` など（nikque GUI が使います）。
- **そのほか 17 件の修正**：ファイルの入出力、持ち時間、PGN・GGF、通信（XBoard・GTP・NBoard）。

すべての変更は [修正一覧](RELEASE-NOTES.ja.md) にあります。

### ライセンス

元と同じ GPL-3.0（[LICENSE](LICENSE)）です。`bin/data/eval.dat` と `bin/data/book.dat` は元の v4.5.5 の配布物から変えずに取り出したものです。実行ファイルを再配布するときは、ソースとライセンスを入手できるようにしてください。

この fork の作業には ChatGPT-6 Astra・Sol と Claude Opus 5.5 を使いました。

---

## Upstream README (okuhara/edax-reversi-AVX)

The text below is the original README of the upstream project, kept unchanged.

Automatically exported from code.google.com/p/okuharaandroid-edax-reversi

Edax is a strong othello program. Its main features are:

    fast bitboard based & multithreaded engine.
    accurate midgame-evaluation function.
    opening book learning capability.
    text based rich interface.
    multi-protocol support to connect to graphical interfaces or play on Internet (GGS).
    multi-OS support to run under MS-Windows, Linux and Mac OS X.

This is SSE/AVX optimized version of Edax 4.4.0. Functionally equivalent to the parent project, provided no bugs are introduced.

Thanks to AVX2, x64-modern build solves fforum-40-59.obf 60% faster than official edax-4.4 on Haswell, and runs level 30 autoplay 80% faster.

See http://www.amy.hi-ho.ne.jp/okuhara/bitboard.htm and http://www.amy.hi-ho.ne.jp/okuhara/edaxopt.htm for optimization details in Japanese.

## 1. Mobility (board_sse.c, board_mmx.c)

### 1.1 new SSE2 version of get_moves
Diagonals are SIMD'd using vertical mirroring by bswap.

    Athlon -get_moves_sse
    problem\fforum-20-39.obf: 111349635 nodes in 0:07.998 (13922185 nodes/s).
    mobility: 81.10 < 81.28 +/- 0.17 < 82.03
    Athlon +get_moves_sse
    problem\fforum-20-39.obf: 111349635 nodes in 0:07.889 (14114544 nodes/s).
    mobility: 71.08 < 71.72 +/- 0.34 < 73.53
    Core2 -get_moves_sse
    problem/fforum-20-39.obf: 111349635 nodes in 0:10.180 (10938078 nodes/s).
    mobility: 78.06 < 78.18 +/- 0.08 < 78.41
    Core2 +get_moves_sse
    problem/fforum-20-39.obf: 111349635 nodes in 0:09.978 (11159514 nodes/s).
    mobility: 60.84 < 61.19 +/- 0.13 < 61.47

### 1.2 can_move
Now calls SIMD'd get_moves for x86/x64 build.

## 2. Stability (board.c, board_sse.c, board_mmx.c)

### 2.1 get_full_lines_h, get_full_lines_v
get_full_lines for horizontal and vertical are simplified. The latter is compiled into rotation instrunction.

### 2.2 rearranged loop
The last while loop is rearranged not to call bit_count in case stable == 0.

### 2.3 new SSE2 version with bswap and pcmpeqb
    Athlon -get_stability_sse
    stability: 90.10 < 90.28 +/- 0.24 < 91.20
    Athlon +get_stability_sse
    stability: 81.59 < 81.93 +/- 0.73 < 86.25
    Core2 -get_stability_sse
    stability: 79.24 < 79.39 +/- 0.15 < 79.93
    Core2 +get_stability_sse
    stability: 71.80 < 71.85 +/- 0.06 < 72.07

### 2.4 get_corner_stability
Kindergarten version eliminates bit_count call.

### 2.5 find_edge_stable
Loop optimization and flip using carry propagation. One time execution but affect total solving time.

## 3. eval.c (4.4.5)
Eval feature calculation using SSE2 / AVX2 (now in eval_sse.c) improves midgame by 15-30% and endgame by 8-12%.
Restoring eval from backup instead of rewinding.
eval_open (one time execution) is also optimized.

## 4. hash.c
I think hash->data.move[0] on line 677 should be hash->data.move[1].

## 5. board_symetry, board_unique (board.c, board_sse.c)
SSE optimization and mirroring reduction. (Not used in solving game)

## 6. endgame_sse.c (4.4.7)
Keep more variables in SSE registers.  SSE optimized count_last_flip.  Parity sort by shuffle.

## 7. board_get_hash_code (4.5.0)
Changed to use CRC32c.  This enables hardware acceleration on modern build.

## 8. AVX2 versions (x64-modern build only)
In many cases AVX2 version is simplest, thanks to variable shift instructions (although they are 3 micro-op instructions).

Benchmarks are on Core i5-4260U (Haswell) 1.4GHz (TB 2.7GHz) single thread.

    4.4.0 original x64-modern clang
    problem/fforum-20-39.obf: 111349635 nodes in 0:05.726 (19446321 nodes/s).
    +optimizations 1-5 above, no-avx2
    problem/fforum-20-39.obf: 111349635 nodes in 0:05.342 (20844185 nodes/s).
    +get_moves (board_sse.c)
    problem/fforum-20-39.obf: 111349635 nodes in 0:05.142 (21654927 nodes/s).
    +flip_avx.c
    problem/fforum-20-39.obf: 111349635 nodes in 0:04.946 (22513068 nodes/s).
    +count_last_flip_sse.c
    problem/fforum-20-39.obf: 111349635 nodes in 0:04.906 (22696624 nodes/s).

## 9. makefile
gcc-old, x86 build should be -m32, not -m64. Some flags and defines added for optimization.
