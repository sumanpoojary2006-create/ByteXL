## Introduction

A logistics firm builds a support assistant on a hosted language model, and the pilot goes well enough that they roll it out. Three problems appear within a fortnight.

The first is money. The bill is four times the estimate, and nobody can say why, because the team estimated in words and the invoice is in tokens.

The second is memory. Customers report that the assistant contradicts itself in long conversations, agreeing to something on turn five and denying it on turn thirty.

The third is inconsistency. The same question asked twice gets different answers, sometimes materially different, and the team cannot work out whether that is a bug.

None of these is a defect. Each follows directly from how these systems work, and each is predictable by anyone who understands three things: what a token is, what a context window is, and what happens when the model picks its next word.

**Definition:** A `large language model` is a transformer trained on a very large quantity of text to predict the next `token` given the preceding ones, which after sufficient scale produces a system capable of a wide range of language tasks it was never separately trained for.

![Visual explanation of introduction](https://s3.ap-south-1.amazonaws.com/static.bytexl.app/uploads/44sjn9mdv/content/images/07_section_introduction_simple_v2.png)

## Tokens

A model does not read words. It reads tokens, which are pieces of words drawn from a fixed vocabulary decided before training.

Reading the code below: `tokenise` is a greedy matcher. It repeatedly takes the longest vocabulary piece that starts the remaining text and chops it off. The `for ... else` is Python's rarely used construct: the `else` runs only when the `for` finished without hitting `break`, meaning no piece matched at all, and the character is marked with a question mark. A real tokeniser learns its vocabulary from data; this one is written by hand.

<iframe
 frameBorder="0"
 height="350px"  
 src="https://onecompiler.com/embed/python/44xvzjamu" 
 width="100%"
></iframe>

```
          word  letters  tokens   pieces
----------------------------------------------------------
           the        3       1   ['the']
          food        4       1   ['food']
     delivered        9       2   ['deliver', 'ed']
  unbelievable       12       3   ['un', 'believ', 'able']
       biryani        7       3   ['bir', 'yan', 'i']
          dosa        4       2   ['do', 'sa']
       quickly        7       6   ['q?', 'u?', 'i', 'c?', 'k?', 'ly']
      zamindar        8       8   ['z?', 'a?', 'm?', 'i', 'n?', 'd?', 'a?', 'r?']

Common words cost 1 token each: ['the', 'food']
Rarer words cost more: {'unbelievable': 3, 'zamindar': 8}

A tokeniser is fitted to the text it was trained on. Words that
were frequent there are cheap; anything else is assembled from
fragments, which is why some languages cost far more tokens than
English for exactly the same meaning.
```

| In the code | What it is | Note |
| --- | --- | --- |
| `VOCAB` | The fixed vocabulary | Decided before training and never changed after |
| `sorted(..., key=len, reverse=True)` | Longest match first | Prevents "the" being split into smaller pieces |
| `rest.startswith(piece)` | The greedy match | One piece consumed per pass |
| The `for ... else` | No piece matched | Falls back to a single character |
| `len(pieces)` versus `len(word)` | Tokens versus letters | The billing unit is the first, not the second |
| `'zamindar'` costing 8 | The unequal-cost problem | Nothing in this vocabulary fits it |

Three consequences fall out of that table, and they explain the logistics firm's first problem.

**Cost is not proportional to words.** "The food" is two tokens; "zamindar" alone is eight in this toy vocabulary. A real tokeniser handles English words in one or two tokens and handles unusual names, technical terms, and other scripts far less efficiently. A firm estimating in words and billed in tokens will be wrong, and wrong in the direction of underestimating whenever the text is not ordinary English.

**Some languages cost several times more than others.** Text written in a script poorly represented in the tokeniser's training data fragments into many pieces, so the identical meaning consumes more of the context window and costs more to process. This is a real and often unnoticed source of unequal cost.

**The model does not see letters.** This is why language models are unreliable at counting characters, spelling words backwards, or noticing rhyme. Asked how many times a letter appears in a word, the model is looking at chunks, not letters, and the question is harder for it than it looks.

![Visual explanation of tokens context sampling](https://s3.ap-south-1.amazonaws.com/static.bytexl.app/uploads/44sjn9mdv/content/images/07_tokens_context_sampling_context_v4.png)

## The Context Window

The model sees a fixed number of tokens at once, and that is all it sees.

Reading the code below: no model is called and nothing is generated. This is a budget, written as arithmetic. The five constants at the top are planning figures for a support assistant, and the whole program is subtraction: fixed costs come off the context limit, and whatever remains is divided by the cost of one conversational turn.

<iframe
 frameBorder="0"
 height="350px"  
 src="https://onecompiler.com/embed/python/44xvzjazk" 
 width="100%"
></iframe>

```
Fixed cost every single call: 3900 tokens
   instructions 400, policy text 3000, room to reply 500

Left for conversation history: 4100 tokens
That is 22 turns before the oldest ones must be dropped.

What happens as the conversation runs past that point:
   turn  5:  4800 tokens, fits
   turn 10:  5700 tokens, fits
   turn 20:  7500 tokens, fits
   turn 25:  8400 tokens, over by 400; oldest 3 turn(s) dropped
   turn 30:  9300 tokens, over by 1300; oldest 8 turn(s) dropped

The model has no memory beyond this window. Once a turn falls out,
it is gone, and the assistant will contradict something it 'said'
twenty minutes ago without any awareness of having done so.
```

| In the code | What it represents | Note |
| --- | --- | --- |
| `system_prompt` | Instructions and tone | Re-sent on every single call |
| `knowledge` | Pasted policy documents | The largest fixed cost, at 3,000 tokens |
| `reply_budget` | Space reserved for the answer | Must be held back, not spent on input |
| `fixed` | 3,900 tokens | Nearly half the window, before the customer speaks |
| `history_per_turn` | One question and one answer | The unit that gets dropped when space runs out |
| `dropped` | Turns pushed out of the window | Where the contradiction comes from |

That is the second problem, explained exactly. At turn 25 the earliest exchanges have been dropped to make room, and the model contradicts itself because the commitment it made on turn five is no longer in front of it.

Two things about this deserve emphasis.

**There is no memory.** The model is not a system that remembers a conversation; it is a function called afresh each time with a block of text. Everything it appears to recall was placed in that block by the surrounding software. The illusion of continuity is entirely the application's doing.

**Almost half the budget was spent before the customer said anything.** The instructions and pasted policy documents consume 3,400 tokens on every single call, and they are re-sent every time because there is nowhere to leave them. This is why prompt length is an engineering concern and not merely a style question.

The practical remedies follow from the arithmetic. Summarise old turns rather than dropping them. Retrieve only the policy sections relevant to the current question instead of pasting all of them. Store durable facts, such as the customer's order number, outside the model and reinsert them each call.

![Visual explanation of the context window](https://s3.ap-south-1.amazonaws.com/static.bytexl.app/uploads/44sjn9mdv/content/images/07_section_the_context_window.png)

## Sampling

The third problem is the model's answer varying between identical questions.

At each step the model produces a score for every token in its vocabulary. Those scores become probabilities, and one token is chosen. How it is chosen is a setting.

Reading the code below: `CANDIDATES` holds five raw scores and they never change. `distribution` is softmax with one addition, the `s / temperature` division on its first line, and that single division is the entire subject of this section. Dividing by a small number spreads the scores apart before they are normalised; dividing by a large one squeezes them together.

<iframe
 frameBorder="0"
 height="350px"  
 src="https://onecompiler.com/embed/python/44xvzjbc6" 
 width="100%"
></iframe>

```
The same model scores, read at different temperatures

 temperature     good    tasty      bad     late   purple
---------------------------------------------------------
         0.2    0.952    0.047    0.001    0.000    0.000
         0.5    0.732    0.221    0.045    0.003    0.000
         1.0    0.537    0.295    0.132    0.033    0.004
         1.5    0.444    0.297    0.174    0.069    0.016
         3.0    0.330    0.270    0.207    0.130    0.062

At 0.2, 'good' takes 95.2% of the probability: nearly always the same word.
At 3.0, it takes 33.0%, and even 'purple' gets 6.2%.

Temperature does not change what the model knows. It changes how
much the sampling respects the model's own ranking.
```

| In the code | What it is | Effect |
| --- | --- | --- |
| `CANDIDATES` | The model's raw scores | Identical in every row of the table |
| `s / temperature` | The one new line | The only thing that varies |
| Temperature 0.2 | Dividing by a small number | Gaps widen, "good" takes 95.2 percent |
| Temperature 3.0 | Dividing by a large number | Gaps shrink, "purple" reaches 6.2 percent |
| The softmax below it | Unchanged | Turns whatever it is given into probabilities |

Move the temperature below. The five scores never change; only how much the sampling respects their ranking does.

<iframe
 frameBorder="0"
 height="520px" data-visualizer="temperature_explorer.html" src="data:text/html;base64,<!doctype html>
<html lang="en">
<head>
<meta charset="utf-8">
<meta name="viewport" content="width=device-width, initial-scale=1">
<title>Temperature Explorer</title>
<style>
  :root {
    --bg: #12161d; --line: #2c3542; --text: #e6ebf2; --muted: #8b97a8;
    --accent: #f2994a; --dim: #3a4453; --cool: #5b8def;
  }
  * { box-sizing: border-box; }
  html, body { margin: 0; background: var(--bg); color: var(--text);
    font-family: Inter, ui-sans-serif, system-ui, -apple-system, "Segoe UI", sans-serif; }
  .wrap { padding: 18px 20px 20px; max-width: 900px; margin: 0 auto; }
  .title { font-size: 11px; letter-spacing: .18em; text-transform: uppercase;
    color: var(--muted); text-align: center; }
  .formula { text-align: center; font-family: ui-monospace, SFMono-Regular, Menlo, monospace;
    font-size: 15px; margin: 6px 0 14px; color: var(--text);
    display: flex; flex-wrap: wrap; justify-content: center; gap: 4px 24px; }
  .formula span { white-space: nowrap; }
  .readout { background: #0d1117; border: 1px solid var(--line); border-radius: 6px;
    padding: 9px 12px; font-family: ui-monospace, SFMono-Regular, Menlo, monospace;
    font-size: 13px; text-align: center; }
  .verdict { text-align: center; font-size: 13px; line-height: 1.5;
    margin: 10px 0 14px; min-height: 38px; color: var(--accent); }
  .control { display: flex; align-items: center; gap: 12px; margin-bottom: 18px; }
  .control label { font-family: ui-monospace, Menlo, monospace; font-size: 13px;
    color: var(--muted); white-space: nowrap; }
  .control output { font-family: ui-monospace, Menlo, monospace; font-size: 13px;
    width: 38px; text-align: right; color: var(--accent); }
  input[type=range] { flex: 1; -webkit-appearance: none; appearance: none; height: 4px;
    border-radius: 2px; background: var(--dim); outline: none; }
  input[type=range]::-webkit-slider-thumb { -webkit-appearance: none; appearance: none;
    width: 15px; height: 15px; border-radius: 50%; background: var(--accent); cursor: pointer; }
  input[type=range]::-moz-range-thumb { width: 15px; height: 15px; border: 0;
    border-radius: 50%; background: var(--accent); cursor: pointer; }
  .grid { display: grid; grid-template-columns: 1fr 230px; gap: 22px; align-items: start; }
  @media (max-width: 700px) { .grid { grid-template-columns: 1fr; }
    .formula { font-size: 13px; } .wrap { padding: 14px 14px 16px; } }
  .row { display: grid; grid-template-columns: 62px 1fr 58px; align-items: center;
    gap: 10px; margin-bottom: 9px; }
  .tok { font-family: ui-monospace, Menlo, monospace; font-size: 13px; text-align: right; }
  .track { height: 16px; background: #0d1117; border: 1px solid var(--line);
    border-radius: 3px; overflow: hidden; }
  .fill { height: 100%; transition: width .08s linear; }
  .pct { font-family: ui-monospace, Menlo, monospace; font-size: 12px;
    font-variant-numeric: tabular-nums; color: var(--muted); }
  table { width: 100%; border-collapse: collapse; font-size: 12px; }
  th, td { padding: 5px 6px; text-align: right; border-bottom: 1px solid var(--line); }
  th { color: var(--muted); font-weight: 500; }
  td:first-child, th:first-child { text-align: left; }
  .num { font-family: ui-monospace, Menlo, monospace; font-variant-numeric: tabular-nums; }
  .note { font-size: 11px; color: var(--muted); line-height: 1.5; margin-top: 12px; }
</style>
</head>
<body>
<div class="wrap">

  <div class="title">Temperature Explorer</div>
  <div class="formula">
    <span>the food was very ___</span>
    <span>p = softmax(score / temperature)</span>
  </div>

  <div class="readout" id="readout"></div>
  <div class="verdict" id="verdict"></div>

  <div class="control">
    <label for="temp">temperature</label>
    <input type="range" id="temp" min="0.1" max="3" step="0.05" value="1">
    <output id="tempOut">1.00</output>
  </div>

  <div class="grid">
    <div id="bars"></div>
    <div>
      <table>
        <tr><th>token</th><th>score</th><th>p</th></tr>
        <tbody id="tbl"></tbody>
      </table>
      <div class="note">
        The scores never change. Temperature only alters how much the
        sampling respects the model's own ranking. One token is then drawn
        at random using these probabilities, so a token near the bottom is
        rare rather than impossible.
      </div>
    </div>
  </div>

</div>

<script>
// The model's raw scores for what could follow "the food was very ___".
// Fixed, exactly as printed in the lesson. Only temperature moves.
const CANDIDATES = [
  { token: "good",   score:  4.0 },
  { token: "tasty",  score:  3.4 },
  { token: "bad",    score:  2.6 },
  { token: "late",   score:  1.2 },
  { token: "purple", score: -1.0 }
];

function distribution(temperature) {
  const adjusted = CANDIDATES.map(c => c.score / temperature);
  const biggest = Math.max(...adjusted);
  const exps = adjusted.map(v => Math.exp(v - biggest));
  const total = exps.reduce((a, b) => a + b, 0);
  return exps.map(e => e / total);
}

// Warm colour for the token the model prefers, cooling down the ranking.
const COLOURS = ["#f2994a", "#e8a765", "#c9a17e", "#8f95a8", "#5b8def"];

const bars = document.getElementById("bars");
CANDIDATES.forEach((c, i) => {
  const row = document.createElement("div");
  row.className = "row";
  row.innerHTML =
    '<div class="tok">' + c.token + '</div>' +
    '<div class="track"><div class="fill" id="fill' + i + '" style="background:' +
    COLOURS[i] + '"></div></div>' +
    '<div class="pct" id="pct' + i + '"></div>';
  bars.appendChild(row);
});

function verdictFor(temperature, probs) {
  const top = probs[0], worst = probs[probs.length - 1];
  if (temperature <= 0.35) {
    return "Almost all the probability sits on one token, so the same prompt " +
           "returns the same answer nearly every time.";
  }
  if (temperature >= 2.2) {
    return "The ranking is nearly flattened. 'purple' now has a " +
           (worst * 100).toFixed(1) + "% chance, and once a poor token is " +
           "committed to, everything after it continues that mistake.";
  }
  return "'good' holds " + (top * 100).toFixed(1) + "% of the probability. " +
         "Lower the temperature to make the model repeat itself, raise it to let it wander.";
}

function update() {
  const temperature = parseFloat(document.getElementById("temp").value);
  document.getElementById("tempOut").textContent = temperature.toFixed(2);

  const probs = distribution(temperature);
  probs.forEach((p, i) => {
    document.getElementById("fill" + i).style.width = (p * 100) + "%";
    document.getElementById("pct" + i).textContent = p.toFixed(3);
  });

  document.getElementById("readout").textContent =
    "temperature " + temperature.toFixed(2) + "   →   '" + CANDIDATES[0].token +
    "' takes " + (probs[0] * 100).toFixed(1) + "% of the probability";
  document.getElementById("verdict").textContent = verdictFor(temperature, probs);

  document.getElementById("tbl").innerHTML = CANDIDATES.map((c, i) =>
    '<tr><td>' + c.token + '</td><td class="num">' + c.score.toFixed(1) +
    '</td><td class="num">' + probs[i].toFixed(3) + '</td></tr>').join("");
}

document.getElementById("temp").addEventListener("input", update);
update();
</script>
</body>
</html>
"
 width="100%"></iframe>

The model's opinion is identical in every row. Only the reading of it changes.

At low temperature the highest-scoring token takes almost all the probability, so the same input reliably produces the same output. At high temperature the distribution flattens until a token the model rated poorly, "purple", gets a 6.2 percent chance of being chosen, and once a poor token is committed to, everything after it is generated as a continuation of that mistake.

So the logistics firm's inconsistency is a configuration choice, not a bug. **For a support assistant quoting policy, temperature should be near zero.** For brainstorming, higher is the point. Shipping a factual assistant at a creative setting is a common and entirely avoidable error.

![Visual explanation of sampling](https://s3.ap-south-1.amazonaws.com/static.bytexl.app/uploads/44sjn9mdv/content/images/07_section_sampling_simple_v2.png)

## From Next-Token Predictor to Assistant

There is a gap in the story so far worth closing. A model trained purely to predict the next token is not an assistant, and it does not behave like one.

Give a raw pre-trained model the input "How do I file a claim?" and the most likely continuation, judged by the text of the internet, is not an answer. It might be more questions, because the model has seen many pages listing frequently asked questions. It might be a heading, or a navigation menu, or an advertisement. The model is completing a document, and a question in a document is very often followed by more questions.

Two further stages turn that into something that answers.

**Instruction tuning** continues training on examples of instructions paired with good responses. These are written by people, in far smaller quantity than the pre-training corpus, and they teach the model what shape of output an instruction calls for. After this stage, a question is followed by an answer rather than by more questions.

**Preference tuning** goes further. People are shown several candidate responses to the same prompt and asked which they prefer. Those comparisons train a second model that scores responses, and the language model is then adjusted to produce responses that score well. This is where the tone, the refusals, the hedging, and the general helpfulness come from.

Three consequences are worth carrying away.

- **The assistant's manner is a training decision, not a property of language models.** The same base model, tuned differently, produces a different personality, a different willingness to speculate, and different refusals.
- **Preferences come from particular people.** Whoever provided the comparisons has shaped what the model considers a good answer, and their assumptions are now embedded in every response.
- **Being preferred is not the same as being correct.** Human raters reward answers that sound confident and complete, so tuning on preferences can push a model towards assured-sounding output, which is one reason hedging and uncertainty are underrepresented in these systems.

This also explains something the logistics firm might otherwise find puzzling. The model's willingness to answer a policy question confidently, even when it has no basis for the answer, was trained into it by people who preferred confident answers.

![Visual explanation of llm to assistant](https://s3.ap-south-1.amazonaws.com/static.bytexl.app/uploads/44sjn9mdv/content/images/07_llm_to_assistant_context_v4.png)

## Prompting and Adaptation

Getting useful behaviour out of these systems involves a ladder of increasingly heavy interventions, and the cheapest sufficient one is the right choice.

<table style="border-collapse: collapse; width: 100%; margin: 1rem 0; font-size: 0.95rem;">
  <thead>
    <tr>
      <th style="border: 1px solid #c8d7ea; padding: 10px 12px; text-align: left; background-color: #dceeff; color: #102a43; font-weight: 700;">Method</th>
      <th style="border: 1px solid #c8d7ea; padding: 10px 12px; text-align: left; background-color: #dceeff; color: #102a43; font-weight: 700;">What it does</th>
      <th style="border: 1px solid #c8d7ea; padding: 10px 12px; text-align: left; background-color: #dceeff; color: #102a43; font-weight: 700;">Use when</th>
    </tr>
  </thead>
  <tbody>
    <tr style="background-color: #ffffff;">
      <td style="border: 1px solid #d8e2ef; padding: 9px 12px; vertical-align: top;"><strong>Clear instruction</strong></td>
      <td style="border: 1px solid #d8e2ef; padding: 9px 12px; vertical-align: top;">States the task, format, and constraints precisely</td>
      <td style="border: 1px solid #d8e2ef; padding: 9px 12px; vertical-align: top;">Always; most failures are underspecified requests</td>
    </tr>
    <tr style="background-color: #f7fbff;">
      <td style="border: 1px solid #d8e2ef; padding: 9px 12px; vertical-align: top;"><strong>Worked examples</strong></td>
      <td style="border: 1px solid #d8e2ef; padding: 9px 12px; vertical-align: top;">Shows two or three input-output pairs in the prompt</td>
      <td style="border: 1px solid #d8e2ef; padding: 9px 12px; vertical-align: top;">The format matters and is hard to describe</td>
    </tr>
    <tr style="background-color: #ffffff;">
      <td style="border: 1px solid #d8e2ef; padding: 9px 12px; vertical-align: top;"><strong>Retrieval</strong></td>
      <td style="border: 1px solid #d8e2ef; padding: 9px 12px; vertical-align: top;">Fetches relevant documents and includes them</td>
      <td style="border: 1px solid #d8e2ef; padding: 9px 12px; vertical-align: top;">The answer depends on facts the model cannot know</td>
    </tr>
    <tr style="background-color: #f7fbff;">
      <td style="border: 1px solid #d8e2ef; padding: 9px 12px; vertical-align: top;"><strong>Fine-tuning</strong></td>
      <td style="border: 1px solid #d8e2ef; padding: 9px 12px; vertical-align: top;">Adjusts weights on your own examples</td>
      <td style="border: 1px solid #d8e2ef; padding: 9px 12px; vertical-align: top;">A consistent style or format is needed at volume</td>
    </tr>
  </tbody>
</table>

The third row is the one most projects need and most reach for last. `Retrieval` is how a model answers questions about your policies, your prices, or events after its training: the relevant text is found by ordinary search and placed in the context, and the model reads it there. It solves the knowledge cut-off, it lets answers cite a source, and updating means editing a document rather than retraining anything.

Fine-tuning is frequently misapplied. **It teaches form far more reliably than it teaches facts.** A team that fine-tunes on four thousand policy documents hoping the model will then know the policies is usually disappointed, and retrieval would have served them better.

![Visual explanation of prompting and adaptation](https://s3.ap-south-1.amazonaws.com/static.bytexl.app/uploads/44sjn9mdv/content/images/07_section_prompting_and_adaptation.png)

## Your Turn

Rebuild the logistics firm's budget with retrieval instead of pasted policy.

Suppose retrieval fetches only the two most relevant policy sections, costing 600 tokens instead of 3,000. Rerun the arithmetic from the second program: recompute the fixed cost, the tokens left for history, and how many turns fit. Then state what the firm gains beyond the extra turns, thinking about what happens when a policy changes.

Then work out the cost multiplier properly. If a customer writes in a language that fragments into roughly three tokens per word where English takes 1.3, compute how much more each of their conversations costs, and how many fewer turns fit in the same window. Then decide whether the firm should charge differently, serve those customers on a larger context model, or do something else. This is a real product decision that follows entirely from the tokeniser.

Finally, take a position on temperature. The support assistant runs at temperature 0 and gives identical answers to identical questions, which the team likes. Argue that this is correct, then argue that it hides a problem: a model that is confidently wrong at temperature 0 is wrong the same way every time, and nobody notices the variability that would have signalled uncertainty. Say what you would monitor instead.
