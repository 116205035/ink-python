# PyInk Phase 3 — content rendering

## Goal

为 Jarvis AI 助手 TUI 提供完整的内容渲染能力：流式文本、Markdown、代码高亮、Diff。Phase 3 完成后，PyInk 能搭出 Claude Code 风格的对话 UI（AI 流式回复 + Markdown 格式 + 语法高亮代码 + 文件编辑 diff）。

## Background

PyInk 已交付：
- MVP（534 测试）：signals + 6 内置组件 + flex + ANSI + render 管线
- Examples 补全（13 examples）：覆盖所有 MVP 能力
- Phase 2（693 测试）：Spinner/Link/Divider externals + Context 系统 + use_focus/use_box_metrics hooks + measure_element API

Phase 3 补 4 个内容渲染组件，全部在 `pyink/externals/`：
- **StreamingText**：无依赖
- **Markdown**：`markdown-it-py` optional dep
- **HighlightedCode**：`pygments` optional dep
- **StructuredDiff**：`difflib` stdlib

## Decisions (ADR-lite)

### Decision 1: Markdown 解析用 markdown-it-py

**Context**: Python Markdown 解析库选择。常见选项：`markdown-it-py`（CommonMark 标准 + 扩展）、`markdown`（Python-Markdown，老牌）、`mistune`（速度）。

**Decision**: 用 `markdown-it-py`。
- CommonMark 兼容（跟 GitHub/VSCode 一致）
- 流式解析友好（增量 token，适合 AI token-by-token）
- 扩展系统成熟（tables/strikethrough/task lists）
- 与 mdit-py-plugins 生态配合

**Consequences**:
- ✅ 标准兼容
- ✅ 流式友好
- ❌ 拖一个中等依赖（~200KB），需要 optional-dependencies 隔离

### Decision 2: 代码高亮用 Pygments

**Context**: Python 语法高亮库。`pygments`（事实标准，500+ lexers）、`tree-sitter`（精确但需 grammar 包）、`rich.syntax`（包装 pygments）。

**Decision**: 用 `pygments`。
- 不需要 grammar 包，开箱即用
- 500+ lexers 覆盖所有主流语言
- token 类型清晰，映射到颜色简单
- 跟 markdown-it-py 的 highlight 插件兼容

**Consequences**:
- ✅ 零配置支持多语言
- ✅ mature 稳定
- ❌ 拖较大依赖（~5MB），必须 optional
- ❌ 不如 tree-sitter 精确（如错误恢复、增量解析）

### Decision 3: Markdown 检测代码块时智能降级

**Context**: Markdown 渲染时遇到 code block，如果 `pyink[highlight]` 没装，怎么办？

**Decision**: 自动检测 HighlightedCode 是否可用：
- 装了 `pyink[highlight]` → 用 HighlightedCode 渲染（语法着色）
- 没装 → 降级为纯 Text + dimColor（保持可读）

Markdown 不强制依赖 HighlightedCode，反之亦然。

### Decision 4: Diff 用 stdlib difflib

**Context**: 文件编辑 diff 显示。

**Decision**: 用 `difflib`（stdlib，无依赖）。
- unified_diff / ndiff 算法够用
- 不需要 `diff-match-patch` 之类的字符级 diff
- 行级 diff 已经够清晰

### Decision 5: StreamingText 用 signal buffer + 可选平滑展开

**Context**: AI 流式回复需要展示逐字/逐 token 出现的效果。

**Decision**:
- **基本用法（默认）**：`buffer = signal("")` + `Text(lambda: buffer.value)` 已经能流式（信号变 → rerender）。StreamingText 提供便利封装。
- **StreamingText 组件**：包 buffer + 可选 cursor + 可选平滑展开（每 N ms 显示 +1 字符，模拟打字）
- 实现用 use_interval 驱动展开

**Consequences**:
- ✅ 简单场景就是 signal + Text，无新概念
- ✅ StreamingText 提供 UX 增强（cursor、平滑）
- ❌ 平滑展开需要 buffer 比当前显示更长——内部维护 `revealed_count`

## Requirements

### 必交付（6 PRs）

