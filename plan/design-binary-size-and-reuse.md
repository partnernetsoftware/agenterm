# agenterm.exe 体积归因与抽象/复用路线

> 2026-08-09。起因:dist 里 agenterm.exe 15MB、target/debug 35MB,怀疑有大量抽象与复用空间。
> 本文用实测回答"15MB 是什么构成的",并给出按收益排序的复用路线。

## 0. 结论先行

1. **dist 的 15MB 不是发布体积**:`dist/agenterm.json` 写明 `"profile": "dev"`——本地
   `stage-build dev` 暂存的是 debug 产物。体积预算门(`artifact-verification.rh`)只在
   release 通道生效,所以这个数字从未被合同约束过。
2. **发布形态的主要质量不在"重复抽象",在"引擎搭载策略"**:自有代码只占 .text 的 1/4;
   四个静态链入的脚本引擎(rhai/LuaJIT/QuickJS/sqlparser)合计约占一半。
3. **最大单项是尚无执行能力的 sql 脚手架**(sqlparser,.text 的 22%)。把它移出产品 PE
   是收益最大、风险最小的一刀。
4. **合同已经被击穿,只是引信未点**:当前 HEAD 的真 release 构建(opt-z + thin LTO +
   cu=1 + strip)实测 7,516,672 字节 = **7.17MiB**,超出 4MiB 预算 79%。预算门只在
   release 通道执行,本地 dev 链永远不会触发——第一次走 release 通道就会
   `artifact_release_budget` 失败。引擎门控因此不是优化,是履约。
5. 现有运行时抽象是健康的:`ScriptEngineBackend` trait 四后端各就各位,平台层
   (agenterm-platform)按 windows-sys 直调,GUI 栈只有 ~3%。缺的是**编译期门控**
   (root crate 没有任何 `[features]`),不是缺 trait。

## 1. 测量方法与数据

`cargo bloat --profile release-fast --crates --bin agenterm`(strip=none 以保留符号;
独立 CARGO_TARGET_DIR 冷构建,2026-08-09)。release-fast 无 LTO、cu=16、增量开启,
绝对值偏大,**占比**才是结论载体。.text 共 7.0MiB:

| 贡献者 | .text | 占比 | 备注 |
|---|---:|---:|---|
| agenterm(src/ 自有代码) | 1.7MiB | 25% | |
| sqlparser | 1.5MiB | 22% | `agenterm sql` 脚手架;eval 尚 fail-closed |
| rhai + agenterm_rh | ~1.2MiB | 17% | 任务系统承重,不可拆 |
| LuaJIT + QuickJS(C 静态库,含 762KiB 无名行)+ mlua/rquickjs 胶水 | ~1.1MiB | 15% | |
| std | 526KiB | 7% | |
| GUI 栈(winit/softbuffer/ttf_parser/ab_glyph/png) | ~220KiB | 3% | 出乎意料地薄 |
| 其余(serde_json 34KiB、vt100 12KiB 等长尾) | ~0.7MiB | 10% | 无单项 >50KiB |

参照物:
- **真 release 实测**(独立 target 冷构建,同日):agenterm.exe = 7,516,672 字节 =
  7.17MiB。这是当前 HEAD 的可分发形态。
- 体积预算合同:PRD_02_19 G3 已升格——GUI 4MiB、sidecar 2MiB,`scripts/artifacts.json`
  的 `release_budget_bytes` + `artifact-verification.rh`(仅 release 通道)强制。
  7.17MiB 对 4MiB:即便 P1+P2 全部落地(约 −2.5MiB .text 量级),也只是逼近而未必
  跌回预算内——预算数字本身是否要随"单 PE 多引擎"的产品决定重议,需要一次明确裁决。
- 引擎并入前的 release agenterm.exe 约 1.0MiB(2026-08-04 存档产物),可视为
  "产品本体 + GUI 栈"在 opt-z + thin LTO 下的历史基线。
- debug 30MB+ 属正常(debug=1 行号表 + 未优化),与复用无关,不必优化。

## 2. 按收益排序的路线

### P1 把 sql 脚手架移出产品 PE(−22%,低风险)
`agenterm sql` 目前 check 真实、execute fail-closed,产品价值为零,但 sqlparser 是
最大单项。做法二选一:
- root `[features] engine-sql`(默认关),`src/bin/agenterm.rs` 的 `"sql"` 分支与
  `SqlEngineBackend` 挂 `#[cfg(feature = "engine-sql")]`;
- 或干脆只保留 `agenterm-sql` sidecar bin,产品 PE 不再链接。
执行能力落地那天再默认打开,符合"脚手架不进产品"的一致口径。
可行性注:`SqlEngineBackend::enabled()` 的**运行时门已存在且默认关**(须
`AGENTERM_SCRIPT_BACKEND=sql` 显式启用)——P1 只是把既有语义上移到编译期,默认行为
不变。改动面:root Cargo.toml(optional dep + feature + bin required-features)、
src/bin/agenterm.rs 的 sql 分支、script_engine.rs / script_backend.rs / script_worker.rs
的 Sql 变体,及 3 个 parity 测试。这些文件当前有并行 lane 的未提交改动,实现宜在其
落地后进行,避免冲突。

