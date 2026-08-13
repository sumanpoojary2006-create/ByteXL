## Introduction

A doctoral student in 2006 adds a fifth layer to a network that works perfectly well with four, retrains it, and gets a worse result. She checks the mathematics, which is right. She checks the new code against the four-layer version, which is identical apart from the extra layer. She adds a sixth, half expecting the trend to reverse, and it gets worse again.

She is not making a mistake, and she is not alone. Between 1990 and 2010 a great many capable researchers tried to train deep neural networks and mostly failed.

The theory said depth should help. The networks were built correctly, the mathematics was right, and the training procedure was the same one that worked perfectly well on networks two or three layers deep. Add more layers and performance did not improve; it got worse, and the early layers of a deep network would come out of training looking almost exactly as they had gone in, as though the process had never reached them.

Part of what eventually unlocked deep learning was not a new algorithm or more data. It was replacing a smooth S-shaped curve with a function so simple it looks like a mistake: output the input if it is positive, and zero otherwise.

Understanding why that helped means understanding what the activation function is actually for, and what a badly chosen one quietly does to a deep network.

**Definition:** An `activation function` is the rule applied to a neuron's weighted sum to produce its output. It is what prevents stacked layers from collapsing into a single layer, and its shape determines how well a correction can travel back through a deep network during training.

