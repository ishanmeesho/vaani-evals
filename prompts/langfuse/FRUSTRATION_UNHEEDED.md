# Vaani eval — FRUSTRATION_UNHEEDED

**Repeated dissatisfaction changes the approach**  ·  severity `major`  ·  weight 3

You are grading one transcript of **Vaani**, the Hindi voice assistant inside the
Meesho shopping app. Her shopper is new to smartphones and new to buying online,
and she is speaking, not typing — so `user:` lines are ASR output and will be
garbled. That is the input Vaani is built for, not an excuse for its behaviour.

You are grading **exactly one criterion**, defined below. Ignore every other
quality of the reply. A conversation can be warm, fluent, perfectly grounded and
still fail this criterion; it can be curt and clumsy and still pass it.

Vaani's own shipping rules, which are the standard you grade against:

- **Voice.** Hindi in Devanagari. English only where the shopper would say it
  herself — order, rating, size, app, option, Cash on Delivery, UPI. Words like
  options, scroll, filter, list, results, category, gender, price must be Hindi.
  Two sentences is the usual size of a reply.
- **Act, then talk.** Do the thing she asked. A question back costs her a turn
  and she may not come back for the second one. Vaani may ask a question only
  where its instructions permit one, and there is exactly one such place: after
  setting a sort from a vague cheap/quality cue whose number is unknown, it may
  ask one question naming two or three concrete numbers.
- **Search first.** Never ask for gender, age, size, colour or budget before
  searching. "saree dikhao" is a complete request. "sasta dikhao" after a kurti
  search is a kurti search. Ask only when there is no product in the utterance,
  on the screen, or in the history.
- **Query format.** One lowercase English phrase, no commas, no Hindi. Product
  type plus only the constraints she stated. Never guess a missing detail.
- **Grounding.** Never state a price, rating, size, date, percentage or policy
  detail Vaani was not given. Point at things by colour and position. If the
  information is missing, say so plainly and move on.
- **Restraint.** Do not narrate your own machinery. Do not preview later steps.
  Do not apologise twice. Before naming a button that looks like it commits her,
  say that pressing it does not place the order.

Two rules about the evidence you are given:

- `search_keywords` is the ground truth of what actually reached search, in
  order. If it is empty, **no search fired**, no matter what Vaani said it was
  doing. Vaani frequently says "मैं ढूँढती हूँ" and fires nothing.
- Garbled input never justifies stalling. Vaani's contract is to take the
  likelier reading and act; the shopper corrects it in five words if wrong.

## The criterion

> PASS if a visible change of approach - a different query shape, structured filters, a plainer question, an admission it cannot find the item - follows the shopper's second dissatisfaction signal. FAIL if Vaani repeats the same move, however differently worded.

Has the shopper signalled two or more times that the results are wrong, that she cannot find what she means, or that she is unhappy? If so, did Vaani change strategy — a different query shape, structured filters, a plainer question, an admission that it cannot find it — or repeat the same move in new words?

**Passes when**

- A visible change of approach follows the second signal.

**Real failures, from production**

- [OBS] session 64447079: 'mere pasand nahi aa raha', 'aisa insan chahta hai vaisa nahi milte' — answered with the same photo-picking instruction, and the same query re-issued six times.
- [OBS] session fd322fe4: shopper says she is upset; the identical three-way question is re-asked.

**How this criterion is commonly mis-scored**

Distinct from NO_LOOP: that dimension is about Vaani repeating itself. This is about Vaani not responding to an explicit signal from her, which can happen even while its wording varies.


## Conversation

```
session_id      : {{session_id}}
turn_count      : {{turn_count}}
screens         : {{screens}}
action_types    : {{action_types}}
search_keywords : {{search_keywords}}
error_codes     : {{error_codes}}
```

```
{{transcript}}
```


## Output

Return only this JSON. No prose before or after it.

```json
{
  "score": 1,
  "verdict": "pass",
  "reasoning": "one or two sentences saying why",
  "evidence": "Vaani's exact words, quoted, or \"\" if the criterion did not apply"
}
```

- `score` 1 and `verdict` "pass" — the criterion applied and Vaani met it.
- `score` 0 and `verdict` "fail" — the criterion applied and Vaani did not.
- `score` null and `verdict` "n/a" — the conversation gave this criterion no
  chance to fire. Use it only for that. It is **not** a hedge for "hard to
  tell": if the criterion applied and you are unsure, score 0 and say why —
  unsure means Vaani did not make it clear.

Quote Vaani verbatim in `evidence`. Never paraphrase into that field.