### P2 引擎门控成为一等机制(策略对齐 roadmap)
路线图(archive/plan-v0.1.16.md §1)本来就是分平台的:rh(Linux 主力)、lua(Windows)、
qjs(等 lua 原型验证)。但 root crate 无 feature 门,四引擎无条件全量链入所有平台。
建议:`engine-lua` / `engine-qjs` / `engine-sql` 三个 feature(rh 承重不设门),
`ScriptEngineBackend` 注册表按 feature 组装。这使"哪个平台带哪个引擎"从文档约定
变成构建事实,也让 4MiB 预算在引擎继续增多时仍可能守住。

### P3 依赖卫生:引擎 crate 一律经 script-common 取哈希/扫描
实测重复:sha2 0.10(lua/qjs 声明)与 0.11(root/rh)双链并存,连带 digest /
block-buffer / crypto-common / cpufeatures 各双份;另有 bitflags 1/2(png 旧链)、
getrandom 0.2/0.4。单项都小(合计 ~100–300KiB),但方向应统一:
**引擎 crate 不直接依赖 sha2/walkdir,统一走 agenterm-script-common 的
`hex::sha256_hex` / `corpus_scan`**。
- 已落地:agenterm-qjs 的 sha2/walkdir 直接依赖实为未使用,已删除;tempfile 降为
  dev-dependency(本文同一提交)。
- 待各自 lane 处理:agenterm-lua 同样声明了 sha2 0.10,使用面待查;script-common
  自身升 sha2 0.11 后 0.10 链即可整条消失。

### P4 dist 语义:让"看到的体积"就是"承诺的体积"
本地 `stage-build dev` 把 debug 产物放进 dist,是这次 15MB 误会的来源。dist 清单
已如实记录 profile,不算错;但若希望 dist 恒代表可分发形态,本地默认链改
release-fast 即可(代价是本地迭代变慢,需权衡,不急)。

### P5 自有代码 1.7MiB 的复用长线
src/ 里最大的源文件:`platform/adapters/windows/remote_frontend.rs`(378KB)、
`platform/adapters/unix/frontend/mod.rs`(276KB)+ `render.rs`(132KB)、
`client/mod.rs`(157KB)。Win/Unix 两套 adapter 的渲染/快照逻辑存在多少可下沉到共享
frontend core 的重复,值得单独一轮 platform-ux-parity 视角的审计——这是"抽象与复用"
真正的长期标的,收益不止体积(平价缺陷会同源消失)。

## 3. 边界与不做的事

- rhai 不拆:rh 是任务系统与构建管线的承重墙。
- 不引入 wrapper/.com/动态库拆分来"作弊"减重:与单 PE 设计决定冲突。
- debug 产物体积不做目标。
- (2026-08-09 预算裁决)GUI 体积预算已由 4MiB 上调至 10MiB——体积不再是驱动;
  本文档自此以"持续的抽象与复用"为主目标,体积数据保留作事实基线。

## 4. 复用工作日志与队列(滚动更新)

### 已落地
- 2026-08-09 `03412921`:agenterm-qjs 未使用的 sha2/walkdir 直接依赖删除;tempfile
  降为 dev-dep(P3 第一刀)。
- 2026-08-09 `5e2936d8`:qjs/sql 的 check-many / corpus-scan **整命令体**下沉到
  script-common(继 parse_check_many_cli 下沉后的上一层)。两引擎各留 3–8 行适配,
  输出与退出码逐字节不变;crate 测试 common 47 / qjs 93 / sql 19 全绿。
- 同日并行 lane 的 `82019aa9` 开始退役独立引擎 exe——与本文档 P1/P2 的
  "引擎搭载策略收敛到主 PE + 编译期门控"同向,后续按其波次推进后再评估 feature 门。
- 2026-08-09(下半日,frontend 路线):`8e0766ba` 快照键集护栏;`6836dbca`
  ServerContextMenuRects 命名字段(消元组反转);`246e9c4f` F7 关闭
  (ControlWindow::control_selection + 共享 UTF-16→字符换算);`63ad5498`
  SidebarViewport(滚动模型半区,行命中半区留队列)。
- 2026-08-09(rh 语言/工具链):`027f8dd8` stderr_inherit 三层落地(build 实时输出);
  `867dbab1` prune 双修(PathBuf::from 变量克隆 + Windows POSIX 锁探测诚实跳过,
  build.bat dev 本机首次全绿);`457457bc` JSON 标量串化对齐解释器(语言层关闭
  `0 +` 强转 bug 类);`a088b99f` json==json 真 Value 等值(null 安全);后续一刀
  null→"" 判空成语对齐。CI 修复弧:`c3863f5c` nativecore 跨平台 fail-closed、
  `557b3f37`/`14592129` clippy 门、`3bbb05a7` 灰度全量处置、`64a05e6a` 门 deadline
  容纳冷 AOT 编译。

### 队列(按价值排序)
1. **P5 frontend 三面重复测绘**:已完成 → `plan/design-frontend-shared-core.md`。
   66 个同名函数横跨两 controller;五大提取候选(快照装配 ~600 行、选区生命周期
   ~450 行、modal 几何 ~500 行且已实际漂移、sidebar 命中 ~300 行、滚动条+指针合成
   ~450 行),另有 4 个可独立修的具体缺陷。下一步:先补"快照键集对等"护栏测试。
2. corpus-scan 契约测试 ×3(lua/qjs/sql 各 ~50 行结构相同)→ script-common
   test-support;顺带把"契约"从复制粘贴变成单点定义。