#### PR1: StreamingText external

`src/pyink/externals/streaming_text.py`：
```python
def StreamingText(
    buffer: Signal[str] | Callable[[], str] | str,
    *,
    cursor: str | None = None,        # 默认 None，可设 "▋" 或 "|"
    cursor_color: str | None = None,
    reveal_speed: int = 0,             # chars per second; 0 = 即时显示全部
    color: str | None = None,
    **text_props,
) -> Element:
    """流式文本展示。
    - buffer：源（signal 或 callable 在 layout 时求值，str 是静态）
    - cursor：末尾光标字符
    - reveal_speed>0：每秒显示 N 字符，模拟打字
    - revealSpeed=0：buffer 变化立即显示全部
    """
```

依赖：use_interval（Phase 2 PR1）

#### PR2: HighlightedCode external

`src/pyink/externals/highlighted_code.py`：
```python
PYGMENTS_TOKEN_COLORS = {
    "Token.Keyword": "magenta",
    "Token.String": "green",
    "Token.Comment": "brightBlack",  # dim
    "Token.Number": "cyan",
    "Token.Name.Function": "blue",
    "Token.Name.Class": "yellow",
    "Token.Operator": "red",
    "Token.Punctuation": None,  # 默认色
    # ... 完整 Pygments token tree
}

def HighlightedCode(
    code: str,
    *,
    language: str = "text",  # 自动检测如果 "text" 或 "auto"
    theme: dict | None = None,  # 覆盖默认颜色
    line_numbers: bool = False,
    **text_props,
) -> Element:
    """代码语法高亮。
    - lazy import pygments
    - 缺 pygments 抛友好 ImportError："pip install pyink[highlight]"
    """
```

依赖：pygments（optional）

#### PR3: Markdown basic renderer

`src/pyink/externals/markdown.py`：
```python
def Markdown(
    source: str | Signal[str] | Callable[[], str],
    *,
    theme: dict | None = None,  # 样式覆盖（heading_color, code_bg, etc.）
    **box_props,
) -> Element:
    """Markdown 渲染。
    - lazy import markdown_it
    - 缺 markdown_it 抛友好 ImportError："pip install pyink[markdown]"

    支持的 markdown 元素：
    - 标题（h1-h6，带颜色 + bold）
    - 段落
    - 强调（bold/italic/strikethrough）
    - 行内 code
    - 链接（用 Link external 渲染 OSC 8）
    - 列表（ordered/unordered，缩进）
    - 代码块（用 HighlightedCode 如果可用，否则纯 Text）
    - 引用块（blockquote，缩进 + dimColor）
    - 水平线（用 Divider external）
    - 表格（基本支持，column 对齐）
    """
```

依赖：markdown-it-py（optional）+ Link + Divider + 可选 HighlightedCode

#### PR4: Markdown + HighlightedCode 集成

修改 PR3 的 Markdown，让 code block 检测 HighlightedCode 可用性：
- 可用 → 用 HighlightedCode(language=lang, theme=...)
- 不可用 → 降级 Text(code, dimColor=True) + Box 包装

加测试覆盖：
- 装 pygments + markdown 时 code block 高亮
- 只装 markdown 时 code block 纯文本
- 各种语言代码块（Python/JS/SQL/YAML/JSON 等）

#### PR5: StructuredDiff external

`src/pyink/externals/diff.py`：
```python
def StructuredDiff(
    before: str,
    after: str,
    *,
    language: str = "text",       # 可选高亮
    context_lines: int = 3,       # 显示多少行 context
    show_header: bool = True,     # 显示 file path header
    **box_props,
) -> Element:
    """文件编辑 diff 显示。
    - 用 difflib.unified_diff 计算
    - 行级染色：+ green / - red / @@ magenta / context default
    - 可选用 HighlightedCode 给 +/- 行加语法高亮（如果可用）
    """
```

依赖：difflib（stdlib）+ 可选 HighlightedCode

#### PR6: Examples + README + integration tests

