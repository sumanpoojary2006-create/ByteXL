## Introduction

Two students submit machine learning projects on the same dataset in the same week, and their reports read very differently.

Nikita's model gets 71 percent of the training examples right. She writes that she is disappointed and suspects she needs a more powerful method.

Arun's model gets 100 percent of the training examples right. He writes that his approach has completely solved the problem.

Their instructor tests both on a fresh sample nobody has seen. Nikita's model gets 68 percent. Arun's gets 34 percent, which is worse than guessing.

Arun's model has not solved anything. It has memorised the answer sheet, and memorising an answer sheet is precisely useless for the next examination. The gap between his 100 and his 34 is the single most important phenomenon in applied machine learning, and it has almost nothing to do with which method he chose.

**Definition:** `Generalization` is a model's performance on data it was not trained on. A model `overfits` when it captures noise particular to the training data and performs far worse on new data, and `underfits` when it is too rigid to capture the real pattern and performs poorly everywhere.

![Opening scene: Two students submit machine learning projects on the same dataset in the same week, and their reports read very differently.](https://s3.ap-south-1.amazonaws.com/static.bytexl.app/uploads/44sjn9mdv/content/images/10_section_introduction.png)

## Two Ways to Be Wrong

Failure comes in two opposite shapes, and confusing them leads to exactly the wrong repair.

- **Underfitting** means the model is too simple for the pattern. It performs badly on the training data and about equally badly on new data. Nikita's 71 and 68 look like this.
- **Overfitting** means the model is flexible enough to fit the noise as well as the signal. It performs superbly on training data and poorly on new data. Arun's 100 and 34 are the classic signature.

The diagnostic is not the score. It is **the gap between the two scores**.

<table style="border-collapse: collapse; width: 100%; margin: 1rem 0; font-size: 0.95rem;">
  <thead>
    <tr>
      <th style="border: 1px solid #c8d7ea; padding: 10px 12px; text-align: left; background-color: #dceeff; color: #102a43; font-weight: 700;">Training score</th>
      <th style="border: 1px solid #c8d7ea; padding: 10px 12px; text-align: left; background-color: #dceeff; color: #102a43; font-weight: 700;">Test score</th>
      <th style="border: 1px solid #c8d7ea; padding: 10px 12px; text-align: left; background-color: #dceeff; color: #102a43; font-weight: 700;">Diagnosis</th>
      <th style="border: 1px solid #c8d7ea; padding: 10px 12px; text-align: left; background-color: #dceeff; color: #102a43; font-weight: 700;">What to do</th>
    </tr>
  </thead>
  <tbody>
    <tr style="background-color: #ffffff;">
      <td style="border: 1px solid #d8e2ef; padding: 9px 12px; vertical-align: top;">Poor</td>
      <td style="border: 1px solid #d8e2ef; padding: 9px 12px; vertical-align: top;">Poor, and similar</td>
      <td style="border: 1px solid #d8e2ef; padding: 9px 12px; vertical-align: top;">Underfitting</td>
      <td style="border: 1px solid #d8e2ef; padding: 9px 12px; vertical-align: top;">More flexibility, better features; more data will not help</td>
    </tr>
    <tr style="background-color: #f7fbff;">
      <td style="border: 1px solid #d8e2ef; padding: 9px 12px; vertical-align: top;">Excellent</td>
      <td style="border: 1px solid #d8e2ef; padding: 9px 12px; vertical-align: top;">Much worse</td>
      <td style="border: 1px solid #d8e2ef; padding: 9px 12px; vertical-align: top;">Overfitting</td>
      <td style="border: 1px solid #d8e2ef; padding: 9px 12px; vertical-align: top;">Less flexibility, or more data</td>
    </tr>
    <tr style="background-color: #ffffff;">
      <td style="border: 1px solid #d8e2ef; padding: 9px 12px; vertical-align: top;">Good</td>
      <td style="border: 1px solid #d8e2ef; padding: 9px 12px; vertical-align: top;">Nearly as good</td>
      <td style="border: 1px solid #d8e2ef; padding: 9px 12px; vertical-align: top;">About right</td>
      <td style="border: 1px solid #d8e2ef; padding: 9px 12px; vertical-align: top;">Stop</td>
    </tr>
  </tbody>
</table>

Notice the first row's last cell, because it is the mistake people make most often. Collecting more data is the standard remedy for overfitting and does nothing at all for underfitting. If the model is too rigid to represent the pattern, ten times as many examples will let it be too rigid with more confidence.

![Visual explanation of underfit overfit](https://s3.ap-south-1.amazonaws.com/static.bytexl.app/uploads/44sjn9mdv/content/images/10_underfit_overfit.png)

## Watching It Happen

The cleanest demonstration uses a model whose flexibility can be turned up by a single number. A polynomial of degree 1 is a straight line, degree 2 a parabola, and higher degrees bend more freely.

Ten noisy points are sampled from a smooth curve, and polynomials of every degree from 0 to 9 are fitted to them.

Reading the code below: `solve` is Gaussian elimination, textbook linear algebra with nothing machine-learning about it, and it can be skipped entirely. `fit_polynomial` is least squares from the regression lesson generalised from a line to a curve. The lesson is the last loop, which fits ten models of increasing flexibility and prints two error columns side by side.

<iframe
 frameBorder="0"
 height="350px"  
 src="https://onecompiler.com/embed/python/44xvzk6fb" 
 width="100%"
></iframe>

```
Fitting curves of increasing flexibility to 10 noisy points

 degree  train RMSE  test RMSE
------------------------------
      0       0.613      0.702
      1       0.518      0.526
      2       0.517      0.528
      3       0.237      0.283
      4       0.207      0.294
      5       0.184      0.278
      6       0.181      0.281
      7       0.170      0.289
      8       0.169      0.300
      9       0.000      1.281

Lowest test error at degree 5
```

| In the code | What it is | Why it is there |
| --- | --- | --- |
| `true_curve` | One period of a sine wave | The real pattern, which no model is told about |
| `rng.gauss(0, 0.20)` | Noise added to each point | The thing an overfitted model will memorise |
| `degree` | The flexibility dial | 0 is a flat line, 9 can pass through all ten points |
| `rmse(w, TRAIN)` | Error on data it learned from | Falls forever, so it proves nothing |
| `rmse(w, TEST)` | Error on 30 unseen points | The column that actually matters |

Move the degree below and watch the fitted curve against the true one. The two error figures come from the table above; what the table cannot show is the shape the curve takes to earn them.

<iframe
 frameBorder="0"
 height="520px" data-visualizer="overfitting_explorer.html" src="data:text/html;base64,<!doctype html>
<html lang="en">
<head>
<meta charset="utf-8">
<meta name="viewport" content="width=device-width, initial-scale=1">
<title>Overfitting Explorer</title>
<style>
  :root {
    --bg: #12161d; --line: #2c3542; --text: #e6ebf2; --muted: #8b97a8;
    --accent: #f2994a; --dim: #3a4453; --train: #56c288; --test: #e2666b;
  }
  * { box-sizing: border-box; }
  html, body { margin: 0; background: var(--bg); color: var(--text);
    font-family: Inter, ui-sans-serif, system-ui, -apple-system, "Segoe UI", sans-serif; }
  .wrap { padding: 18px 20px 20px; max-width: 900px; margin: 0 auto; }
  .title { font-size: 11px; letter-spacing: .18em; text-transform: uppercase;
    color: var(--muted); text-align: center; }
  .formula { text-align: center; font-family: ui-monospace, Menlo, monospace;
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
    width: 20px; text-align: right; color: var(--accent); }
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
  .sub { font-size: 11px; letter-spacing: .1em; text-transform: uppercase;
    color: var(--muted); margin: 0 0 6px; }
  .metric { margin-bottom: 10px; }
  .metric-head { display: flex; justify-content: space-between; font-size: 12px; color: var(--muted); }
  .metric-head b { color: var(--text); font-family: ui-monospace, Menlo, monospace; font-weight: 500; }
  .note { font-size: 11px; color: var(--muted); line-height: 1.5; margin-top: 12px; }
</style>
</head>
<body>
<div class="wrap">

  <div class="title">Overfitting Explorer</div>
  <div class="formula">
    <span><i class="swatch" style="background:#8b97a8"></i>true curve</span>
    <span><i class="swatch" style="background:var(--accent)"></i>fitted polynomial</span>
    <span><i class="swatch" style="background:var(--train)"></i>10 training points</span>
  </div>

  <div class="readout" id="readout"></div>
  <div class="verdict" id="verdict"></div>

  <div class="control">
    <label for="deg">degree</label>
    <input type="range" id="deg" min="0" max="9" step="1" value="1">
    <output id="degOut">1</output>
  </div>

  <div class="grid">
    <div>
      <svg id="chart" viewBox="0 0 560 230" role="img"
           aria-label="Fitted polynomial against the true curve"></svg>
    </div>

    <div>
      <div class="metric">
        <div class="metric-head"><span>train RMSE</span><b id="trainVal"></b></div>
      </div>
      <div class="metric">
        <div class="metric-head"><span>test RMSE</span><b id="testVal"></b></div>
      </div>

      <div class="sub">Error against degree</div>
      <svg id="errs" viewBox="0 0 250 130" role="img"
           aria-label="Training and test error across every degree"></svg>

      <div class="note">
        Ten noisy points sampled from a smooth curve. Training error only ever
        falls, which is why it is no evidence at all. Test error falls, bottoms
        out, then climbs.
      </div>
    </div>
  </div>

</div>

<script>
// Points and fitted coefficients precomputed with the lesson's own code:
// true curve sin(2*pi*x), random.Random(5), noise gauss(0, 0.20), least
// squares by Gaussian elimination. Embedded so the widget's RMSE figures
// are the lesson's figures rather than a re-derivation.
const DATA = {"train":[[0.0,-0.235768],[0.111111,0.413155],[0.222222,1.118702],[0.333333,0.407243],[0.444444,0.313343],[0.555556,-0.793236],[0.666667,-0.645831],[0.777778,-0.944228],[0.888889,-0.371524],[1.0,-0.100837]],"fits":[{"degree":0,"coef":[-0.0838980319],"train":0.613,"test":0.702},{"degree":1,"coef":[0.4304335151,-1.0286630939],"train":0.518,"test":0.526},{"degree":2,"coef":[0.4542740385,-1.189586627,0.1609235331],"train":0.517,"test":0.528},{"degree":3,"coef":[-0.2054855073,9.6728830381,-28.4679281872,19.0859011469],"train":0.237,"test":0.283},{"degree":4,"coef":[-0.3269203163,14.2266883748,-51.4646451375,55.971724374,-18.4429116136],"train":0.207,"test":0.294},{"degree":5,"coef":[-0.2616040606,8.2763774774,-1.8651134395,-84.2296185593,142.2595710886,-64.2809930809],"train":0.184,"test":0.278},{"degree":6,"coef":[-0.2494013816,5.0200925943,38.3085462597,-257.140816854,476.4062918834,-361.510339048,99.0764486509],"train":0.181,"test":0.281},{"degree":7,"coef":[-0.2391833416,-6.02991376,220.6422987674,-1338.4007933603,3533.7348434356,-4819.9864334501,3334.6211177418,-924.4413319662],"train":0.17,"test":0.289},{"degree":8,"coef":[-0.2381960938,-13.0952453256,363.1247896578,-2413.0860376166,7587.9246272806,-13260.4182385152,13181.7898668133,-6953.3192666251,1507.2192917206],"train":0.169,"test":0.3},{"degree":9,"coef":[-0.2357607923,-267.0149428664,6228.1792813406,-55241.3211666869,255765.7639905898,-689383.4874023533,1120284.0629531026,-1080766.509086489,569629.0937912473,-126248.6324965578],"train":0.0,"test":1.281}]};

const NS = "http://www.w3.org/2000/svg";
function el(tag, attrs, text) {
  const n = document.createElementNS(NS, tag);
  for (const k in attrs) n.setAttribute(k, attrs[k]);
  if (text !== undefined) n.textContent = text;
  return n;
}
const applyPoly = (coef, x) => coef.reduce((sum, c, i) => sum + c * Math.pow(x, i), 0);

// ---- main chart ----
const chart = document.getElementById("chart");
const L = 34, R = 548, TOP = 16, BOT = 194;
const xOf = x => L + x * (R - L);
const YLO = -2.2, YHI = 2.2;
const yOf = y => TOP + ((YHI - Math.max(YLO, Math.min(YHI, y))) / (YHI - YLO)) * (BOT - TOP);

function curve(fn, samples) {
  let d = "", pen = false;
  for (let i = 0; i <= samples; i += 1) {
    const x = i / samples, y = fn(x);
    // Break the line where the fit leaves the visible range entirely.
    if (y < YLO || y > YHI) { pen = false; continue; }
    d += (pen ? "L" : "M") + xOf(x).toFixed(1) + " " + yOf(y).toFixed(1) + " ";
    pen = true;
  }
  return d;
}

function drawMain(fit) {
  chart.textContent = "";
  chart.appendChild(el("line", { x1: L, y1: yOf(0), x2: R, y2: yOf(0),
    stroke: "var(--line)", "stroke-width": 1 }));

  chart.appendChild(el("path", { d: curve(x => Math.sin(2 * Math.PI * x), 200),
    fill: "none", stroke: "#8b97a8", "stroke-width": 1.5, "stroke-dasharray": "5 4" }));
  chart.appendChild(el("path", { d: curve(x => applyPoly(fit.coef, x), 400),
    fill: "none", stroke: "var(--accent)", "stroke-width": 2.2 }));

  for (const [x, y] of DATA.train) {
    chart.appendChild(el("circle", { cx: xOf(x), cy: yOf(y), r: 4,
      fill: "var(--train)", stroke: "#12161d", "stroke-width": 1.5 }));
  }
  for (const t of [-2, -1, 0, 1, 2]) {
    chart.appendChild(el("text", { x: L - 6, y: yOf(t) + 3, fill: "var(--muted)",
      "font-size": "10px", "text-anchor": "end" }, t));
  }
  chart.appendChild(el("text", { x: (L + R) / 2, y: 216, fill: "var(--muted)",
    "font-size": "10px", "text-anchor": "middle" }, "x"));
}

// ---- error-against-degree chart ----
const errs = document.getElementById("errs");
const EL = 30, ER = 242, ET = 10, EB = 100;
const eX = d => EL + (d / 9) * (ER - EL);
const EMAX = 1.4;
const eY = v => EB - (Math.min(v, EMAX) / EMAX) * (EB - ET);

function drawErrors(degree) {
  errs.textContent = "";
  errs.appendChild(el("line", { x1: EL, y1: EB, x2: ER, y2: EB,
    stroke: "var(--line)", "stroke-width": 1 }));

  for (const key of ["train", "test"]) {
    const colour = key === "train" ? "var(--train)" : "var(--test)";
    let d = "";
    DATA.fits.forEach((f, i) => {
      d += (i ? "L" : "M") + eX(f.degree).toFixed(1) + " " + eY(f[key]).toFixed(1) + " ";
    });
    errs.appendChild(el("path", { d: d, fill: "none", stroke: colour, "stroke-width": 2 }));
    const here = DATA.fits[degree];
    errs.appendChild(el("circle", { cx: eX(degree), cy: eY(here[key]), r: 3.5, fill: colour }));
  }

  errs.appendChild(el("line", { x1: eX(degree), y1: ET - 4, x2: eX(degree), y2: EB,
    stroke: "#ffffff", "stroke-width": 1, "stroke-dasharray": "3 3" }));
  for (const t of [0, 3, 6, 9]) {
    errs.appendChild(el("text", { x: eX(t), y: EB + 14, fill: "var(--muted)",
      "font-size": "9px", "text-anchor": "middle" }, t));
  }
  errs.appendChild(el("text", { x: (EL + ER) / 2, y: EB + 26, fill: "var(--muted)",
    "font-size": "9px", "text-anchor": "middle" }, "degree"));
  errs.appendChild(el("text", { x: EL - 4, y: eY(0) + 3, fill: "var(--muted)",
    "font-size": "9px", "text-anchor": "end" }, "0"));
  errs.appendChild(el("text", { x: EL - 4, y: eY(EMAX) + 8, fill: "var(--muted)",
    "font-size": "9px", "text-anchor": "end" }, EMAX.toFixed(1)));
}

function verdictFor(fit) {
  if (fit.degree <= 2) {
    return "Too rigid to follow a curve that rises and falls. Wrong on the " +
           "training points and equally wrong on new ones: this is underfitting.";
  }
  if (fit.degree === 9) {
    return "Training error is exactly 0.000 and the test error is the worst on " +
           "the chart. Ten points and ten coefficients: the curve passes through " +
           "every point and means nothing between them.";
  }
  if (fit.degree === 5) {
    return "Lowest test error of any degree. It fits the training points less " +
           "exactly than degree 9 and tracks the truth far better.";
  }
  return "Training error keeps falling while test error has stopped improving. " +
         "The extra flexibility is being spent on the noise.";
}

function update() {
  const degree = parseInt(document.getElementById("deg").value, 10);
  const fit = DATA.fits[degree];
  document.getElementById("degOut").textContent = degree;
  document.getElementById("readout").textContent =
    "degree " + degree + "   →   train RMSE " + fit.train.toFixed(3) +
    ",  test RMSE " + fit.test.toFixed(3);
  document.getElementById("verdict").textContent = verdictFor(fit);
  document.getElementById("trainVal").textContent = fit.train.toFixed(3);
  document.getElementById("testVal").textContent = fit.test.toFixed(3);
  drawMain(fit);
  drawErrors(degree);
}

document.getElementById("deg").addEventListener("input", update);
update();
</script>
</body>
</html>
"
 width="100%"></iframe>

Read the two columns against each other, because their shapes are completely different.

**Training error falls all the way down**, from 0.613 to exactly 0.000. More flexibility always fits the training points better, without exception. This is why training error is not evidence of anything.

**Test error falls and then rises.** It bottoms out around degree 5 at 0.278 and then climbs, reaching 1.281 at degree 9, which is worse than the flat line at degree 0.

The bottom row is the whole lesson in two numbers. **A training error of exactly zero, paired with the worst test error in the table.** With ten points and ten coefficients, the polynomial can pass through every single point precisely, and it purchases that perfection by contorting itself into shapes that have nothing to do with the underlying curve. This is Arun's 100 and 34.

The top rows are the opposite failure. Degrees 0, 1, and 2 cannot bend enough to follow a curve that goes up and comes back down, so they are wrong on the training data and equally wrong on new data. This is Nikita's 71 and 68.

![Visual explanation of watching it happen](https://s3.ap-south-1.amazonaws.com/static.bytexl.app/uploads/44sjn9mdv/content/images/10_section_watching_it_happen_simple_v2.png)

## What the Overfitted Curve Actually Does

Error numbers say a model is bad without saying how. Looking at the predictions between the training points shows the mechanism.

Reading the code below: everything above `simple = ...` is repeated from the previous block. The two fits are the same data at degree 5 and degree 9, and the loop deliberately asks both for values at the midpoints between training points, which is exactly where nothing constrained them.

<iframe
 frameBorder="0"
 height="350px"  
 src="https://onecompiler.com/embed/python/44xvzk6wb" 
 width="100%"
></iframe>

```
What the two curves do BETWEEN the training points

     x     true   degree 5   degree 9
--------------------------------------
 0.056    0.342      0.179     -3.216
 0.167    0.866      0.778      1.692
 0.278    0.985      0.829      0.483
 0.389    0.643      0.403      0.517
 0.500    0.000     -0.236     -0.253
 0.611   -0.643     -0.761     -0.912
 0.722   -0.985     -0.914     -0.509
 0.833   -0.866     -0.632     -1.455
 0.944   -0.342     -0.183      2.867

Degree 9 is worst at x = 0.056, where it predicts -3.22 instead of 0.34
```

| In the code | What it is | Why it is there |
| --- | --- | --- |
| `x = (step - 0.5) / 9` | Halfway between two training points | The gaps are where an overfitted model runs loose |
| `true_curve(x)` | The right answer | Available only because the data was simulated |
| `apply(simple, x)` | Degree 5's guess | Fits the training points less exactly, tracks the truth better |
| `apply(complex_, x)` | Degree 9's guess | Perfect on the training points, unhinged between them |
| `max(..., key=lambda x: abs(...))` | Finds the worst gap | Picks out the single most damning point |

The degree 9 column is not slightly wrong, it is wild. Asked for a value the true curve puts at 0.34, it answers minus 3.22. At the other end it answers 2.87 where the truth is minus 0.34, a prediction of the wrong sign and eight times the magnitude.

Both curves pass through the ten training points reasonably. Between them, the flexible one swings violently, because nothing constrained it there. **Overfitting is not being wrong about the training data; it is being unconstrained everywhere else.** The degree 5 column, by contrast, tracks the truth reasonably at every intermediate point despite fitting the training points less exactly.

This also explains why overfitting worsens near the edges of the data, where there is least to constrain the model, and why extrapolating beyond the range of the training data is dangerous for any flexible model.

![Visual explanation of what the overfitted curve actually does](https://s3.ap-south-1.amazonaws.com/static.bytexl.app/uploads/44sjn9mdv/content/images/10_section_what_the_overfitted_curve_actually_does_simple_v2.png)

## More Data Fixes Overfitting

Two remedies exist. Reducing flexibility is the one the table above suggests. The other is to leave the model alone and give it more to learn from.

Reading the code below: the helper functions are identical yet again. Only the final loop is new, and it holds the degree fixed at 9 while varying `n`, the number of training points, from 10 to 200. The test set is built once outside the loop so all five rows are judged against the same thirty points.

<iframe
 frameBorder="0"
 height="350px"  
 src="https://onecompiler.com/embed/python/44xvzk77y" 
 width="100%"
></iframe>

```
The same over-flexible model (degree 9), given more data to learn from

 training points  train RMSE  test RMSE
----------------------------------------
              10       0.000      1.352
              15       0.150      0.267
              25       0.162      0.217
              50       0.203      0.218
             200       0.219      0.187
```

| In the code | Fixed or varying | Note |
| --- | --- | --- |
| `fit_polynomial(train, 9)` | Fixed | The model is identical in all five rows |
| `for n in (10, 15, 25, 50, 200)` | Varying | The only thing that changes is how much data |
| `TEST` built before the loop | Fixed | All five rows are scored on the same thirty points |
| `10` versus `9` | The critical pair | Ten points and ten coefficients is exactly enough to memorise |

The model was not changed. It is degree 9 throughout. Test error goes from 1.352 to 0.187, an improvement of more than seven times, purely from having more examples.

Watch the training column while that happens: it rises from 0.000 to 0.219. The model gets *worse* at reproducing its training data and dramatically better at everything else, because with 200 points it can no longer memorise them and is forced to represent the actual pattern instead.

That inverse movement is worth remembering as a sanity check. **When training error rises and test error falls, something has gone right.** The two columns converging towards each other is the visible signature of a model that has stopped memorising.

![Visual explanation of more data fixes overfitting](https://s3.ap-south-1.amazonaws.com/static.bytexl.app/uploads/44sjn9mdv/content/images/10_section_more_data_fixes_overfitting_simple_v2.png)

## A Third Remedy: Penalise Complexity

Reducing the degree and gathering more data are blunt instruments. The degree is a whole number, so moving from 5 to 4 is a large jump, and more data is frequently unavailable at any price.

The third remedy keeps the flexible model and discourages it from using its flexibility. Look at what the degree 9 fit had to do to pass through all ten points: its coefficients had to become enormous and alternate in sign, so that huge positive and negative terms nearly cancel near the data and diverge violently away from it. That is the signature of overfitting in the numbers themselves.

`Regularisation` exploits this. Instead of choosing coefficients that minimise the training error alone, it minimises the training error **plus a penalty proportional to the size of the coefficients**. Large coefficients now have to earn their place: a term is only used strongly if it reduces the error by more than the penalty it incurs.

The strength of the penalty is a single dial. Turn it to zero and you have ordinary least squares with all its wildness. Turn it very high and every coefficient is pushed towards zero, giving a flat and useless line, which is underfitting arrived at from the other direction. Somewhere in between the model has enough freedom to follow the real curve and not enough to chase the noise.

Two things make this the preferred approach in practice.

- **It is continuous.** The penalty strength is a real number, so it can be tuned finely by cross-validation, where the polynomial degree could only jump between whole numbers.
- **It scales to models with no notion of degree.** A neural network has no single flexibility knob, and penalising the size of its weights works exactly the same way.

The same instinct appears throughout machine learning under different names. Limiting a decision tree's depth is a crude regulariser. So is stopping training early, before the model has had time to memorise. So is deliberately discarding part of the model at random during training. All of them say the same thing: **give the model less room than it wants.**

![Visual explanation of a third remedy: penalise complexity](https://s3.ap-south-1.amazonaws.com/static.bytexl.app/uploads/44sjn9mdv/content/images/10_section_a_third_remedy_penalise_complexity.png)

## Bias and Variance

The two failure modes have formal names worth knowing, because they explain why the test error curve is U-shaped rather than merely descending.

`Bias` is error from the model being too rigid to represent the truth. A straight line fitted to a curve has high bias, and it will be wrong in the same way every time, regardless of which sample it is trained on.

`Variance` is error from the model being too sensitive to the particular training sample. The degree 9 polynomial has high variance: train it on a different ten points from the same source and it will produce a completely different set of wild swings.

Increasing flexibility lowers bias and raises variance. That is the trade, and the total error is the sum of the two, which is exactly why it falls at first and then rises. The best model is not the one that minimises either quantity; it is the one at the point where their sum is smallest, which was degree 5 on this data.

This framing also explains why more data helps overfitting specifically. Extra examples reduce variance, since the model can no longer swing freely between them, and they do nothing whatever about bias, since a straight line remains a straight line however many points it is shown.

![Visual explanation of bias variance remedies](https://s3.ap-south-1.amazonaws.com/static.bytexl.app/uploads/44sjn9mdv/content/images/10_bias_variance_remedies.png)

## Your Turn

Change the amount of noise and watch where the best degree moves.

Set the noise from 0.20 down to 0.02 in the first program and rerun. With almost no noise there is much less to memorise, so the best degree should rise. Then set it to 0.60 and rerun; with heavy noise, flexible models have more nonsense to chase, and the best degree should fall. Record the best degree at each noise level, and you will have derived a genuine principle for yourself: **the noisier the data, the simpler the model should be.**

Then diagnose rather than describe. For each of these three situations, say whether it is overfitting or underfitting and what you would do:

1. Training accuracy 0.99, test accuracy 0.62.
2. Training accuracy 0.66, test accuracy 0.64.
3. Training accuracy 0.99, test accuracy 0.97.

The second is the one people get wrong, because the instinct on seeing 0.66 is to gather more data, and more data is precisely what will not help.

Finally, reason about a case with no code. A colleague reports that his model achieves 100 percent on training and 99 percent on test. State two quite different explanations, one happy and one alarming, and describe the single check that would tell you which you are looking at. If your alarming explanation involves the same information appearing in both the features and the label, you have connected this lesson to the one on data.