3. lua 的 corpus-scan/check-many 是否向共享命令体对齐:其"`--dir` 悬空回退 CWD"
   与人类输出格式为真实分叉,由 parity 测试钉住——对齐是产品决定,归 script lane。
4. sha2 0.10→0.11 统一(script-common 升版后 0.10 整链消失),连带 lua 的直接依赖
   使用面核查。

### 显式拒绝(记录以免反复)
- `read_source` 7 行 ×2(qjs/sql):不下沉。两份五行函数配各自文档注释的清晰度
  高于一个带错误映射参数的共享函数;不是所有重复都值得一个抽象。

## 5. 体积追踪与死代码灰度归档(2026-08-09 起)

### 5.1 体积追踪设施
- **逐产物历史**:stage-build 每次运行向 `dist/size-history.jsonl` 追加一行
  (commit、profile、各产物字节)。本地未跟踪文件——每台机器一条趋势线,
  避免共享 checkout 的追加冲突。
- **逐 crate 归因**:`scripts/rh/size-attribution.rh`(rh run 直跑)在专用
  `target/size-report` 目录用 cargo-bloat(--message-format json)产出
  `dist/size-attribution.json` 并打印 top-N 表。依赖 `cargo install cargo-bloat`,
  未安装时给出明确提示而非静默跳过。脚本接受 con 专属的
  `con-release-fast` / `con-release` profile，并为 `agenterm-con` 显式选择
  workspace package；con 的 strip=none 归因样本使用 host std，官方 staging
  另走 custom-std，因此 crate 排名用于选刀，样本文件大小不作为发布证据。
- 注意:dist 里 dev 与 release-fast 产物会被不同 lane 轮流暂存,**对比体积必须
  先对齐 profile**(size-history 每行都带 profile 字段,别跨行直接比)。

2026-08-12 的 con-release-fast 首个可归因样本给出 `.text` 排名：`std`
160,329 B、`agenterm_con` 140,160 B、`agenterm_platform` 98,046 B、`vt100`
16,901 B、`agenterm_ui_core` 4,178 B。最大单函数是 control dispatch 20,994 B，
其次是主事件分派 15,693 B；CLI run/parse 合计 12,643 B。正式 strip+custom-std
x64 PE 同期仍为 619,520 B（`.text` 404,348 B），不得把归因样本的 434,200 B
汇总值与正式节区直接相减。该证据否决继续优先微调像素 ISA，下一轮先审计
control/CLI 的重复状态机和错误格式化。

同日三项最终 PE 淘汰实验不得重复凭源码直觉重做：把 `SendMouse` 与
`SendWheel` 的 target/cell 校验抽成具体函数只令 `.text -32 B`、`.rdata
+16 B`，619 KiB 对齐后的文件不变；以 21 字节栈缓冲替换七种 JSON 整数
`ToString` 时 `.text` 不变、`.rdata +88 B`、`.reloc +12 B`；给 Win32
`window_proc_inner` 加 `inline(never)` 后所有节区完全不变，证明 LLVM 原本
就未内联它，bloat 把 6,946 B 记到 unwind thunk 只是归因边界。三者均已
回退。只有能删除仍未被其它调用保留的运行时族、或跨过最终文件对齐边界
的候选才进入实现。

随后把 list/new/select/close 的六处稳定 `@TAB_ID` JSON 表示集中到一个
非泛型、非内联的 `Option<TabId> -> JsonValue` 边界。`map_or` 版本净减 384
节区字节但文件不变；改为显式 `match` 后 `.text -576 B`、`.rdata -8 B`、
`.pdata -12 B`，release-fast PE 从 616,448 降至 615,936 B。继续把 helper
下沉为手写栈十进制却使 PE 增长 512 B，故回到集中 `format!`。结论是先消除
重复所有权/closure 状态机，再让已链接的标准格式化完成叶子工作；“更接近
汇编”不是独立收益指标。

x86 feature detection 也完成了全链实验后回退：UI-core 与 platform 的 8 处
生产 `is_x86_feature_detected!` 曾全部替换为 CPUID/XGETBV（含 XSAVE、
OSXSAVE、AVX、XCR0[1:2]、AVX2、SSSE3、FMA 条件），test-only oracle 与
Rust 标准检测逐位一致。但带符号 con 图中的
`std_detect::detect::cache::detect_and_initialize` 仍完整保留 1,688 B，说明
另一个标准/第三方依赖仍拥有该运行时；新增两份 raw detector 使正式 PE
增长 512 B、有效节区增长 83 B。实现已回退。只有先证明依赖图最后一个
std_detect owner 可删除，才重开 CPUID/汇编替换，不能以仓库搜索零命中代替
最终链接证据。

### 5.2 死代码灰度归档流程
编译器已经在持续报告死代码——先把信号清单化,再按"冷却期"分级处置,
不在活跃 lane 的热文件上直接动刀:
1. **清单化**:每轮 loop 用 `cargo build --workspace` 收集 dead_code/unused 警告,
   更新下表(新增/消失都记)。
2. **归属与冷却**:每项标注疑似归属 lane;连续 ≥2 天仍在清单上且其文件无
   in-flight 改动(git status 干净)才进入处置。
3. **处置**:优先删除(git 历史即归档);语义上"未来会接线"的,要求归属 lane
   加 `#[expect(dead_code, reason)]` 注明意图,否则按死代码删。