5 个新 examples：
- `examples/markdown/markdown_demo.py` —— 各种 markdown 元素
- `examples/highlighted-code/highlighted_code_demo.py` —— 多语言代码高亮
- `examples/streaming-text/streaming_text_demo.py` —— 模拟 AI 流式回复
- `examples/diff/diff_demo.py` —— 文件编辑 diff
- `examples/markdown-code-integration/integration_demo.py` —— Markdown 含代码块

更新：
- `pyproject.toml`：加 `[project.optional-dependencies]` 的 markdown/highlight/all
- `tests/test_examples.py`：+5 测试
- `README.md`：API 表 + examples 索引 + 安装说明（`pip install pyink[markdown]`）

## Acceptance Criteria

- [ ] 6 PRs 全部交付
- [ ] 4 个新 externals（StreamingText/Markdown/HighlightedCode/StructuredDiff）+ 测试
- [ ] `pyproject.toml` optional-dependencies 配置正确
- [ ] lazy import 错误信息清晰（"pip install pyink[xxx]"）
- [ ] 5 个新 examples 跑通
- [ ] mypy strict + ruff 全绿
- [ ] 全部测试通过（应该 693 + ~80 新 = 773+）
- [ ] 不破坏 Phase 1-2 现有测试
- [ ] README 完整更新

## Definition of Done

- 6 PRs（每个含 implement + check + commit）
- 集成测试覆盖
- 5 个 examples 真实终端验证
- 全部 quality gates 绿
- 公共导出（externals 不默认导出，用户显式 import）

## Bug Fixes (post-PR6 hardening pass)

Five user-reported bugs against the Phase 3 examples were addressed in a
single hardening pass. Root-cause analysis + fix per bug:

### Bug 1 — ANSI SGR state leaks into the shell after exit

**Symptom**: after quitting `streaming_text_demo.py` the terminal font
kept the colour of the StreamingText cursor (green) and any subsequent
shell input was green too.

**Root cause**: `Instance._clear_frame_for_exit` only emitted cursor-up
+ per-row `\\x1b[2K` line clears; it never reset the terminal SGR state.
Components leave whatever SGR sequence the last painted row applied in
the active terminal state, so the shell inherited it.

**Fix**: `src/pyink/render/instance.py` — `_clear_frame_for_exit` now
writes a trailing `\\x1b[0m` after the frame clear so the terminal is
returned to the default SGR state. Alternate-screen mode is unaffected
(the buffer swap discards SGR state, and `_clear_frame_for_exit` only
runs in inline mode anyway).

### Bug 2 / 3 — high CPU + streaming Markdown shows only the final frame

**Symptom**: highlighted-code / markdown / diff / markdown-streaming
examples all showed a perceptible startup delay and pinned a CPU core
near 100%; `markdown_streaming_demo.py` rendered the full Markdown
instantly rather than streaming it token-by-token.

**Root cause**: the render loop runs the layout **twice** per signal
flush — once inside the render-loop `effect` body (to establish signal
subscriptions) and once inside the throttled `_paint_now` (the actual
paint). For reactive Markdown this meant:

* `_MarkdownImpl`'s `Text` callable re-parsed the whole document with a
  freshly-constructed `MarkdownIt` parser on every layout.
* It then built a per-block Element tree, mounted it via a throwaway
  `Reconciler`, ran a nested `layout`, and rendered it to a string.
* All of this happened **twice** per signal flush (≈50 writes/sec in the
  streaming demo).
* `HighlightedCode` did the same — re-tokenising the same code block on
  every layout.