![Visual explanation of introduction](https://s3.ap-south-1.amazonaws.com/static.bytexl.app/uploads/44sjn9mdv/content/images/05_section_introduction.png)

## The Three Common Choices

Three functions cover most of what you will meet.

- **Sigmoid** squashes any input into the range 0 to 1, following a smooth S.
- **Tanh** does the same into the range −1 to +1, so its output is centred on zero.
- **ReLU**, the rectified linear unit, returns the input unchanged if positive and zero otherwise.

Reading the code below: the three functions at the top are one line each and are the entire subject of the lesson. Everything after `FUNCTIONS` is plotting, a text chart that marks a star wherever the curve passes close to a given height. The table of numbers matters more than the drawing.

<iframe
 frameBorder="0"
 height="350px"  
 src="https://onecompiler.com/embed/python/44xvzjsfa" 
 width="100%"
></iframe>

```
  input   sigmoid      tanh      ReLU
--------------------------------------
     -6    0.0025   -1.0000    0.0000
     -3    0.0474   -0.9951    0.0000
     -1    0.2689   -0.7616    0.0000
   -0.5    0.3775   -0.4621    0.0000
      0    0.5000    0.0000    0.0000
    0.5    0.6225    0.4621    0.5000
      1    0.7311    0.7616    1.0000
      3    0.9526    0.9951    3.0000
      6    0.9975    1.0000    6.0000

The same three, drawn across inputs from -6 to +6

sigmoid, output range 0.0 to 1.0
   1.0 |                  *******
   0.9 |               ***
   0.7 |              *
   0.6 |             *
   0.5 |            *
   0.4 |           *
   0.3 |          *
   0.1 |       ***
   0.0 |*******
       +-------------------------
        -6         0        +6

tanh, output range -1.0 to 1.0
   1.0 |               **********
   0.7 |              *
   0.5 |             *
   0.2 |
   0.0 |            *
  -0.2 |
  -0.5 |           *
  -0.7 |          *
  -1.0 |**********
       +-------------------------
        -6         0        +6

ReLU, output range 0.0 to 6.0
   6.0 |                        *
   5.2 |                      **
   4.5 |                     *
   3.8 |                   **
   3.0 |                  *
   2.2 |                **
   1.5 |               *
   0.8 |             **
   0.0 |*************
       +-------------------------
        -6         0        +6
```

| In the code | The function | Shape to notice |
| --- | --- | --- |
| `1 / (1 + math.exp(-z))` | Sigmoid | Flattens at both ends, never leaves 0 to 1 |
| `math.tanh(z)` | Tanh | Same S, but centred on zero |
| `max(0.0, z)` | ReLU | Exactly zero on the left, a straight ramp on the right |
| The star plot | Not part of any model | Draws each curve so the flattening is visible |

The shapes tell most of the story.

**Sigmoid and tanh flatten out at both ends.** Look at the sigmoid rows for inputs of 3 and 6: the outputs are 0.9526 and 0.9975, barely different despite the input having doubled. The same happens at the negative end. Beyond roughly plus or minus 4, the function has essentially stopped responding.

**ReLU does not flatten on the positive side.** It keeps rising forever, at a constant rate, and it is exactly zero for every negative input.

**Only tanh is centred on zero.** Sigmoid outputs are always positive, which means every neuron in the next layer receives only positive inputs, and that biases how its weights can move during training.

![Visual explanation of activation functions](https://s3.ap-south-1.amazonaws.com/static.bytexl.app/uploads/44sjn9mdv/content/images/05_activation_functions.png)

## What Steepness Has to Do With Learning

The shapes matter because of how training works. A network learns by asking, for each weight, whether nudging it up or down would reduce the error. That question is answered by how steep the activation function is at the neuron's current operating point.

Where the function is steep, a small change in the weighted sum produces a noticeable change in the output, so the weight has visible influence and can be adjusted usefully. Where the function is flat, changing the weight barely moves the output, so there is almost nothing to learn from.

Reading the code below: the three `_slope` functions give the steepness of each curve at a point, which is its derivative. You do not need the calculus to read the table; treat each one as a black box answering "how much does the output move if the input moves a little here". The rest is a printed table.

<iframe
 frameBorder="0"
 height="350px"  
 src="https://onecompiler.com/embed/python/44xvzjsrz" 
 width="100%"
></iframe>

```
How steep each function is, which is how much a weight change matters

  input    sigmoid       tanh     ReLU
--------------------------------------
     -8    0.00034    0.00000      0.0
     -4    0.01766    0.00134      0.0
     -2    0.10499    0.07065      0.0
      0    0.25000    1.00000      0.0
      2    0.10499    0.07065      1.0
      4    0.01766    0.00134      1.0
      8    0.00034    0.00000      1.0

Steepest sigmoid slope anywhere: 0.25, at input 0
Sigmoid slope at input 8:        0.00034

A neuron whose total is 8 has essentially stopped responding to change.
It is said to be saturated.
```

| In the code | What it reports | Why it matters |
| --- | --- | --- |
| `sigmoid_slope(z)` | Steepness of sigmoid at z | Peaks at 0.25 and falls away fast |
| `tanh_slope(z)` | Steepness of tanh at z | Peaks at 1.0, but collapses even faster off centre |
| `relu_slope(z)` | Steepness of ReLU at z | Exactly 1 for any positive input, at any size |
| `sigmoid_slope(8)` | 0.00034 | A saturated neuron: still outputs, no longer learns |

Drag z below. The top strip is the output, the bottom strip is the slope, and the right-hand panel carries that slope forward through several layers, which is the subject of the next section.

<iframe
 frameBorder="0"
 height="620px" data-visualizer="activation_explorer.html" src="data:text/html;base64,<!doctype html>
<html lang="en">
<head>
<meta charset="utf-8">
<meta name="viewport" content="width=device-width, initial-scale=1">
<title>Activation Explorer</title>
<style>
  :root {
    --bg: #12161d; --line: #2c3542; --text: #e6ebf2; --muted: #8b97a8;
    --accent: #f2994a; --dim: #3a4453;
    --sig: #f2994a; --tanh: #5b8def; --relu: #56c288;
  }
  * { box-sizing: border-box; }
  html, body { margin: 0; background: var(--bg); color: var(--text);
    font-family: Inter, ui-sans-serif, system-ui, -apple-system, "Segoe UI", sans-serif; }
  .wrap { padding: 18px 20px 20px; max-width: 900px; margin: 0 auto; }
  .title { font-size: 11px; letter-spacing: .18em; text-transform: uppercase;
    color: var(--muted); text-align: center; }
  .formula { text-align: center; font-family: ui-monospace, SFMono-Regular, Menlo, monospace;
    font-size: 15px; margin: 6px 0 14px;
    display: flex; flex-wrap: wrap; justify-content: center; gap: 4px 20px; }
  .formula span { white-space: nowrap; }
  .swatch { display: inline-block; width: 9px; height: 9px; border-radius: 2px; margin-right: 5px; }
  .readout { background: #0d1117; border: 1px solid var(--line); border-radius: 6px;
    padding: 9px 12px; font-family: ui-monospace, Menlo, monospace;
    font-size: 13px; text-align: center; }
  .verdict { text-align: center; font-size: 13px; line-height: 1.5;
    margin: 10px 0 14px; min-height: 38px; color: var(--accent); }
  .control { display: flex; align-items: center; gap: 12px; margin-bottom: 16px; }
  .control label { font-family: ui-monospace, Menlo, monospace; font-size: 13px;
    color: var(--muted); white-space: nowrap; }
  .control output { font-family: ui-monospace, Menlo, monospace; font-size: 13px;
    width: 46px; text-align: right; color: var(--accent); }
  input[type=range] { flex: 1; -webkit-appearance: none; appearance: none; height: 4px;
    border-radius: 2px; background: var(--dim); outline: none; }
  input[type=range]::-webkit-slider-thumb { -webkit-appearance: none; appearance: none;
    width: 15px; height: 15px; border-radius: 50%; background: var(--accent); cursor: pointer; }
  input[type=range]::-moz-range-thumb { width: 15px; height: 15px; border: 0;
    border-radius: 50%; background: var(--accent); cursor: pointer; }
  .grid { display: grid; grid-template-columns: 1fr 250px; gap: 20px; align-items: start; }
  @media (max-width: 700px) { .grid { grid-template-columns: 1fr; }
    .formula { font-size: 13px; } .wrap { padding: 14px 14px 16px; } }
  svg { width: 100%; display: block; }
  table { width: 100%; border-collapse: collapse; font-size: 12px; margin-bottom: 14px; }
  th, td { padding: 5px 6px; text-align: right; border-bottom: 1px solid var(--line); }
  th { color: var(--muted); font-weight: 500; }
  td:first-child, th:first-child { text-align: left; }
  .num { font-family: ui-monospace, Menlo, monospace; font-variant-numeric: tabular-nums; }
  .sub { font-size: 11px; letter-spacing: .1em; text-transform: uppercase;
    color: var(--muted); margin-bottom: 6px; }
  .note { font-size: 11px; color: var(--muted); line-height: 1.5; margin-top: 10px; }
</style>
</head>
<body>
<div class="wrap">

  <div class="title">Activation Explorer</div>
  <div class="formula">
    <span><i class="swatch" style="background:var(--sig)"></i>sigmoid</span>
    <span><i class="swatch" style="background:var(--tanh)"></i>tanh</span>
    <span><i class="swatch" style="background:var(--relu)"></i>ReLU</span>
  </div>

  <div class="readout" id="readout"></div>
  <div class="verdict" id="verdict"></div>

  <div class="control">
    <label for="z">weighted sum z</label>
    <input type="range" id="z" min="-8" max="8" step="0.1" value="0">
    <output id="zOut">0.0</output>
  </div>

  <div class="grid">
    <div>
      <svg id="chart" viewBox="0 0 560 260" role="img"
           aria-label="Activation outputs and slopes against the weighted sum"></svg>
    </div>

    <div>
      <div class="sub">At this z</div>
      <table>
        <tr><th></th><th>output</th><th>slope</th></tr>
        <tbody id="now"></tbody>
      </table>

      <div class="sub">Correction left after N layers</div>
      <table>
        <tr><th>layers</th><th>sigmoid</th><th>ReLU</th></tr>
        <tbody id="decay"></tbody>
      </table>

      <div class="note">
        A correction is multiplied by each layer's slope on its way back.
        ReLU's slope is exactly 1 wherever the neuron is active, at any size
        of input, which is why depth stopped being self-defeating.
      </div>
    </div>
  </div>

</div>

<script>
const sigmoid = z => 1 / (1 + Math.exp(-z));
const FUNCS = [
  { name: "sigmoid", colour: "var(--sig)",
    f: sigmoid,           slope: z => sigmoid(z) * (1 - sigmoid(z)) },
  { name: "tanh",    colour: "var(--tanh)",
    f: Math.tanh,         slope: z => 1 - Math.tanh(z) ** 2 },
  { name: "ReLU",    colour: "var(--relu)",
    f: z => Math.max(0, z), slope: z => (z > 0 ? 1 : 0) }
];

const NS = "http://www.w3.org/2000/svg";
const chart = document.getElementById("chart");
function el(name, attrs, text) {
  const node = document.createElementNS(NS, name);
  for (const k in attrs) node.setAttribute(k, attrs[k]);
  if (text !== undefined) node.textContent = text;
  return node;
}

const L = 40, R = 548, W = R - L, ZMIN = -8, ZMAX = 8;
const xOf = z => L + ((z - ZMIN) / (ZMAX - ZMIN)) * W;
// Top strip: outputs, -1.1 to 1.1. Bottom strip: slopes, 0 to 1.05.
const OUT = { y: 22, h: 96, lo: -1.1, hi: 1.1 };
const SLP = { y: 152, h: 74, lo: 0, hi: 1.05 };
const yIn = (strip, v) => strip.y + strip.h - ((v - strip.lo) / (strip.hi - strip.lo)) * strip.h;

function path(strip, fn) {
  const pts = [];
  for (let i = 0; i <= 260; i += 1) {
    const z = ZMIN + (i / 260) * (ZMAX - ZMIN);
    const v = fn(z);
    // Clip rather than let ReLU shoot far off the top of the strip.
    if (v > strip.hi) { pts.push(null); continue; }
    pts.push([xOf(z), yIn(strip, Math.max(strip.lo, v))]);
  }
  let d = "", pen = false;
  for (const p of pts) {
    if (!p) { pen = false; continue; }
    d += (pen ? "L" : "M") + p[0].toFixed(1) + " " + p[1].toFixed(1) + " ";
    pen = true;
  }
  return d;
}

function draw(z) {
  chart.textContent = "";

  for (const strip of [OUT, SLP]) {
    const zeroY = yIn(strip, Math.min(Math.max(0, strip.lo), strip.hi));
    chart.appendChild(el("line", { x1: L, y1: zeroY, x2: R, y2: zeroY,
      stroke: "var(--line)", "stroke-width": 1 }));
  }
  chart.appendChild(el("text", { x: L, y: OUT.y - 7, fill: "var(--muted)",
    "font-size": "11px" }, "output, with ReLU clipped at the top because it keeps rising"));
  chart.appendChild(el("text", { x: L, y: SLP.y - 7, fill: "var(--muted)",
    "font-size": "11px" }, "slope, which is how much a weight change matters"));

  for (const fn of FUNCS) {
    chart.appendChild(el("path", { d: path(OUT, fn.f), fill: "none",
      stroke: fn.colour, "stroke-width": 2 }));
    chart.appendChild(el("path", { d: path(SLP, fn.slope), fill: "none",
      stroke: fn.colour, "stroke-width": 2 }));
  }
  const x = xOf(z);
  chart.appendChild(el("line", { x1: x, y1: OUT.y - 4, x2: x, y2: SLP.y + SLP.h,
    stroke: "#ffffff", "stroke-width": 1.5, "stroke-dasharray": "4 3" }));
  for (const fn of FUNCS) {
    const out = fn.f(z);
    if (out <= OUT.hi) {
      chart.appendChild(el("circle", { cx: x, cy: yIn(OUT, out), r: 3.5, fill: fn.colour }));
    }
    chart.appendChild(el("circle", { cx: x, cy: yIn(SLP, fn.slope(z)), r: 3.5, fill: fn.colour }));
  }

  for (const tick of [-8, -4, 0, 4, 8]) {
    chart.appendChild(el("text", { x: xOf(tick), y: 244, fill: "var(--muted)",
      "font-size": "10px", "text-anchor": "middle" }, tick));
  }
  chart.appendChild(el("text", { x: (L + R) / 2, y: 257, fill: "var(--muted)",
    "font-size": "10px", "text-anchor": "middle" }, "z, the neuron's weighted sum"));
}

function verdictFor(z) {
  const s = FUNCS[0].slope(z);
  if (Math.abs(z) >= 6) {
    return "Sigmoid's slope here is " + s.toFixed(5) +
           ". This neuron is saturated: it still produces an output and has stopped learning.";
  }
  if (Math.abs(z) <= 0.4) {
    return "Sigmoid is at its steepest anywhere, and that steepest is still only 0.25.";
  }
  return "Sigmoid slope " + s.toFixed(3) + ", ReLU slope " +
         FUNCS[2].slope(z).toFixed(1) + ". Drag towards either edge and watch the S-curves flatten.";
}

function update() {
  const z = parseFloat(document.getElementById("z").value);
  document.getElementById("zOut").textContent = z.toFixed(1);

  document.getElementById("readout").textContent =
    "z = " + z.toFixed(1) + "   →   " +
    FUNCS.map(fn => fn.name + " " + fn.f(z).toFixed(3)).join(",  ");
  document.getElementById("verdict").textContent = verdictFor(z);

  document.getElementById("now").innerHTML = FUNCS.map(fn =>
    '<tr><td><i class="swatch" style="background:' + fn.colour + '"></i>' + fn.name +
    '</td><td class="num">' + fn.f(z).toFixed(3) +
    '</td><td class="num">' + fn.slope(z).toFixed(5) + '</td></tr>').join("");

  const sigSlope = FUNCS[0].slope(z);
  document.getElementById("decay").innerHTML = [1, 5, 10, 20].map(n => {
    const left = Math.pow(sigSlope, n);
    return '<tr><td class="num">' + n + '</td><td class="num">' +
      (left < 0.001 ? left.toExponential(1) : left.toFixed(3)) +
      '</td><td class="num">1.0</td></tr>';
  }).join("");

  draw(z);
}

document.getElementById("z").addEventListener("input", update);
update();
</script>
</body>
</html>
"
 width="100%"></iframe>

Two numbers in that output decide the rest of this lesson.

**The steepest sigmoid ever gets is 0.25.** Not at some unusual point, but at its very best, right in the middle. Everywhere else it is shallower.

**At an input of 8, the slope is 0.00034.** A neuron that has drifted into that region is `saturated`. It still produces an output, and it has stopped learning, because no adjustment to its weights makes an appreciable difference to what it produces. It is effectively frozen.

ReLU's column is different in kind. Its slope is exactly 1 for every positive input, no matter how large. A ReLU neuron with a weighted sum of 8 is just as responsive as one with a sum of 0.5.

![Visual explanation of what steepness has to do with learning](https://s3.ap-south-1.amazonaws.com/static.bytexl.app/uploads/44sjn9mdv/content/images/05_section_what_steepness_has_to_do_with_learning_simple_v2.png)

## Why Depth Broke

Now the two facts combine into the thing that stalled the field for twenty years.

When a network is trained, the correction is worked out at the output and passed backwards through the layers. At each layer it is multiplied by that layer's slope. So a correction reaching the first layer of a ten-layer network has been multiplied by ten slopes in succession.

Reading the code below: there is no network here and nothing is trained. The whole program is one multiplication repeated, `slope ** depth`, which is what "multiplied by each layer's slope on the way back" amounts to arithmetically. Sigmoid is given its most generous possible slope, 0.25, so the table understates the problem rather than exaggerating it.

<iframe
 frameBorder="0"
 height="350px"  
 src="https://onecompiler.com/embed/python/44xvzjtca" 
 width="100%"
></iframe>

```
A correction travelling back through a deep network gets multiplied
by each layer's slope on the way. Best possible case for each:

 layers        sigmoid     ReLU
--------------------------------
      1       2.50e-01      1.0
      2       6.25e-02      1.0
      5       9.77e-04      1.0
     10       9.54e-07      1.0
     20       9.09e-13      1.0
     50       7.89e-31      1.0

With sigmoid, after 10 layers the signal reaching the first layer is
about 9.5e-07 of its original size, and that is the
most optimistic case. Those early layers barely learn at all.

With ReLU the slope is exactly 1 wherever the neuron is active, so
the signal passes through undiminished however many layers there are.
```

| In the code | What it stands for | Note |
| --- | --- | --- |
| `BEST_SIGMOID = sigmoid_slope(0)` | 0.25 | The best sigmoid ever manages, not a typical value |
| `RELU = 1.0` | ReLU's slope when active | Independent of how large the input is |
| `** depth` | Crossing that many layers | Each layer contributes one multiplication |
| `0.25 ** 10` | About 9.5e-07 | What reaches the first layer of a ten-layer network |
| `1.0 ** 50` | Still 1.0 | Why depth stopped being self-defeating |

This is the `vanishing gradient problem`, and the table states it more brutally than any description.

Multiplying by at most 0.25 ten times leaves under one millionth. Twenty layers leaves about 10 to the power of minus 13. Fifty layers leaves a number with thirty zeros after the decimal point. **The early layers of a deep sigmoid network receive a correction so small that, in ordinary floating-point arithmetic, they receive nothing at all.**

And 0.25 is the optimistic figure, requiring every neuron in every layer to sit exactly at its steepest point. Real neurons drift away from centre, so the true multipliers are smaller and the collapse is faster.

ReLU's column explains the fix. A slope of exactly 1 means the correction passes through unchanged, so the fiftieth layer back receives the same magnitude of signal as the first. Depth stops being self-defeating.

![Visual explanation of why depth broke](https://s3.ap-south-1.amazonaws.com/static.bytexl.app/uploads/44sjn9mdv/content/images/05_section_why_depth_broke_simple_v2.png)

## What ReLU Costs

ReLU is not free, and the honest account matters.

Its slope for negative inputs is exactly zero, which means a neuron whose weighted sum has become negative for every training example receives no correction at all and never recovers. It outputs zero forever and is called a `dead ReLU`. In a large network some proportion of neurons die during training, and while a network usually has enough spare capacity to tolerate it, wasting neurons is not ideal.

The usual remedy is a small variant: `leaky ReLU` gives negative inputs a small non-zero slope, perhaps 0.01, so a struggling neuron retains a faint path back to life.

<table style="border-collapse: collapse; width: 100%; margin: 1rem 0; font-size: 0.95rem;">
  <thead>
    <tr>
      <th style="border: 1px solid #c8d7ea; padding: 10px 12px; text-align: left; background-color: #dceeff; color: #102a43; font-weight: 700;">Function</th>
      <th style="border: 1px solid #c8d7ea; padding: 10px 12px; text-align: left; background-color: #dceeff; color: #102a43; font-weight: 700;">Range</th>
      <th style="border: 1px solid #c8d7ea; padding: 10px 12px; text-align: left; background-color: #dceeff; color: #102a43; font-weight: 700;">Strength</th>
      <th style="border: 1px solid #c8d7ea; padding: 10px 12px; text-align: left; background-color: #dceeff; color: #102a43; font-weight: 700;">Weakness</th>
      <th style="border: 1px solid #c8d7ea; padding: 10px 12px; text-align: left; background-color: #dceeff; color: #102a43; font-weight: 700;">Use for</th>
    </tr>
  </thead>
  <tbody>
    <tr style="background-color: #ffffff;">
      <td style="border: 1px solid #d8e2ef; padding: 9px 12px; vertical-align: top;"><strong>Sigmoid</strong></td>
      <td style="border: 1px solid #d8e2ef; padding: 9px 12px; vertical-align: top;">0 to 1</td>
      <td style="border: 1px solid #d8e2ef; padding: 9px 12px; vertical-align: top;">Reads as a probability</td>
      <td style="border: 1px solid #d8e2ef; padding: 9px 12px; vertical-align: top;">Saturates; slope never exceeds 0.25</td>
      <td style="border: 1px solid #d8e2ef; padding: 9px 12px; vertical-align: top;">The final layer of a yes-or-no classifier</td>
    </tr>
    <tr style="background-color: #f7fbff;">
      <td style="border: 1px solid #d8e2ef; padding: 9px 12px; vertical-align: top;"><strong>Tanh</strong></td>
      <td style="border: 1px solid #d8e2ef; padding: 9px 12px; vertical-align: top;">-1 to 1</td>
      <td style="border: 1px solid #d8e2ef; padding: 9px 12px; vertical-align: top;">Centred on zero; steeper than sigmoid</td>
      <td style="border: 1px solid #d8e2ef; padding: 9px 12px; vertical-align: top;">Still saturates at both ends</td>
      <td style="border: 1px solid #d8e2ef; padding: 9px 12px; vertical-align: top;">Hidden layers in shallow networks; recurrent networks</td>
    </tr>
    <tr style="background-color: #ffffff;">
      <td style="border: 1px solid #d8e2ef; padding: 9px 12px; vertical-align: top;"><strong>ReLU</strong></td>
      <td style="border: 1px solid #d8e2ef; padding: 9px 12px; vertical-align: top;">0 upwards</td>
      <td style="border: 1px solid #d8e2ef; padding: 9px 12px; vertical-align: top;">Slope of 1 when active; very fast to compute</td>
      <td style="border: 1px solid #d8e2ef; padding: 9px 12px; vertical-align: top;">Neurons can die permanently</td>
      <td style="border: 1px solid #d8e2ef; padding: 9px 12px; vertical-align: top;">Hidden layers, as the default choice</td>
    </tr>
    <tr style="background-color: #f7fbff;">
      <td style="border: 1px solid #d8e2ef; padding: 9px 12px; vertical-align: top;"><strong>Leaky ReLU</strong></td>
      <td style="border: 1px solid #d8e2ef; padding: 9px 12px; vertical-align: top;">Unbounded</td>
      <td style="border: 1px solid #d8e2ef; padding: 9px 12px; vertical-align: top;">Keeps a small slope when negative</td>
      <td style="border: 1px solid #d8e2ef; padding: 9px 12px; vertical-align: top;">One more setting to choose</td>
      <td style="border: 1px solid #d8e2ef; padding: 9px 12px; vertical-align: top;">Hidden layers where dead units are a problem</td>
    </tr>
  </tbody>
</table>

Note the last column carefully. Sigmoid did not disappear; it moved. It is a poor choice inside a deep network and remains the right choice for a final layer that must output something readable as a probability. The activation for hidden layers and the activation for the output layer are separate decisions.

![Visual explanation of what relu costs](https://s3.ap-south-1.amazonaws.com/static.bytexl.app/uploads/44sjn9mdv/content/images/05_section_what_relu_costs_simple_v2.png)

## The Output Layer Is a Separate Decision

Everything above concerns hidden layers, where the question is whether a correction can travel back through the network. The final layer answers a different question: what should the answer look like?

Three cases cover almost everything.

- **Predicting a quantity.** Use no activation at all. A price in lakh or a temperature in degrees should not be squashed into 0 to 1, and the layer's raw weighted sum is exactly what is wanted. This is the one place where a linear output is correct rather than a mistake.
- **A yes-or-no decision.** Use sigmoid. Its output between 0 and 1 reads directly as the probability of the positive class, and the threshold that turns it into a decision can then be chosen separately.
- **One of several categories.** Use `softmax`, which is the multi-class generalisation of sigmoid.

Softmax is worth a paragraph because it is the one genuinely new idea here. Given one raw total per class, it exponentiates each and divides by the sum of them all. Two properties follow, and both are what a multi-class output needs. Every result lands between 0 and 1, and they add up to exactly 1, so the layer produces a distribution across the classes rather than several unrelated scores.

The exponentiation matters more than it looks. Because it grows so steeply, a class whose total is modestly higher than the rest ends up with a substantially larger share, so the layer expresses confidence rather than merely ranking. Totals of 2, 1, and 0.1 do not become roughly a third each; they become approximately 0.66, 0.24, and 0.10.

The practical rule is short. **Hidden layers get ReLU because of gradients; the output layer gets whatever shape the answer needs.** Confusing the two produces networks that either cannot train or produce outputs nobody can interpret, and a sigmoid on the output of a regression model is one of the more common versions of the mistake.

![Visual explanation of output activation choice](https://s3.ap-south-1.amazonaws.com/static.bytexl.app/uploads/44sjn9mdv/content/images/05_output_activation_choice.png)

## Your Turn

Work out how flat is too flat, using the slope program.

Find the input at which the sigmoid slope drops below 0.01, then below 0.001. You will find these happen at surprisingly modest inputs, well inside the range a neuron's weighted sum reaches routinely once weights grow during training. That is why saturation is a practical problem rather than a theoretical one.

Then investigate the dead ReLU. Write a version of `relu_slope` for leaky ReLU with a slope of 0.01 on the negative side, and recompute the depth table with it. Check whether 0.01 to the power of 50 is any better than 0.25 to the power of 50. It is not, which tells you something important: leaky ReLU fixes dead neurons, and it does **not** fix vanishing gradients, because a network relying on the leak is back in the multiplying-small-numbers regime. The leak is insurance, not a substitute for neurons being active.

Finally, reason about the opposite failure. If multiplying by numbers below 1 makes the correction vanish, work out what happens when the multipliers are consistently above 1, say 1.5 per layer across 20 layers. Compute it. The resulting problem has its own name and its own remedies, and meeting it now will make it recognisable when you see a training run produce numbers that are not numbers at all.