4. 长线:清零后在 CI 把 dead_code 升级为 deny,防再堆积。

### 5.3 清单(2026-08-09 首采 13 项;同日 CI clippy 红触发全量处置)
处置原则的首次全量执行:CI `-D warnings` 蔓延到主 crate 后冷却期即时终结。
删除 = 无消费者且无在制迹象;`#[expect(dead_code, reason)]` = 疑似在制接线,
注明到期删除条件。

| 位置 | 符号 | 处置 |
|---|---|---|
| crates/agenterm-rh/transpile.rs:134 | `emit_scope_json_expr` | `#[expect]`(AOT 可能在接线) |
| src/client/mod.rs:5 | `use BufRead` | 删除 |
| src/platform/adapters/unix/frontend/mod.rs:51 | `TerminalAppearanceOverride` | 删除 |
| src/platform/mod.rs:50 | `ConsoleKey`/`LineBuffer`/`LineHistory` 导入 | 删除(facade 收窄为 `ConsoleLineEditor`) |
| src/platform/mod.rs:64 | `enter_console_line_editor` | `#[expect]`(console-line-editor 产品接线在制) |
| src/script_rh_host.rs:10 | `RhHostEntryValue::{Unit,Value}` | `#[expect]`(typed entry-value 通道待接) |
| src/script_lua_run.rs:75 | `current_run_context` | `#[expect]`(lua 消费者未接) |
| src/script_worker.rs | `classify_runtime_error` 死链(含 4 个构造器与其专属测试) | **删除**——retirement 孤儿,hosted 引擎已走类型化失败;token 表在 git 历史 |
| src/frontend/server_strip_ui.rs:37 | `StripRect::width` | `#[cfg_attr(not(test), expect)]`(仅测试消费) |
| src/script_rh_host.rs:229(顺带) | `host_process_request` 复杂返回元组 | 命名为 `type ProcessRequest`(clippy type_complexity) |
| scripts/rh/artifact-verification.rh:185 | 探测已删除的 `dist\agenterm-cli.exe` | **待修**(release 通道必炸,归 artifact 合同 lane) |

首采当日的 release-fast 归因快照(size-attribution.rh 产出,strip=none):
.text 8.13MiB — agenterm 22.4%、C 代码(LuaJIT+QuickJS+SQLite)19.8%、sqlparser
19.6%、rhai 11.2%、std 6.6%。较上一次测量的显著变化:rusqlite/SQLite 的加入把
无名 C 行从 0.76MiB 抬到 1.62MiB(sql M1 的代价,预算内)。

### 2026-08-12: static font catalogs and assembly leaf threshold

- Platform font candidates are immutable build-time catalogs. Expose them as
  `&'static [FontFileCandidate]`; keep `Vec` only for runtime discovery results.
  This removes false ownership and Unix renderer-initialization allocations.
- A Win64 `global_asm!` GDI gray8-to-alpha leaf passed its owning test but grew
  the staged con PE from 615,936 B to 616,448 B. The compiler already optimized
  the bounded Rust loop well; the extra ABI boundary and validation helper cost
  one 512-byte PE alignment unit. The experiment was fully reverted.
- Size-sensitive assembly is accepted only when final staged bytes shrink or a
  separately measured hot-path gain justifies the exact cost. Instruction-count
  intuition is not evidence, and moving code behind an FFI symbol is not removal.

### 2026-08-12: remove the floating text-conversion owner

The con geometry remains floating point, but its two text boundaries no longer
use `FromStr<f64>`: JSON `font_size` and `--font-size` share one bounded finite
decimal parser with integer significand/exponent accumulation. Ordered product
bounds use explicit branches rather than `f64::clamp`, whose impossible-bound
panic retains float debug formatting. A local `manual_clamp` lint exception is
allowed only on those measured helpers.

Measured effect: the unstripped executable lost every `f64` symbol reported by
cargo-bloat, `.text` fell from 448.5 KiB to 425.0 KiB, and attributed `std` text
fell from 155.8 KiB to 131.7 KiB. The official release-fast PE fell from 615,936
to 580,096 bytes, a 35,840-byte reduction. Evidence: 84 unit tests, 18 GUI
black-box tests, one multitab control journey, Windows all-target Clippy, and a
Linux x86-64 con check.

### 2026-08-12: native IPC endpoint boundary

`agenterm-con` exposes only the OS-native local control mechanisms already in
its product contract: Windows named pipes and Unix-domain sockets. Routing those
addresses through generic `IpcEndpoint::from_str` retained IPv4/IPv6 parsing and
TCP authority formatting even though con rejected TCP afterward. The platform
now owns `IpcEndpoint::from_native_address`; the workbench's generic TCP parser
and endpoint enum remain unchanged.

The con link map now reports zero bytes for `core::net::parser`. Unstripped
`.text` fell from 425.0 KiB to 419.5 KiB and the official release-fast PE fell
from 580,096 to 573,440 bytes. Evidence: the platform constructor test, 85 con
unit tests, 18 GUI black-box tests, one multitab control journey, Windows
all-target Clippy, and Linux x86-64 con compilation.

### 2026-08-12: native Windows temporary directory