**Fix** (per-layer caches; no change to the render loop's double-layout
contract, which is intentional — the subscription layout must run
inside the effect's tracking context):

* `src/pyink/externals/markdown.py`:
  * Replaced the per-call `MarkdownIt` construction with a shared
    process-wide parser instance (`_get_parser`).
  * Added an LRU render cache (`_cached_render`) keyed on
    `(text, columns, id(theme))` so the second layout of the same
    signal flush hits the cache. Bounded to 64 entries.
  * Extracted the snapshot pipeline into `_render_markdown_to_string`
    so the cache layer is testable in isolation.
* `src/pyink/externals/highlighted_code.py`:
  * Added an LRU tokenise cache (`_tokenize`) keyed on
    `(code, language)`, bounded to 64 entries.

**Bug 3 follow-up**: with the cache in place the render loop can keep
up with the 50 Hz buffer writes and the user sees the incremental
typing animation again.

### Bug 4 — bordered Box border "scrambled" at the end of a stream

**Symptom**: at the end of `markdown_streaming_demo.py` the round border
around the Markdown Box appeared with its characters in the wrong
columns.

**Root cause**: this was a visible artefact of Bug 2/3 — when the render
loop fell behind, frames were coalesced mid-flush and the diff wrote
border characters against a stale `current_frame` whose row count no
longer matched the actual on-screen state. Once the cache fixed the
throughput the artefact disappeared; the frame diff code itself is
correct for the constant-height case (the bordered Box always stretches
to the viewport, so every frame has the same row count and the
line-by-line diff can't drift).

**Regression test**: `test_streaming_markdown_inside_border_box_stays_consistent`
grows the buffer one character at a time and asserts every painted
frame keeps its left border column on every row.

### Bug 5 — reference implementations consulted

* **ink** (`D:\\Projects\\github\\ink`): confirmed the inline-renderer
  convention of never emitting `\\x1b[2J` and that exit cleanup emits a
  reset; PyInk's instance already followed the no-`2J` rule and now
  also emits the reset.
* **Textual** (`D:\\Projects\\github\\textual-main`): consulted its
  `Markdown` widget caching strategy (parse once, re-render on theme
  change) — the LRU cache mirrors that pattern at a smaller scale.
* **Claude Code** (`D:\\Projects\\github\\claude-code`): the
  `Markdown.tsx` / `HighlightedCode` / `StructuredDiff` components
  inspired the original Phase 3 design; this pass focused on the
  caching layer that the original implementation omits.

### Bug 6 — `_FpsThrottle` busy-spin on static frames (root cause of "high CPU after render")

**Symptom** (post-Bug 2/3 follow-up): even with the LRU caches in
place the user still reported (a) the static highlighted-code /
markdown / diff demos showing "very slow" startup and (b) CPU
remaining pinned at ~100% after the static frame finished rendering
(rather than dropping to near 0 as expected for a console program).

**Diagnosis**: a throwaway profiling script mounted a static
`Box(Text("hello"), Text("world"), borderStyle="round")` and counted
`_FpsThrottle._loop` iterations over a 2-second idle window. The
result was **9,163,072 iterations in 2 s (~4.6 million iterations /
sec)** — a tight `while True: continue` busy-spin. `psutil` sampling
on the same setup showed `cpu_percent == 99.98%` while idle, dropping
to `0.0%` after the fix.

**Root cause**: `_FpsThrottle._loop` initialised `last = 0.0` and
computed the wait duration as

```
wait_for = self.min_interval - (time.monotonic() - last)
```

When there was no pending work the loop took the `if not pending:
continue` branch, so `last` was never advanced past `0.0`. Because
`time.monotonic()` returns seconds-since-some-epoch (a large positive
number), `time.monotonic() - last` was always huge, so `wait_for` was
always negative, the `wait_for > 0` guard never triggered, and the
loop never slept. The throttle thread therefore burnt an entire CPU
core whether or not anything was being painted.

The earlier LRU cache fix (Bug 2/3) reduced the per-tick work done
when a paint *did* fire, but did not address the idle spin — so the
user still observed 100% CPU on a static frame and a perceptible
"slow startup" because the demo was already competing with the
spinning thread for CPU time on mount.

**Fix**: `src/pyink/render/instance.py` — `_FpsThrottle._loop` now
takes pending work *first* and only computes the FPS wait when there
is work to defer. When the queue is empty it parks indefinitely on
`self._wakeup.wait()` (no timeout) — the wakeup `Event` is the only
legitimate reason to leave that branch, so a static frame uses zero
CPU. When work is queued it waits out the remaining interval, then
runs the latest pending callback (any callback that arrived during
the wait wins; if none did the original `pending` list still has the
callback that woke us).

**Regression tests** (`tests/render/test_instance.py`):

* `test_fps_throttle_does_not_spin_when_idle` — runs the fixed loop
  on a fresh thread for 0.5 s with no schedules and asserts the
  iteration count stays ≤ 2 (one per stray wakeup). The pre-fix code
  logged hundreds of thousands of iterations in the same window.
* `test_fps_throttle_coalesces_burst_into_one_callback` — three
  `schedule()` calls inside one window fire exactly one callback
  (the latest), preserving the documented coalescing contract.

**Verification**:

* `psutil` sampling on a static `Box(Text("hi"), borderStyle="round")`
  frame: pre-fix avg `99.98%` CPU, post-fix avg `0.0%` CPU.
* The streaming Markdown profile (67-char drip at 20 ms/char) now
  records 46 paints over a 1.5 s window at a steady 33 ms interval —
  matching the 30 FPS cap and producing visible incremental typing
  (`Ti` → `Tit` → `Title` → `Hello` → …).
* All 879 tests pass (877 baseline + 2 new regression tests).
* `ruff check src tests` and `mypy src tests` both clean.

### Verification

* All 877 tests pass (870 baseline + 7 new regression tests).
* `ruff check src tests` and `mypy src tests` both clean.
* Manual `markdown_streaming_demo.py` run now shows incremental typing
  animation rather than a single instant render; quitting no longer
  leaves the shell with a coloured font.

### Bug 7 — nested Markdown code-block border scrambles at end of stream

**Symptom**: streaming Markdown inside a bordered parent Box renders
with the inner code-block border "scrambled" at the end of the stream.
Inner top/bottom edges appear on their own rows at the wrong width;
inner left/right edges are missing on the code-bearing rows; the
outer parent's right border carries the orphaned inner-edge
characters. The visual reads as the inner box having been cleaved
across multiple lines.

**Root cause**: `_MarkdownImpl` (the reactive source branch) renders
its Markdown snapshot to a single string via `_cached_render`. The
width it passed to `_render_markdown_to_string` was `inst.columns`
— i.e. the **viewport width** (e.g. 70), not the width of the
content box the Markdown `Text` leaf actually lives in (e.g. 66 = 70
- 2 outer border - 2 outer padding). The snapshot was therefore
pre-rendered at 70 cells with box-drawing characters locked in, then
handed to a `Text` leaf that the layout engine constrained to 66
cells. The engine cannot re-wrap pre-rendered box-drawing characters
without scrambling them, so the inner border overflowed into the
parent's right border column.

The static `str` fast path was unaffected because it returns a real
element tree (no snapshot string); the layout engine sees the
inner `Box(highlighted, borderStyle=...)` directly and constrains
it correctly. Only the reactive branch snapshot suffered.

**Fix** (plumb the layout-time width into width-aware text
renderers):

* `src/pyink/layout/_text_width_context.py` (new): a
  `contextvars.ContextVar` exposing the active text-leaf
  measurement width. ``None`` means "unbounded" / "not set".
* `src/pyink/layout/flex.py`:
  * New `FlexNode.text_renderer` field for single-callable text
    leaves whose body depends on the available width.
  * `_build_host_node` now defers evaluation of single-callable
    text leaves: instead of invoking the callable at flex-tree
    construction (when no width is known), it stores the callable
    on the FlexNode for later.
  * `_layout_node`'s text branch invokes the deferred renderer
    inside a `set_current_text_width(max_w_for_text)` block, so
    the renderer can read the actual measurement width via
    `get_current_text_width()`. The result is cached on the node
    keyed by width so subsequent layout passes with the same
    width skip the call (mirrors the existing `_wrapped_width`
    bookkeeping for the wrap path).
* `src/pyink/externals/markdown.py`: `_MarkdownImpl`'s
  `render_reactive` callable now consults
  `get_current_text_width()` first; only when that returns
  ``None`` (the layout pass is measuring under unbounded width,
  e.g. the very first subscription layout) does it fall back to
  `inst.columns`.

The deferred-evaluation change preserves the existing subscription
model: the renderer still runs inside the render-loop effect's
tracking context (because `_layout_node` is called from `layout`
which is called from the effect body), so `Signal.value` reads
inside the renderer still establish subscriptions and signal writes
still trigger paints.

**Regression test**
(`tests/externals/test_markdown.py::test_signal_source_nested_border_box_does_not_scramble`):
grows the buffer character-by-character and at the final state
asserts every painted line fits within the viewport, every
code-bearing row carries both inner-left and inner-right ``│``
columns, and those columns are consistent across all code-bearing
rows. Pre-fix the assertion fails because the code-bearing rows
have only the inner-left border.

**Verification**:

* All 880 tests pass (879 baseline + 1 new regression test).
* `ruff check src tests` and `mypy src tests` both clean (the two
  remaining mypy warnings are pre-existing in `measure.py`'s
  `wcwidth` import and unrelated to this fix).
* Manual `markdown_streaming_demo.py` run shows the inner
  code-block border rendering consistently at every intermediate
  state and at the end of the stream — no orphaned half-width
  edges, no missing inner-right border.

### Bug 8 — bordered Box drops one edge when vertical overflow shrinks it below 2 rows

**Symptom**: `examples/markdown-streaming/markdown_streaming_demo.py`
in a viewport too short for the rendered content (e.g. ``rows=10``)
left the inner code-block border Box visually split: the painter drew
the bottom edge ``└─┘`` on one row and the content row below it, but
the matching top edge ``┌─┐`` was missing — so the reader saw a
dangling half-border with no close. At ``rows=24`` (the demo's
original default) the inner border also squeezed to 3 rows and lost
the second source line (``return n * n``), but at least the top and
bottom edges were on separate rows so the artefact was less glaring.

**Reproduction**: a throwaway script mounted
``Box(Text("Header"), Markdown(md), padding=1, borderStyle="round")``
at ``rows=10`` and inspected the painted frame. The inner code-block
border Box resolved to ``66x1`` in the layout tree (height 1!), but
the painter still wrote both edges — the bottom edge write at
``abs_y + height - 1`` landed on the same row as the top edge write
at ``abs_y``, and because the bottom write happens last the bottom
won, leaving the visible artefact ``└─┘`` with no matching ``┌─┐``.

**Root cause**: the flex engine's main-axis shrink path
(:func:`pyink.layout.flex._distribute_main`) is allowed to shrink any
child below its renderable minimum — a single-rounding ``int(round())``
can drop a text leaf from 1 row to 0, and a bordered Box from 2 rows
(the minimum needed to fit its top and bottom edges) to 1 or 0. The
renderer (:func:`pyink.layout.render_layout._paint_box_border`) then
unconditionally wrote both edges, so when both landed on the same row
the later write clobbered the earlier one and left a single orphaned
edge character. The Box's children (positioned by the layout as if
the box still had its natural interior) also leaked past the parent's
border into adjacent rows.

The fix could have lived in either layer; the renderer-side guard is
strictly simpler and matches ink's "either render whole or skip"
contract for clipped elements (``render-node-to-output.ts`` clips
boxes to their computed region; PyInk's MVP grid does not carry a
clip stack, so the equivalent is to skip painting the node entirely
when there is no room to honour the border).

**Fix** (renderer-side guard in
:func:`pyink.layout.render_layout._paint_node`):

* Compute the bordered Box's renderable minimum from the per-edge
  flags: ``needed = (1 if show_top else 0) + (1 if show_bottom else
  0)``. With both edges enabled the minimum is 2 (top + bottom);
  with one edge opted out (``borderTop=False`` or
  ``borderBottom=False``) the minimum is 1; with both opted out
  there is no constraint.
* When ``node.height < needed`` the renderer returns early and
  paints neither the box nor its subtree. The parent's grid cells
  stay blank, which reads as "the element was truncated" rather
  than as a corrupted frame.
* Other node kinds (text leaves, unbordered Boxes) are left to the
  existing ``_paint_text`` height-clip path — they have no edges to
  dangle and the historic "shrink-to-zero but still paint naturally"
  behaviour is preserved (some examples rely on this).

**Demo adjustment**: ``examples/markdown-streaming/markdown_streaming_demo.py``
bumped its viewport from ``rows=24`` to ``rows=30``. At 24 rows the
rendered Markdown's natural height (heading + paragraph + list +
code block + Done) overflowed the outer Box's interior by enough that
the flex engine squeezed the inner code-block border Box to 3 rows,
which fit top + bottom edges + one content row but dropped the
second source line. At 30 rows the entire Markdown fits without
shrink and both code lines render with a properly closed border.
The renderer-side guard keeps the border whole even when shrink
*does* leave the box too small, but bumping the rows gives the
reader the full content too.

