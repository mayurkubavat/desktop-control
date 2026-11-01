# Architecture Overview

`dobby` is designed around a closed-loop **Perception $\rightarrow$ Actuation $\rightarrow$ Verification** cycle.

```
       +-----------------------------------------------+
       |             MCP Client (Agent)                |
       +-----------------------------------------------+
                             |  JSON-RPC (stdio)
                             v
       +-----------------------------------------------+
       |            dobby Server             |
       +-----------------------------------------------+
         /            |             \             \
        v             v              v             v
  +----------+  +-----------+  +------------+  +-----------+
  | Perception|  | Actuation |  | vDOM &     |  | Plugins & |
  | & Quiesce|  | (Mouse,   |  | Self-Heal  |  | Trajectory|
  | (XDamage)|  |  Keyboard)|  | Cache      |  | Dispatcher|
  +----------+  +-----------+  +------------+  +-----------+
         \            |              /             /
          v           v             v             v
       +-----------------------------------------------+
       |           Operating System Desktop            |
       |             (Linux X11 / Windows)             |
       +-----------------------------------------------+
```

---

## 1. Hardware Abstraction Layer (HAL)

The Hardware Abstraction Layer isolates platform-specific desktop APIs behind a common Python interface (`DesktopHAL` in `vision_mcp/hal/base.py`):

- **Linux (`LinuxHAL`)**:
  - Screen capture using `mss`.
  - Window management via `python-xlib` with EWMH `_NET_ACTIVE_WINDOW` ClientMessage protocol.
  - Event quiescence monitoring via X11 `XDamage` and `XFixes`.
  - Mouse and keyboard injection via `pynput` with cadence pacing.
- **Windows (`WindowsHAL`)**:
  - Screen capture via DXGI desktop duplication.
  - Window tracking using Win32 API (`GetForegroundWindow`, `SetForegroundWindow`).
  - Input injection via Win32 `SendInput` with Per-Monitor DPI scaling awareness.

---

## 2. UI Element Grounding & Virtual DOM

Interactive elements are discovered through three complementary mechanisms:

1. **Accessibility Tree (AT-SPI2)**: Directly reads semantic names, accessible roles, and exact pixel bounds from the operating system without visual inference.
2. **Fast ONNX UI Detector**: A lightweight, 159 KB neural model (`vision_mcp/models/ui_detector_fast.onnx`) running on CPU AVX-512 in **~8.3 ms** (~120 FPS). Identifies buttons, inputs, tabs, and panels directly from pixel data.
3. **Template Matching**: Uses normalized cross-correlation (`cv2.matchTemplate`) for finding specific icons, toolbars, and custom widgets.

The **vDOM Fusion Engine** (`vision_mcp/vdom/fusion.py`) merges accessibility nodes and visual proposals into an indexed virtual DOM tree that can be queried with CSS-style selectors (`query_vdom`).

---

## 3. Dynamic Self-Healing Locator Cache

To avoid re-grounding familiar UI elements on every turn, the action cache (`vision_mcp/agent_loop/cache.py`) provides:

1. **Window Movement Re-Projection**: Automatically translates element coordinates when host windows move or resize.
2. **Pre-Flight dHash Verification**: Computes a 64-bit perceptual visual hash on the candidate element patch in **<0.5 ms**. If the visual hash matches, the action executes immediately with 0 visual tokens.
3. **Localized Neighborhood Drift Recovery**: If visual verification detects drift, the engine searches within a $\pm 60\text{ px}$ radius using template matching. If located, the coordinates are auto-reanchored.

---

## 4. Local Macro & Trajectory Dispatcher

Instead of executing multi-step interactions through individual client-server round-trips, the trajectory engine (`vision_mcp/agent_loop/trajectory.py`) batches steps locally:

- **17 Declarative Primitives**: Focus windows, clicks, text typing, shortcuts, sub-pane captures, vDOM queries, plugin features, and shell commands.
- **Jinja2 Variable Interpolation**: Steps can use variables (`{{sim_time}}`) or reference outputs from earlier steps (`{{steps.step_id.output}}`).
- **Post-Condition Assertions**: Automatically checks step exit codes, substring matches, or pixel deltas before proceeding.
- **Performance**: A typical 9-step EDA simulation run executes in **~5.7 seconds locally**, eliminating ~14,400 tokens and 30+ seconds of network latency.

---

## 5. Event-Driven Quiescence (XDamage)

Instead of relying on arbitrary `sleep()` calls, the quiescence monitor (`vision_mcp/hal/quiescence.py`) tracks X11 damage events (`XDamageNotify`). Physical actions wait until pixel updates stop for a configurable settle window (e.g. 150ms), ensuring reliable interaction with animated or rendering UIs.