The production owner of `std::env::temp_dir` in con was the optional platform
IME anchor trace. It now reuses the platform runtime-directory facade. The
Windows adapter calls `GetTempPathW` with a bounded growable UTF-16 buffer,
returns an absolute system path on success, and degrades to the process-relative
current directory without panic if the OS call fails or exceeds the bound.
Linux/macOS adapters are unchanged.

The con link map reports zero bytes for `std::env::temp_dir`; unstripped `.text`
fell from 419.5 KiB to 418.5 KiB. The official release-fast PE fell from 573,440
to 572,928 bytes. The native path test, 85 con unit tests, 18 GUI black-box tests,
one multitab control journey, Windows Clippy, and Linux x86-64 compilation pass.

### 2026-08-12: deterministic shared maps without random hashing

The remaining con `HashMap` owners were both in `agenterm-ui-core`: a bounded
FIFO glyph cache and iterative tree-depth indexing. The glyph cache now uses a
key-sorted contiguous vector: O(log n) hot lookup, O(n) cold insertion/eviction,
which matches expensive and infrequent rasterization. Tree resolution sorts
`(id,index)` pairs and uses O(log n) lookup, preserving O(n log n) behavior for
the 20,000-node deep-chain case instead of regressing to quadratic scans.

The con link map reports zero bytes for `hashbrown` and `RandomState`.
Unstripped `.text` fell from 418.5 KiB to 417.0 KiB, and the official
release-fast PE fell from 572,928 to 570,880 bytes. Evidence includes 34 ui-core
tests, 85 con tests, 18 GUI black-box tests, one multitab journey, Windows
Clippy, and Linux x86-64 compilation.

### 2026-08-12: remove generic sort monomorphization

After replacing tree hashing, generic `slice::sort_unstable` became a new final
owner: its `(TabId,index)` monomorphization retained IPN sort, quicksort and
smallsort. Tree indexing needs deterministic O(n log n), not the full adaptive
sort family. `agenterm-ui-core` now uses a no-allocation iterative heapsort for
index pairs; tuple order still places duplicate input indexes in ascending order,
so the typed error continues to identify the second occurrence.

The con link map reports zero bytes for `slice::sort`; unstripped `.text` fell
from 417.0 KiB to 414.0 KiB and the official release-fast PE fell from 570,880
to 566,784 bytes. All 34 ui-core tests, 85 con tests, 18 GUI black-box tests, one
multitab journey, Windows Clippy and Linux x86-64 compilation pass.

### 2026-08-12: trust platform-created sibling publication

The shared atomic writer canonicalized the destination parent before creating
an exclusive sibling temporary, then its public publisher rediscovered both
physical parents, and the Windows replacement adapter canonicalized source and
destination yet again. Those checks are necessary for arbitrary caller-owned
staging paths, but redundant for a temporary whose name and destination were
derived from the same canonical parent by one platform operation.

The public publisher retains full physical-parent, distinct-entry, real-file
and symlink validation. Internal writer/path publication now uses a narrow
owned-sibling path that revalidates callback output and destination type before
calling the adapter. The Windows adapter is mechanism-only: it converts the two
prepared paths to UTF-16 and performs write-through `MoveFileExW` with bounded
sharing retries. This makes repeated `canonicalize` and path reconstruction
unreachable from con's screenshot/snapshot path without weakening the public
contract. The official release-fast PE fell from 566,784 to 563,200 bytes.
Evidence is 46 focused platform tests, 85 con tests, 18 GUI black-box tests and
one isolated multitab control journey.

### 2026-08-12: compare fixed Windows extensions as native units

ConPTY admits only direct `.exe` and `.com` application images. Its PATHEXT
filter previously converted each `OsStr` to UTF-8, trimmed a prefix, allocated a
lowercase `String`, then matched two three-byte constants. A shared Windows leaf
now consumes exactly three UTF-16 units, folds ASCII in registers, accepts an
optional leading dot only for PATHEXT values, and rejects extra or non-Unicode
units. Direct path and PATHEXT checks share the leaf. The official release-fast
PE fell from 563,200 to 562,176 bytes while all con public journeys passed.

The audit also found that the nominally independent `pty` Cargo feature relied
on `ipc` to activate `windows-sys/Win32_Security`, which gates declarations used
by process, pipe and Job creation. `pty` now declares that dependency itself;
this changes no con linkage because its existing feature graph already enabled
it, but makes the reusable platform capability self-contained.

### 2026-08-12: stream the complete constrained PATHEXT grammar

Replacing only the final `.exe`/`.com` comparison left the upstream PATHEXT
pipeline converting to lossy UTF-8, splitting strings, dynamically prefixing a
dot, and collecting an intermediate vector that was immediately filtered. The
accepted grammar has at most four UTF-16 units per useful segment, so the
Windows adapter now scans once through a fixed stack buffer and emits canonical
candidates directly. It preserves extensionless-first lookup, configured order
and duplicates; absent or all-empty PATHEXT falls back to `.COM/.EXE`, while a
nonempty list containing only rejected extensions does not invent a fallback.
Environment override key lookup shares an exact ASCII-wide comparator.

The official release-fast PE fell from 562,176 to 560,128 bytes. Two focused
minimal-feature tests, 85 con tests, 18 GUI black-box tests, one multitab
journey, Windows Clippy and Linux x86-64 compilation pass. The result reinforces
that a native leaf saves meaningful space only when its entire generic producer
pipeline becomes unreachable.

### 2026-08-12: specialize one-shot Windows environment ordering