**Regression tests** (``tests/components/test_box.py``):

* ``test_bordered_box_shrunk_to_zero_height_is_skipped`` — a
  bordered Box squeezed to height 0 paints neither edge nor content.
* ``test_bordered_box_shrunk_to_one_row_is_skipped`` — same with
  height 1 (both edges enabled, minimum is 2, height 1 fails the
  guard).
* ``test_bordered_box_with_only_one_edge_at_height_1_renders`` —
  with ``borderBottom=False`` the minimum is 1, so a height-1 box
  still paints its single (top) edge.
* ``test_borderless_top_and_bottom_box_at_height_1_renders`` — the
  historic ``borderTop=False, borderBottom=False`` shape continues
  to render at height 1 (the opt-out path the per-edge override
  unlocks).
* ``test_nested_bordered_box_overflow_closes_borders`` — end-to-end
  nested-Box reproduction: when an inner bordered Box is squeezed
  out by an outer padded bordered Box, neither the inner edge
  characters nor the inner content leak onto the rendered frame.

**Verification**:

* All 885 tests pass (880 baseline + 5 new regression tests).
* ``ruff check src tests`` and ``mypy src tests`` both clean (the
  two remaining mypy warnings are the pre-existing
  ``measure.py``/``wcwidth`` ones, unrelated to this fix).