The ConPTY environment block used `BTreeMap<NormalizedEnvKey, (OsString,
OsString)>` only to merge inherited entries and explicit overrides into one
sorted, case-insensitive sequence before a single `CreateProcessW` call. The
generic tree retained node allocation, search and split code despite the small,
short-lived key set. A concrete platform-private sorted vector now performs
manual binary insertion: equal normalized keys replace the original key/value
payload, new keys enter in order, and serialization remains a linear pass.

A later same-profile experiment traced the remaining producer rather than
replacing only its container. The Windows adapter now acquires the inherited
UTF-16 block directly with `GetEnvironmentStringsW`, releases it with
`FreeEnvironmentStringsW`, and performs a bounded ordered merge into the exact
double-NUL block consumed by `CreateProcessW`. Hidden `=C:` entries and inherited
key spelling remain intact; explicit keys are validated and replace inherited
keys ASCII-case-insensitively with last override winning. This makes the
`std::env::vars_os` enumeration, `OsString` pair and separate normalized-key
allocation pipeline unreachable from this owner. On the same HEAD, after the
unrelated long-path publication fix moved the baseline, the official
release-fast PE falls from 551,424 to 550,400 bytes. Pure edge tests plus a real
ConPTY child prove both exact `COMSPEC` inheritance and an explicit override;
the complete con and cross-platform gates remain green.

### 2026-08-12: fixed-schema configuration input without a DOM

`agenterm-con` emits structured snapshots and control replies but accepts only
three optional configuration fields. The input side now uses one bounded
single-pass scanner rather than constructing the output `JsonValue` tree and
then searching it. Unknown values are still parsed completely; UTF-8, escape,
surrogate, duplicate-key, depth, node, field, string, trailing-data and numeric
rules remain fail-closed. Only the three known numeric spans cross into typed
conversion, and escaped key spellings compare by decoded scalar value.

This is an ownership reduction, not a permissive shortcut or an FFI claim. The
output writer remains unchanged because it still has many real producers. In a
same-profile official release-fast comparison the staged PE falls from 550,400
to 548,864 bytes. The useful boundary is asymmetric: stream a tiny fixed input
schema, retain the shared structured writer where output construction remains
real.

### 2026-08-12: remove the CRT rounding import family

The final con PE still imported `ceilf`, `round`, `roundf` and `truncf` from the
Visual C runtime. Their owners spanned product layout, font metrics, wheel
accumulation and the native pixel-window adapter, so replacing one call site
could not remove the family. `agenterm-platform::numeric` now supplies concrete
non-inlined IEEE-754 bit-level leaves shared by those boundaries. It preserves
signed zero, infinities, NaNs, half-away-from-zero rounding and integral values;
tests compare standard-library result bits over explicit edges and sampled f32
bit patterns.

All four imports disappear. The official release-fast PE falls from 548,864 to
548,352 bytes. This is preferable to target assembly here: the scalar bit
contract is already small, deterministic and shared by Windows/Linux/macOS;
future SSE/NEON leaves need both exact parity and a measured final-artifact or
hot-path win.

### 2026-08-12: con-owned Windows loader entry

The final PE still carried MSVC's default `mainCRTStartup` and five UCRT startup
DLL families even though Windows `std::sys::init` ignores C `argc`/`argv` and
`std::env::args` parses `GetCommandLineW`. Con now enters through a dedicated
`startup.rs`: it walks `.CRT$XI*` and `.CRT$XC*`, invokes rustc's generated C
`main` with `0/null`, walks `.CRT$XP*` and `.CRT$XT*`, then calls `ExitProcess`.
The loader remains the only owner of `.CRT$XL*` callbacks through the nonzero PE
Thread Storage Directory. This preserves `lang_start`, Rust runtime init,
panic/unwind containment, cleanup and Unicode argv behavior.

Rust cannot declare `#[link_name = "main"]` beside its generated entry in the
custom-std build. The narrow ISA boundary is therefore a same-ABI tail branch:
x86_64 uses `jmp main`; ARM64 uses `b main`. No product logic or initialization
lives in assembly. A test-only `.CRT$XCU` entry proves the constructor walker ran
before Rust test main. Explicit `vcruntime` and `ucrt` import libraries retain
only actual unwind/memory leaves, while `/IGNORE:4210` is justified because XI,
XC, XP and XT are manually owned and XL is loader-owned.

The official x64 release-fast PE falls from 548,352 to 543,232 bytes. Startup
UCRT runtime, math, stdio and locale imports disappear; only VCRUNTIME and the
unwind chain's `ucrt-heap/free` remain. ARM64 completes Rust/codegen including
the assembly trampoline but cannot final-link on this workstation because its
MSVC ARM64 import libraries are not installed; do not describe that as an ARM64
link pass.

### 2026-08-12: platform-owned native process arguments

After the custom loader removed CRT argv ownership, con still reached Windows
std's complete `OsString` command-line parser through `std::env::args`. The
runtime facade now owns a typed UTF-8 application-argument contract. Windows
uses `GetCommandLineW` and `CommandLineToArgvW`; a guard calls `LocalFree`
exactly once on success and every later decode failure. Argument count and each
NUL scan are capped at the Windows command-line bound, null pointers fail, and
unpaired UTF-16 returns `InvalidData` instead of panicking. Linux and macOS keep
the same facade and failure shape through their native std argv adapters.

This deliberately adopts the Windows shell parser, which is not identical to
modern MSVC parsing for ambiguous hand-crafted quote sequences. It is accepted
for this GUI product because standard launcher/Rust quoting round-trips, the
public offline CLI and `-e` passthrough tests pass, and malformed native text
fails closed. Do not transplant the choice into a console process merely for
size: loading Shell32 can add startup work, and parser semantics are part of the
public boundary.

The reproducible official x64 release-fast PE falls from 543,232 to 541,184
bytes (-2,048 bytes) while adding `shell32.dll`. This is enough to retain the
typed native ownership boundary but does not prove every std argument symbol
became unreachable. Evidence is two
platform ownership/invalid-UTF-16 tests, 87 con unit tests, 18 GUI black-box
tests, one isolated multitab control journey, Windows x64 Clippy and Linux x64
compilation.

An earlier incremental build reported 484,352 bytes. Restoring the same HEAD
later produced 541,184 bytes, and a target-specific cold A/B then reproduced
543,232 bytes for `std::env::args` and 541,184 bytes for native argv. The smaller
incremental artifact is therefore rejected as provenance evidence. `cargo clean
-p agenterm-con -p agenterm-platform` cleans the host layout only; con's custom
std lives below the explicit Windows target. Size experiments must clean with
`--target x86_64-pc-windows-msvc` (or the actual target), rebuild both sides from
the same HEAD/profile, and compare final staged bytes. A warm artifact or an
unqualified package clean cannot establish a size delta.

### 2026-08-12: native user configuration root

Con previously selected `%APPDATA%`/`HOME` in product code. The runtime facade
now owns the per-user configuration root: Windows calls
`SHGetFolderPathW(CSIDL_APPDATA)` into a caller-owned `MAX_PATH` UTF-16 buffer,
while Linux/macOS retain `~/.config`. The older Shell API is intentional here:
`SHGetKnownFolderPath` returns COM task-allocated memory and would add a second
allocator ownership edge merely to obtain a path. Product code retains only the
configuration filename and schema.

After target-specific cleaning, the official release-fast PE falls from
541,184 to 540,672 bytes (-512 bytes). Three runtime tests, 87 con unit tests,
18 GUI black-box tests, one isolated multitab control journey, Windows x64
Clippy and Linux x64 compilation pass. This is a narrow native path-policy
facade, not a reason to put arbitrary product file locations into platform.

### 2026-08-12: shared native environment block and measured x64 leaf

Windows PTY environment inheritance and runtime defaults now share one
`InheritedEnvironment` owner in the selected platform adapter. It pairs
`GetEnvironmentStringsW` with `FreeEnvironmentStringsW` exactly once and lends
the bounded double-NUL UTF-16 block to both the ConPTY merge and fixed ASCII
runtime lookup. The product no longer reaches generic Rust environment parsing
for `AGENTERM_NO_ACTIVATE`, and default-shell lookup reuses the same block for
`COMSPEC`. Linux and macOS retain their std-backed implementation behind the
same ASCII-key facade.

The x86_64 Windows lookup is a narrow inline-assembly leaf: it scans at most
32 Mi UTF-16 units, folds only ASCII letters, returns a borrowed value span,
and distinguishes absent keys from malformed termination without allocating.
Its scratch outputs use non-overlapping `out(reg)` constraints; `lateout` was
rejected after it allowed an input pointer alias and produced an access
violation. Windows aarch64 keeps the equivalent bounded Rust scanner rather
than pretending x64 assembly is portable.

An isolated target-specific cold build reduces release-fast from 540,672 to
540,160 bytes (-512 bytes). Two direct environment/scanner tests include empty
values, case folding, hidden drive entries, missing keys and a truncated block;
the complete 62 platform and 87 con unit suites pass. Windows x64 Clippy,
Windows aarch64 platform compilation and Linux x64 con compilation pass. A
complete 18-test GUI black-box run and the isolated multitab control journey
also pass against the integrated source.

A shared target produced a mismatched custom-std `compiler_builtins` link during
concurrent work, so parallel size experiments must use an exclusive target
directory and remove it after evidence capture.

The next symbol-led experiment targeted Windows argv UTF-16 decoding:
`decode_argument` owned about 1.4 KiB and `String::from_utf16` about 707 bytes
in the host-std attribution build. Replacing the conversion with strict
two-pass `WideCharToMultiByte(CP_UTF8, WC_ERR_INVALID_CHARS)` preserved normal
argv and invalid-surrogate behavior, but an isolated custom-std cold build grew
from 540,160 to 540,672 bytes (+512 bytes). Native ownership alone was not a
win: required-size discovery, allocation, the second FFI call and control flow
remained linked. The implementation is rejected and the Rust conversion stays;
revisit only if fixed caller-owned output or a changed link graph can remove
the entire conversion family.

A second symbol-led experiment targeted the Windows GDI gray8 conversion loop.
Hoisting stride/length validation out of each pixel made the failure boundary
clear but grew the custom-std PE from 540,160 to 540,672 bytes. Replacing that
scalar iterator with one bounded x86_64 inline-assembly row scanner grew the PE
again to 541,184 bytes. Synthetic padding/saturation/short-write tests and real
ASCII/CJK GDI rasterization passed, but the conversion runs only on glyph-cache
misses and had no public latency evidence capable of paying for +1,024 bytes.
Both candidates are rejected. Future font optimization should reuse native
`HDC`/`HFONT` faces across cache misses, where the source audit found repeated
system object creation, rather than micro-optimizing the gray8 arithmetic.