* Manual ``markdown_streaming_demo.py`` run at ``rows=30`` shows
  the inner code-block border rendering with both source lines and
  a cleanly closed top + bottom edge at every intermediate stream
  state and at the end of the stream.
* Manual repro at ``rows=10`` no longer emits a dangling half-border;
  the inner code-block border Box is skipped entirely (the language
  header line ``python`` is still visible because it lives outside
  the bordered Box; the border itself does not appear).

---

## Out of Scope

- 不实现 tree-sitter 高亮（Pygments 已够 MVP）
- 不实现 Markdown 的 GFM 扩展（task lists、footnotes、math 等）—— 基础 CommonMark + tables 够用
- 不实现流式 Markdown（增量解析）—— 整段重渲就行
- 不写 VirtualList（Phase 5）

## Technical Notes

### 参考实现

- ink 第三方包：`D:\Projects\github\ink\components\` 下：
  - `ink-markdown/` —— Markdown（用 marked-terminal）
  - `ink-syntax-highlight/` —— 代码高亮
- Claude Code：`D:\Projects\github\claude-code\src\components\` 下：
  - `Markdown.tsx` —— 流式 Markdown
  - `HighlightedCode/` —— 代码块
  - `StructuredDiff/` —— 文件 diff
  - `FileEditToolDiff.tsx` —— 工具调用 diff
- Pygments 文档：https://pygments.org/docs/tokens/
- markdown-it-py：https://github.com/executablebooks/markdown-it-py

### 关键约束

- Python 3.11+，mypy strict + ruff
- 全同步 + 线程并发
- 函数组件 only
- Children 位置参数
- 不写 `\x1b[2J`
- style props 支持 callable
- externals 用 lazy import + 友好 ImportError

## Implementation Plan

6 PRs（每 PR implement → check → commit）：

1. **PR1**: StreamingText（无依赖，简单）
2. **PR2**: HighlightedCode（pygments optional，独立）
3. **PR3**: Markdown basic（markdown-it-py optional）
4. **PR4**: Markdown + HighlightedCode 集成
5. **PR5**: StructuredDiff（difflib stdlib，可选集成 HighlightedCode）
6. **PR6**: Examples + README + 集成测试

预计 2-3 周。

## Research References

（暂无；可在 PR3 前派 trellis-research 调研 markdown-it-py AST 渲染模式）