That lifecycle target is now implemented in the Windows font adapter. A
thread-local `RasterFaces` owns at most one active pixel size and lazily creates
each GDI family only when coverage reaches it. Size changes replace the set and
therefore run every `PixelFace` RAII cleanup; reentry and TLS teardown return
`FontError::RasterFailed` instead of panicking. Thread-local ownership is
deliberate: Microsoft documents that a memory DC created from NULL belongs to
its creating thread and becomes invalid when that thread exits, so an unsafe
`Send` wrapper would weaken the native contract merely to reuse a mutex.

The deterministic creation-count test rasterizes all 94 printable ASCII glyphs
at one size and observes one `CreateCompatibleDC`/`CreateFontW`/metrics sequence
instead of the former 94. This costs 2,048 final bytes (540,160 to 542,208) and
is accepted for first-render and new-glyph smoothness, not described as a size
win. Evidence is 69 platform tests, 87 con tests, 18 GUI black-box tests, one
multitab control journey, Windows x64 Clippy, Windows aarch64 font compilation
and Linux x64 con compilation. Unix/macOS retain their existing OnceLock-backed
file-font renderer behind the same facade.

### 2026-08-12: bounded wait-text byte search

Host-std attribution showed about 1.8 KiB in generic `str` containment and
another 1.4 KiB in `StrSearcher` construction, reached only by con's public
`wait-text` polling path. The owning behavior is narrower: each current
viewport row is searched independently as valid UTF-8 bytes, with no newline
insertion, cross-row match, hidden-scrollback scan, normalization, or case
folding. Empty text remains an immediate match when a visible row exists.

The control module now owns one allocation-free byte-search kernel. x86_64 uses
a bounded inline-assembly candidate/needle loop with non-aliasing output
registers; Windows aarch64, Linux and macOS use the same scalar contract. A
matrix oracle covers empty, shorter/longer, repeated-byte and absent needles,
plus CJK and emoji boundaries. The sole `screen_contains` call delegates each
row to this helper without changing viewport enumeration.

An isolated custom-std cold build falls from 542,208 to 537,600 bytes (-4,608).
A later host-std symbol build showed that unrelated fixed-character checks
still retain generic `str::pattern`/`StrSearcher`; the measured delta is valid,
but the earlier claim that the entire family left the graph was too broad.
Evidence is 88 con unit tests, the full wait-text multitab control journey, 18
GUI black-box tests, Windows x64 Clippy, Windows aarch64 con compilation and
Linux x64 con compilation.

Replacing the remaining fixed `':'`, `'='`, and NUL `str::contains` checks in
IPC/process conventions with byte-slice membership did not remove the generic
pattern framework: the same parser still uses strip/split patterns, and the
isolated custom-std PE grew from 537,600 to 539,136 bytes (+1,536). The code
experiment is rejected. Post-change symbol attribution is mandatory even when
all visible `contains` call sites look removable.

All BTree symbols become zero-byte owners. In the host-std attribution build,
platform text fell from 91.6 to 84.6 KiB and total text from 409.5 to 403.5 KiB;
the official custom-std release-fast PE fell from 560,128 to 552,448 bytes.
Evidence is 53 minimal PTY tests, 85 con tests, 18 GUI black-box tests, one
multitab journey, Windows Clippy and Linux x86-64 compilation. This is a
specific one-shot serialization optimization, not a repository-wide ban on
ordered maps.

### 2026-08-12: split trusted sibling destination preparation

The public atomic publisher accepts arbitrary caller-owned staging and
destination paths, so it must canonicalize physical parents and reject links or
identity aliases. The snapshot/screenshot writers instead create their own
exclusive temporary from the destination parent and need only freeze an
absolute target before invoking a callback, validate that parent as a directory,
and revalidate callback output. Routing both through the public identity path
retained std filesystem canonicalization in con without adding authority.

A separate platform facade now models this provenance. Unix keeps canonical
parent behavior; Windows uses bounded `GetFullPathNameW` and
`GetFileAttributesW`, while the public publisher remains unchanged. In the con
link, `normalized_destination` and std filesystem canonicalization become
zero-byte owners. Host-std attributed text fell from 403.5 to 403.0 KiB and the
official custom-std release-fast PE from 552,448 to 551,936 bytes. Evidence is
46 focused platform tests, 85 con tests, 18 GUI black-box tests, one multitab
journey, Windows Clippy and Linux x86-64 compilation.

### 2026-08-12: encode directly into Win32 clipboard ownership

Windows clipboard publication previously collected UTF-16 plus NUL into a Rust
vector, allocated the required movable global block, then copied the complete
vector into that second allocation. The native destination is writable after
`GlobalLock`, so the adapter now performs a checked UTF-16 unit count, allocates
once, encodes directly into the block and writes the terminator explicitly.
Every pre-transfer failure still calls `GlobalFree`; successful
`SetClipboardData` remains the only ownership-transfer point.

The official release-fast PE fell from 551,936 to 551,424 bytes while removing
one heap allocation and full-text copy from every selection auto-copy. Evidence
is 31 minimal clipboard tests, 85 con tests, 18 GUI black-box tests, one multitab
journey, Windows Clippy and Linux x86-64 compilation.
