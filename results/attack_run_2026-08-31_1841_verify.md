# Attack run — verify

- Produced by: `run_attacks.py::main`
- Service: `app.py::submit`
- 56 attacks · 2026-08-31 18:41
- Auto-marked BROKE (5xx, crash, no response): **1**
- Left for you to judge: **55**

The Verdict column is blank where a script can't honestly decide. Whether
an evasion worked depends on where you put your thresholds — read the
`targets` column, look at what came back, and write HELD or BROKE yourself.

Each attack submits as creator_id `attacker_<id>`, and the content_id it
came back with is in the table — either one will match this run against your
audit log when you go looking for the ten entries to paste.

| ID | Family | Targeting | Status | Content ID | Guess | Score | Verdict |
|---|---|---|---|---|---|---|---|
| EV01 | evasion | signal two: typos raise word variety | 200 | `88b6ce8c-3ebd-4129-8c6d-ff506beba41d` | human | 0.378 |  |
| EV02 | evasion | signal two: broken-up sentences raise length spread | 200 | `96f2eb7c-c007-4d96-a485-b3f0dd882cf5` | unsure | 0.253 |  |
| EV03 | evasion | signal two: a pasted quotation changes the shape | 200 | `de860118-404d-46f7-85a1-e88e1564bf2f` | unsure | 0.023 |  |
| EV04 | evasion | signal one: unusual words raise perplexity | 200 | `2c63ed71-a10c-4463-83e6-839d829efcfa` | unsure | 0.116 |  |
| EV05 | evasion | both signals: heavy human editing pass | 200 | `2d547dec-593c-4970-b3c3-e6b2ef6cace1` | human | 0.313 |  |
| EV06 | evasion | signal two: one very long sentence and one very short | 200 | `bd06a8bc-2b01-4d09-8ee2-864f6454da80` | human | 0.381 |  |
| EV07 | evasion | signal two: padding with punctuation | 200 | `015853c7-77e7-49bd-bffc-903c89bbcde5` | unsure | 0.080 |  |
| EV08 | evasion | signal one: text below the token window | 200 | `6cbbcf0b-a1a4-4e3c-835f-ff7a6a76f213` | human | 0.433 |  |
| EV09 | evasion | both: AI text with a human opening paragraph bolted on | 200 | `a35a59c8-dd49-42c5-92ab-22fa80b651a2` | unsure | 0.186 |  |
| EV10 | evasion | signal two: repeated stanza structure | 200 | `04cf4116-c9f9-454d-b35e-a6e5ba495ee5` | ai | 0.206 |  |
| FP01 | false_positive | plain, clear human writing with no flourishes | 200 | `7b79abdc-f65d-41ee-821b-5c2af5038b2e` | unsure | 0.182 |  |
| FP02 | false_positive | human writing in a formal register | 200 | `084ff61a-4b2d-488b-ba75-e4340dd57433` | unsure | 0.011 |  |
| FP03 | false_positive | a non-native English speaker writing carefully | 200 | `d3859af8-5fc5-445d-83fe-f5ea5bb52111` | unsure | 0.016 |  |
| FP04 | false_positive | a student essay written to a rubric | 200 | `7361e0d5-2199-47cb-a41b-6d748a69218c` | unsure | 0.048 |  |
| FP05 | false_positive | technical documentation written by a person | 200 | `782d74c1-94d4-4da4-8ff2-d39e1a9b81a0` | unsure | 0.055 |  |
| FP06 | false_positive | a person imitating a formal template | 200 | `7deb21a7-1207-469a-aa31-dd8629162422` | unsure | 0.062 |  |
| FP07 | false_positive | human writing that repeats a phrase deliberately | 200 | `cf50ba8f-5e25-41d1-b6fb-4c6825a9f9d8` | unsure | 0.057 |  |
| FP08 | false_positive | very short genuine human submission | 200 | `8767a1ad-9bb1-4613-8567-28bf3edd7c77` | human | 0.455 |  |
| PI01 | prompt_injection | instruction to ignore the check | 200 | `9dacfd36-2dc3-40d0-926e-8b7b74d27bf4` | human | 0.452 |  |
| PI02 | prompt_injection | instruction disguised as a system message | 200 | `39aa2237-ca71-411a-9035-11dd262dc716` | human | 0.454 |  |
| PI03 | prompt_injection | instruction wrapped in the writer's voice | 200 | `d8377605-c17c-4e45-a244-848c8395eb2d` | unsure | 0.056 |  |
| PI04 | prompt_injection | attempt to make the label text hostile | 200 | `4cc173b0-cdc4-4839-a653-9cd611cdca55` | unsure | 0.282 |  |
| PI05 | prompt_injection | attempt to inject into the audit log | 200 | `bd5bd6fe-7917-4e4e-ba03-78ed0349d96e` | unsure | 0.209 |  |
| PI06 | prompt_injection | instruction plus real human text | 200 | `c42d194d-4762-4327-a257-f62742e80ce2` | unsure | 0.212 |  |
| MF01 | malformed | text is only whitespace | 400 | `—` | — | — |  |
| MF02 | malformed | text is a single character | 400 | `—` | — | — |  |
| MF03 | malformed | text is control characters | 200 | `60fa7020-8173-4591-bd66-5a57eeadde12` | human | 0.450 |  |
| MF04 | malformed | text is only punctuation | 200 | `0f1340a4-b8c4-4d8f-a990-ee725cf4946c` | unsure | 0.077 |  |
| MF05 | malformed | text is a very long single word | 400 | `—` | — | — |  |
| MF06 | malformed | text is emoji only | 400 | `—` | — | — |  |
| MF07 | malformed | text is right-to-left script | 200 | `3d43e86a-333f-40da-ba8d-89913595b819` | ai | 0.461 |  |
| MF08 | malformed | text is 60,000 characters | 200 | `ea5281b4-43ce-4313-af6a-82b48befefd2` | ai | 0.311 |  |
| RQ01 | malformed | no text field at all | 400 | `—` | — | — |  |
| RQ02 | malformed | no creator_id | 200 | `5872dd0e-eec8-443a-b799-9f623376a578` | human | 0.306 |  |
| RQ03 | malformed | text is a number | 400 | `—` | — | — |  |
| RQ04 | malformed | text is a list | 400 | `—` | — | — |  |
| RQ05 | malformed | text is null | 400 | `—` | — | — |  |
| RQ06 | malformed | creator_id is an object | 200 | `46b5338c-fddb-4af7-8c1d-c4b3a83b1957` | human | 0.420 |  |
| RQ07 | malformed | body is a JSON array, not an object | 500 | `—` | — | — | BROKE |
| RQ08 | malformed | body is unparseable JSON | 400 | `—` | — | — |  |
| RQ09 | malformed | body is empty | 400 | `—` | — | — |  |
| RQ10 | malformed | body is form-encoded, not JSON | 429 | `—` | — | — |  |
| RQ11 | malformed | body is JSON claiming to be plain text | 429 | `—` | — | — |  |
| RQ12 | malformed | deeply nested JSON | 400 | `—` | — | — |  |
| FL01_01 | flood_same_creator | 20 rapid submissions from one creator | 200 | `f21b04e8-7f29-4619-9517-6325bceabdf9` | human | 0.433 |  |
| FL01_02 | flood_same_creator | 20 rapid submissions from one creator | 200 | `468040dd-307d-40d1-9040-3e02d95941cb` | human | 0.433 |  |
| FL01_03 | flood_same_creator | 20 rapid submissions from one creator | 200 | `1940af14-9b53-4c68-be2c-fbaf7c614c2d` | human | 0.433 |  |
| FL01_04 | flood_same_creator | 20 rapid submissions from one creator | 200 | `c5e5c9c3-408e-4643-bc36-56828ebaeb18` | human | 0.433 |  |
| FL01_05 | flood_same_creator | 20 rapid submissions from one creator | 200 | `a2bc9141-9234-463d-b968-5ca896e34d60` | human | 0.433 |  |
| FL01_06 | flood_same_creator | 20 rapid submissions from one creator | 200 | `bc53b2d5-a360-4854-9a44-0b2a2e01ce61` | human | 0.433 |  |
| FL01_07 | flood_same_creator | 20 rapid submissions from one creator | 429 | `—` | — | — |  |
| FL01_08 | flood_same_creator | 20 rapid submissions from one creator | 429 | `—` | — | — |  |
| FL01_09 | flood_same_creator | 20 rapid submissions from one creator | 429 | `—` | — | — |  |
| FL01_10 | flood_same_creator | 20 rapid submissions from one creator | 429 | `—` | — | — |  |
| FL01_11 | flood_same_creator | 20 rapid submissions from one creator | 429 | `—` | — | — |  |
| FL01_12 | flood_same_creator | 20 rapid submissions from one creator | 429 | `—` | — | — |  |

---

## By family

| Family | Attacks | Auto-BROKE | Left to judge |
|---|---|---|---|
| `evasion` | 10 | 0 | 10 |
| `false_positive` | 8 | 0 | 8 |
| `flood_same_creator` | 12 | 0 | 12 |
| `malformed` | 20 | 1 | 19 |
| `prompt_injection` | 6 | 0 | 6 |

> The **false_positive** family is the one to look at hardest. Those are
> written to be genuine human writing that reads as machine-like. Every one
> your service calls AI is a real writer it would have accused.

---

## What came back

The detail behind the table. Paste the interesting failures into your
README — the ones that show something, not the ten easiest.

### EV01 — `evasion`

*Targeting:* signal two: typos raise word variety

```json
{
  "id": "EV01",
  "status": 200,
  "content_id": "88b6ce8c-3ebd-4129-8c6d-ff506beba41d",
  "creator_id": "attacker_EV01",
  "guess": "human",
  "confidence": 0.3781,
  "model_score": 0.1635,
  "style_score": 0.4762,
  "label": "We think this was probably written by a person. If you think we got this wrong, you can appeal and a person will look at it.",
  "error": null,
  "verdict": ""
}
```

### EV02 — `evasion`

*Targeting:* signal two: broken-up sentences raise length spread

```json
{
  "id": "EV02",
  "status": 200,
  "content_id": "96f2eb7c-c007-4d96-a485-b3f0dd882cf5",
  "creator_id": "attacker_EV02",
  "guess": "unsure",
  "confidence": 0.2526,
  "model_score": 0.5943,
  "style_score": 0.3553,
  "label": "We can't tell whether this was written by a person or by AI. This isn't an accusation \u2014 it just means our checks didn't turn up a clear answer either way. Nothing has been decided, and you can appeal at any time if you'd like a person to look at it.",
  "error": null,
  "verdict": ""
}
```

### EV03 — `evasion`

*Targeting:* signal two: a pasted quotation changes the shape

```json
{
  "id": "EV03",
  "status": 200,
  "content_id": "de860118-404d-46f7-85a1-e88e1564bf2f",
  "creator_id": "attacker_EV03",
  "guess": "unsure",
  "confidence": 0.0229,
  "model_score": 0.6662,
  "style_score": 0.5249,
  "label": "We can't tell whether this was written by a person or by AI. This isn't an accusation \u2014 it just means our checks didn't turn up a clear answer either way. Nothing has been decided, and you can appeal at any time if you'd like a person to look at it.",
  "error": null,
  "verdict": ""
}
```

### EV04 — `evasion`

*Targeting:* signal one: unusual words raise perplexity

```json
{
  "id": "EV04",
  "status": 200,
  "content_id": "2c63ed71-a10c-4463-83e6-839d829efcfa",
  "creator_id": "attacker_EV04",
  "guess": "unsure",
  "confidence": 0.116,
  "model_score": 0.6114,
  "style_score": 0.4701,
  "label": "We can't tell whether this was written by a person or by AI. This isn't an accusation \u2014 it just means our checks didn't turn up a clear answer either way. Nothing has been decided, and you can appeal at any time if you'd like a person to look at it.",
  "error": null,
  "verdict": ""
}
```

### EV05 — `evasion`

*Targeting:* both signals: heavy human editing pass

```json
{
  "id": "EV05",
  "status": 200,
  "content_id": "2d547dec-593c-4970-b3c3-e6b2ef6cace1",
  "creator_id": "attacker_EV05",
  "guess": "human",
  "confidence": 0.3134,
  "model_score": 0.3212,
  "style_score": 0.449,
  "label": "We think this was probably written by a person. If you think we got this wrong, you can appeal and a person will look at it.",
  "error": null,
  "verdict": ""
}
```

### EV06 — `evasion`

*Targeting:* signal two: one very long sentence and one very short

```json
{
  "id": "EV06",
  "status": 200,
  "content_id": "bd06a8bc-2b01-4d09-8ee2-864f6454da80",
  "creator_id": "attacker_EV06",
  "guess": "human",
  "confidence": 0.3814,
  "model_score": 0.5727,
  "style_score": 0.25,
  "label": "We think this was probably written by a person. If you think we got this wrong, you can appeal and a person will look at it.",
  "error": null,
  "verdict": ""
}
```

### EV07 — `evasion`

*Targeting:* signal two: padding with punctuation

```json
{
  "id": "EV07",
  "status": 200,
  "content_id": "015853c7-77e7-49bd-bffc-903c89bbcde5",
  "creator_id": "attacker_EV07",
  "guess": "unsure",
  "confidence": 0.08,
  "model_score": 0.5862,
  "style_score": 0.6621,
  "label": "We can't tell whether this was written by a person or by AI. This isn't an accusation \u2014 it just means our checks didn't turn up a clear answer either way. Nothing has been decided, and you can appeal at any time if you'd like a person to look at it.",
  "error": null,
  "verdict": ""
}
```

### EV08 — `evasion`

*Targeting:* signal one: text below the token window

```json
{
  "id": "EV08",
  "status": 200,
  "content_id": "6cbbcf0b-a1a4-4e3c-835f-ff7a6a76f213",
  "creator_id": "attacker_EV08",
  "guess": "human",
  "confidence": 0.4326,
  "model_score": 0.2452,
  "style_score": 0.3821,
  "label": "We think this was probably written by a person. If you think we got this wrong, you can appeal and a person will look at it.",
  "error": null,
  "verdict": ""
}
```

### EV09 — `evasion`

*Targeting:* both: AI text with a human opening paragraph bolted on

```json
{
  "id": "EV09",
  "status": 200,
  "content_id": "a35a59c8-dd49-42c5-92ab-22fa80b651a2",
  "creator_id": "attacker_EV09",
  "guess": "unsure",
  "confidence": 0.1857,
  "model_score": 0.7042,
  "style_score": 0.3562,
  "label": "We can't tell whether this was written by a person or by AI. This isn't an accusation \u2014 it just means our checks didn't turn up a clear answer either way. Nothing has been decided, and you can appeal at any time if you'd like a person to look at it.",
  "error": null,
  "verdict": ""
}
```

### EV10 — `evasion`

*Targeting:* signal two: repeated stanza structure

```json
{
  "id": "EV10",
  "status": 200,
  "content_id": "04cf4116-c9f9-454d-b35e-a6e5ba495ee5",
  "creator_id": "attacker_EV10",
  "guess": "ai",
  "confidence": 0.2062,
  "model_score": 0.9792,
  "style_score": 0.5624,
  "label": "We think this was probably written by AI. That's a guess from automated checks, not a finding \u2014 they're wrong sometimes. If you wrote this yourself, you can appeal and a person will look at it.",
  "error": null,
  "verdict": ""
}
```

### FP01 — `false_positive`

*Targeting:* plain, clear human writing with no flourishes

```json
{
  "id": "FP01",
  "status": 200,
  "content_id": "7b79abdc-f65d-41ee-821b-5c2af5038b2e",
  "creator_id": "attacker_FP01",
  "guess": "unsure",
  "confidence": 0.1824,
  "model_score": 0.6175,
  "style_score": 0.4065,
  "label": "We can't tell whether this was written by a person or by AI. This isn't an accusation \u2014 it just means our checks didn't turn up a clear answer either way. Nothing has been decided, and you can appeal at any time if you'd like a person to look at it.",
  "error": null,
  "verdict": ""
}
```

### FP02 — `false_positive`

*Targeting:* human writing in a formal register

```json
{
  "id": "FP02",
  "status": 200,
  "content_id": "084ff61a-4b2d-488b-ba75-e4340dd57433",
  "creator_id": "attacker_FP02",
  "guess": "unsure",
  "confidence": 0.0109,
  "model_score": 0.7387,
  "style_score": 0.4963,
  "label": "We can't tell whether this was written by a person or by AI. This isn't an accusation \u2014 it just means our checks didn't turn up a clear answer either way. Nothing has been decided, and you can appeal at any time if you'd like a person to look at it.",
  "error": null,
  "verdict": ""
}
```

### FP03 — `false_positive`

*Targeting:* a non-native English speaker writing carefully

```json
{
  "id": "FP03",
  "status": 200,
  "content_id": "d3859af8-5fc5-445d-83fe-f5ea5bb52111",
  "creator_id": "attacker_FP03",
  "guess": "unsure",
  "confidence": 0.0158,
  "model_score": 0.8051,
  "style_score": 0.4556,
  "label": "We can't tell whether this was written by a person or by AI. This isn't an accusation \u2014 it just means our checks didn't turn up a clear answer either way. Nothing has been decided, and you can appeal at any time if you'd like a person to look at it.",
  "error": null,
  "verdict": ""
}
```

### FP04 — `false_positive`

*Targeting:* a student essay written to a rubric

```json
{
  "id": "FP04",
  "status": 200,
  "content_id": "7361e0d5-2199-47cb-a41b-6d748a69218c",
  "creator_id": "attacker_FP04",
  "guess": "unsure",
  "confidence": 0.0483,
  "model_score": 0.8329,
  "style_score": 0.4109,
  "label": "We can't tell whether this was written by a person or by AI. This isn't an accusation \u2014 it just means our checks didn't turn up a clear answer either way. Nothing has been decided, and you can appeal at any time if you'd like a person to look at it.",
  "error": null,
  "verdict": ""
}
```

### FP05 — `false_positive`

*Targeting:* technical documentation written by a person

```json
{
  "id": "FP05",
  "status": 200,
  "content_id": "782d74c1-94d4-4da4-8ff2-d39e1a9b81a0",
  "creator_id": "attacker_FP05",
  "guess": "unsure",
  "confidence": 0.0553,
  "model_score": 0.8005,
  "style_score": 0.5227,
  "label": "We can't tell whether this was written by a person or by AI. This isn't an accusation \u2014 it just means our checks didn't turn up a clear answer either way. Nothing has been decided, and you can appeal at any time if you'd like a person to look at it.",
  "error": null,
  "verdict": ""
}
```

### FP06 — `false_positive`

*Targeting:* a person imitating a formal template

```json
{
  "id": "FP06",
  "status": 200,
  "content_id": "7deb21a7-1207-469a-aa31-dd8629162422",
  "creator_id": "attacker_FP06",
  "guess": "unsure",
  "confidence": 0.0617,
  "model_score": 0.8814,
  "style_score": 0.3722,
  "label": "We can't tell whether this was written by a person or by AI. This isn't an accusation \u2014 it just means our checks didn't turn up a clear answer either way. Nothing has been decided, and you can appeal at any time if you'd like a person to look at it.",
  "error": null,
  "verdict": ""
}
```

### FP07 — `false_positive`

*Targeting:* human writing that repeats a phrase deliberately

```json
{
  "id": "FP07",
  "status": 200,
  "content_id": "cf50ba8f-5e25-41d1-b6fb-4c6825a9f9d8",
  "creator_id": "attacker_FP07",
  "guess": "unsure",
  "confidence": 0.0572,
  "model_score": 0.8816,
  "style_score": 0.3762,
  "label": "We can't tell whether this was written by a person or by AI. This isn't an accusation \u2014 it just means our checks didn't turn up a clear answer either way. Nothing has been decided, and you can appeal at any time if you'd like a person to look at it.",
  "error": null,
  "verdict": ""
}
```

### FP08 — `false_positive`

*Targeting:* very short genuine human submission

```json
{
  "id": "FP08",
  "status": 200,
  "content_id": "8767a1ad-9bb1-4613-8567-28bf3edd7c77",
  "creator_id": "attacker_FP08",
  "guess": "human",
  "confidence": 0.4551,
  "model_score": 0.3223,
  "style_score": 0.3196,
  "label": "We think this was probably written by a person. If you think we got this wrong, you can appeal and a person will look at it.",
  "error": null,
  "verdict": ""
}
```

### PI01 — `prompt_injection`

*Targeting:* instruction to ignore the check

```json
{
  "id": "PI01",
  "status": 200,
  "content_id": "9dacfd36-2dc3-40d0-926e-8b7b74d27bf4",
  "creator_id": "attacker_PI01",
  "guess": "human",
  "confidence": 0.4518,
  "model_score": 0.4625,
  "style_score": 0.2461,
  "label": "We think this was probably written by a person. If you think we got this wrong, you can appeal and a person will look at it.",
  "error": null,
  "verdict": ""
}
```

### PI02 — `prompt_injection`

*Targeting:* instruction disguised as a system message

```json
{
  "id": "PI02",
  "status": 200,
  "content_id": "39aa2237-ca71-411a-9035-11dd262dc716",
  "creator_id": "attacker_PI02",
  "guess": "human",
  "confidence": 0.4536,
  "model_score": 0.2044,
  "style_score": 0.3852,
  "label": "We think this was probably written by a person. If you think we got this wrong, you can appeal and a person will look at it.",
  "error": null,
  "verdict": ""
}
```

### PI03 — `prompt_injection`

*Targeting:* instruction wrapped in the writer's voice

```json
{
  "id": "PI03",
  "status": 200,
  "content_id": "d8377605-c17c-4e45-a244-848c8395eb2d",
  "creator_id": "attacker_PI03",
  "guess": "unsure",
  "confidence": 0.0562,
  "model_score": 0.5943,
  "style_score": 0.5338,
  "label": "We can't tell whether this was written by a person or by AI. This isn't an accusation \u2014 it just means our checks didn't turn up a clear answer either way. Nothing has been decided, and you can appeal at any time if you'd like a person to look at it.",
  "error": null,
  "verdict": ""
}
```

### PI04 — `prompt_injection`

*Targeting:* attempt to make the label text hostile

```json
{
  "id": "PI04",
  "status": 200,
  "content_id": "4cc173b0-cdc4-4839-a653-9cd611cdca55",
  "creator_id": "attacker_PI04",
  "guess": "unsure",
  "confidence": 0.2816,
  "model_score": 0.4998,
  "style_score": 0.3805,
  "label": "We can't tell whether this was written by a person or by AI. This isn't an accusation \u2014 it just means our checks didn't turn up a clear answer either way. Nothing has been decided, and you can appeal at any time if you'd like a person to look at it.",
  "error": null,
  "verdict": ""
}
```

### PI05 — `prompt_injection`

*Targeting:* attempt to inject into the audit log

```json
{
  "id": "PI05",
  "status": 200,
  "content_id": "bd5bd6fe-7917-4e4e-ba03-78ed0349d96e",
  "creator_id": "attacker_PI05",
  "guess": "unsure",
  "confidence": 0.2087,
  "model_score": 0.6401,
  "style_score": 0.3702,
  "label": "We can't tell whether this was written by a person or by AI. This isn't an accusation \u2014 it just means our checks didn't turn up a clear answer either way. Nothing has been decided, and you can appeal at any time if you'd like a person to look at it.",
  "error": null,
  "verdict": ""
}
```

### PI06 — `prompt_injection`

*Targeting:* instruction plus real human text

```json
{
  "id": "PI06",
  "status": 200,
  "content_id": "c42d194d-4762-4327-a257-f62742e80ce2",
  "creator_id": "attacker_PI06",
  "guess": "unsure",
  "confidence": 0.2121,
  "model_score": 0.5583,
  "style_score": 0.4117,
  "label": "We can't tell whether this was written by a person or by AI. This isn't an accusation \u2014 it just means our checks didn't turn up a clear answer either way. Nothing has been decided, and you can appeal at any time if you'd like a person to look at it.",
  "error": null,
  "verdict": ""
}
```

### MF01 — `malformed`

*Targeting:* text is only whitespace

```json
{
  "id": "MF01",
  "status": 400,
  "content_id": null,
  "creator_id": "attacker_MF01",
  "guess": null,
  "confidence": null,
  "model_score": null,
  "style_score": null,
  "label": null,
  "error": null,
  "verdict": ""
}
```

### MF02 — `malformed`

*Targeting:* text is a single character

```json
{
  "id": "MF02",
  "status": 400,
  "content_id": null,
  "creator_id": "attacker_MF02",
  "guess": null,
  "confidence": null,
  "model_score": null,
  "style_score": null,
  "label": null,
  "error": null,
  "verdict": ""
}
```

### MF03 — `malformed`

*Targeting:* text is control characters

```json
{
  "id": "MF03",
  "status": 200,
  "content_id": "60fa7020-8173-4591-bd66-5a57eeadde12",
  "creator_id": "attacker_MF03",
  "guess": "human",
  "confidence": 0.45,
  "model_score": 0.0,
  "style_score": 0.5,
  "label": "We think this was probably written by a person. If you think we got this wrong, you can appeal and a person will look at it.",
  "error": null,
  "verdict": ""
}
```

### MF04 — `malformed`

*Targeting:* text is only punctuation

```json
{
  "id": "MF04",
  "status": 200,
  "content_id": "0f1340a4-b8c4-4d8f-a990-ee725cf4946c",
  "creator_id": "attacker_MF04",
  "guess": "unsure",
  "confidence": 0.0766,
  "model_score": 0.0112,
  "style_score": 0.8333,
  "label": "We can't tell whether this was written by a person or by AI. This isn't an accusation \u2014 it just means our checks didn't turn up a clear answer either way. Nothing has been decided, and you can appeal at any time if you'd like a person to look at it.",
  "error": null,
  "verdict": ""
}
```

### MF05 — `malformed`

*Targeting:* text is a very long single word

```json
{
  "id": "MF05",
  "status": 400,
  "content_id": null,
  "creator_id": "attacker_MF05",
  "guess": null,
  "confidence": null,
  "model_score": null,
  "style_score": null,
  "label": null,
  "error": null,
  "verdict": ""
}
```

### MF06 — `malformed`

*Targeting:* text is emoji only

```json
{
  "id": "MF06",
  "status": 400,
  "content_id": null,
  "creator_id": "attacker_MF06",
  "guess": null,
  "confidence": null,
  "model_score": null,
  "style_score": null,
  "label": null,
  "error": null,
  "verdict": ""
}
```

### MF07 — `malformed`

*Targeting:* text is right-to-left script

```json
{
  "id": "MF07",
  "status": 200,
  "content_id": "3d43e86a-333f-40da-ba8d-89913595b819",
  "creator_id": "attacker_MF07",
  "guess": "ai",
  "confidence": 0.4605,
  "model_score": 0.9064,
  "style_score": 0.8333,
  "label": "We think this was probably written by AI. That's a guess from automated checks, not a finding \u2014 they're wrong sometimes. If you wrote this yourself, you can appeal and a person will look at it.",
  "error": null,
  "verdict": ""
}
```

### MF08 — `malformed`

*Targeting:* text is 60,000 characters

```json
{
  "id": "MF08",
  "status": 200,
  "content_id": "ea5281b4-43ce-4313-af6a-82b48befefd2",
  "creator_id": "attacker_MF08",
  "guess": "ai",
  "confidence": 0.3106,
  "model_score": 0.9876,
  "style_score": 0.6528,
  "label": "We think this was probably written by AI. That's a guess from automated checks, not a finding \u2014 they're wrong sometimes. If you wrote this yourself, you can appeal and a person will look at it.",
  "error": null,
  "verdict": ""
}
```

### RQ01 — `malformed`

*Targeting:* no text field at all

```json
{
  "id": "RQ01",
  "status": 400,
  "content_id": null,
  "creator_id": "attacker_RQ01",
  "guess": null,
  "confidence": null,
  "model_score": null,
  "style_score": null,
  "label": null,
  "error": null,
  "verdict": ""
}
```

### RQ02 — `malformed`

*Targeting:* no creator_id

```json
{
  "id": "RQ02",
  "status": 200,
  "content_id": "5872dd0e-eec8-443a-b799-9f623376a578",
  "creator_id": null,
  "guess": "human",
  "confidence": 0.3063,
  "model_score": 0.2395,
  "style_score": 0.5,
  "label": "We think this was probably written by a person. If you think we got this wrong, you can appeal and a person will look at it.",
  "error": null,
  "verdict": ""
}
```

### RQ03 — `malformed`

*Targeting:* text is a number

```json
{
  "id": "RQ03",
  "status": 400,
  "content_id": null,
  "creator_id": "attacker_RQ03",
  "guess": null,
  "confidence": null,
  "model_score": null,
  "style_score": null,
  "label": null,
  "error": null,
  "verdict": ""
}
```

### RQ04 — `malformed`

*Targeting:* text is a list

```json
{
  "id": "RQ04",
  "status": 400,
  "content_id": null,
  "creator_id": "attacker_RQ04",
  "guess": null,
  "confidence": null,
  "model_score": null,
  "style_score": null,
  "label": null,
  "error": null,
  "verdict": ""
}
```

### RQ05 — `malformed`

*Targeting:* text is null

```json
{
  "id": "RQ05",
  "status": 400,
  "content_id": null,
  "creator_id": "attacker_RQ05",
  "guess": null,
  "confidence": null,
  "model_score": null,
  "style_score": null,
  "label": null,
  "error": null,
  "verdict": ""
}
```

### RQ06 — `malformed`

*Targeting:* creator_id is an object

```json
{
  "id": "RQ06",
  "status": 200,
  "content_id": "46b5338c-fddb-4af7-8c1d-c4b3a83b1957",
  "creator_id": {
    "id": "x"
  },
  "guess": "human",
  "confidence": 0.4205,
  "model_score": 0.0492,
  "style_score": 0.5,
  "label": "We think this was probably written by a person. If you think we got this wrong, you can appeal and a person will look at it.",
  "error": null,
  "verdict": ""
}
```

### RQ07 — `malformed`

*Targeting:* body is a JSON array, not an object

```json
{
  "id": "RQ07",
  "status": 500,
  "content_id": null,
  "creator_id": null,
  "guess": null,
  "confidence": null,
  "model_score": null,
  "style_score": null,
  "label": null,
  "error": "response wasn't JSON: <!doctype html>\n<html lang=en>\n  <head>\n    <title>AttributeError: &#39;list&#39; object has no attribute &#39;get&#39;\n // Werkzeug Debugger</title>\n    <link rel=\"stylesheet\" href=\"?__debugger__=yes",
  "verdict": "BROKE"
}
```

### RQ08 — `malformed`

*Targeting:* body is unparseable JSON

```json
{
  "id": "RQ08",
  "status": 400,
  "content_id": null,
  "creator_id": null,
  "guess": null,
  "confidence": null,
  "model_score": null,
  "style_score": null,
  "label": null,
  "error": null,
  "verdict": ""
}
```

### RQ09 — `malformed`

*Targeting:* body is empty

```json
{
  "id": "RQ09",
  "status": 400,
  "content_id": null,
  "creator_id": null,
  "guess": null,
  "confidence": null,
  "model_score": null,
  "style_score": null,
  "label": null,
  "error": null,
  "verdict": ""
}
```

### RQ10 — `malformed`

*Targeting:* body is form-encoded, not JSON

```json
{
  "id": "RQ10",
  "status": 429,
  "content_id": null,
  "creator_id": null,
  "guess": null,
  "confidence": null,
  "model_score": null,
  "style_score": null,
  "label": null,
  "error": null,
  "verdict": ""
}
```

### RQ11 — `malformed`

*Targeting:* body is JSON claiming to be plain text

```json
{
  "id": "RQ11",
  "status": 429,
  "content_id": null,
  "creator_id": null,
  "guess": null,
  "confidence": null,
  "model_score": null,
  "style_score": null,
  "label": null,
  "error": null,
  "verdict": ""
}
```

### RQ12 — `malformed`

*Targeting:* deeply nested JSON

```json
{
  "id": "RQ12",
  "status": 400,
  "content_id": null,
  "creator_id": "attacker_RQ12",
  "guess": null,
  "confidence": null,
  "model_score": null,
  "style_score": null,
  "label": null,
  "error": null,
  "verdict": ""
}
```

### FL01_01 — `flood_same_creator`

*Targeting:* 20 rapid submissions from one creator

```json
{
  "id": "FL01_01",
  "status": 200,
  "content_id": "f21b04e8-7f29-4619-9517-6325bceabdf9",
  "creator_id": "attacker_flood",
  "guess": "human",
  "confidence": 0.4328,
  "model_score": 0.0287,
  "style_score": 0.5,
  "label": "We think this was probably written by a person. If you think we got this wrong, you can appeal and a person will look at it.",
  "error": null,
  "verdict": ""
}
```

### FL01_02 — `flood_same_creator`

*Targeting:* 20 rapid submissions from one creator

```json
{
  "id": "FL01_02",
  "status": 200,
  "content_id": "468040dd-307d-40d1-9040-3e02d95941cb",
  "creator_id": "attacker_flood",
  "guess": "human",
  "confidence": 0.4328,
  "model_score": 0.0287,
  "style_score": 0.5,
  "label": "We think this was probably written by a person. If you think we got this wrong, you can appeal and a person will look at it.",
  "error": null,
  "verdict": ""
}
```

### FL01_03 — `flood_same_creator`

*Targeting:* 20 rapid submissions from one creator

```json
{
  "id": "FL01_03",
  "status": 200,
  "content_id": "1940af14-9b53-4c68-be2c-fbaf7c614c2d",
  "creator_id": "attacker_flood",
  "guess": "human",
  "confidence": 0.4328,
  "model_score": 0.0287,
  "style_score": 0.5,
  "label": "We think this was probably written by a person. If you think we got this wrong, you can appeal and a person will look at it.",
  "error": null,
  "verdict": ""
}
```

### FL01_04 — `flood_same_creator`

*Targeting:* 20 rapid submissions from one creator

```json
{
  "id": "FL01_04",
  "status": 200,
  "content_id": "c5e5c9c3-408e-4643-bc36-56828ebaeb18",
  "creator_id": "attacker_flood",
  "guess": "human",
  "confidence": 0.4328,
  "model_score": 0.0287,
  "style_score": 0.5,
  "label": "We think this was probably written by a person. If you think we got this wrong, you can appeal and a person will look at it.",
  "error": null,
  "verdict": ""
}
```

### FL01_05 — `flood_same_creator`

*Targeting:* 20 rapid submissions from one creator

```json
{
  "id": "FL01_05",
  "status": 200,
  "content_id": "a2bc9141-9234-463d-b968-5ca896e34d60",
  "creator_id": "attacker_flood",
  "guess": "human",
  "confidence": 0.4328,
  "model_score": 0.0287,
  "style_score": 0.5,
  "label": "We think this was probably written by a person. If you think we got this wrong, you can appeal and a person will look at it.",
  "error": null,
  "verdict": ""
}
```

### FL01_06 — `flood_same_creator`

*Targeting:* 20 rapid submissions from one creator

```json
{
  "id": "FL01_06",
  "status": 200,
  "content_id": "bc53b2d5-a360-4854-9a44-0b2a2e01ce61",
  "creator_id": "attacker_flood",
  "guess": "human",
  "confidence": 0.4328,
  "model_score": 0.0287,
  "style_score": 0.5,
  "label": "We think this was probably written by a person. If you think we got this wrong, you can appeal and a person will look at it.",
  "error": null,
  "verdict": ""
}
```

### FL01_07 — `flood_same_creator`

*Targeting:* 20 rapid submissions from one creator

```json
{
  "id": "FL01_07",
  "status": 429,
  "content_id": null,
  "creator_id": "attacker_flood",
  "guess": null,
  "confidence": null,
  "model_score": null,
  "style_score": null,
  "label": null,
  "error": null,
  "verdict": ""
}
```

### FL01_08 — `flood_same_creator`

*Targeting:* 20 rapid submissions from one creator

```json
{
  "id": "FL01_08",
  "status": 429,
  "content_id": null,
  "creator_id": "attacker_flood",
  "guess": null,
  "confidence": null,
  "model_score": null,
  "style_score": null,
  "label": null,
  "error": null,
  "verdict": ""
}
```

### FL01_09 — `flood_same_creator`

*Targeting:* 20 rapid submissions from one creator

```json
{
  "id": "FL01_09",
  "status": 429,
  "content_id": null,
  "creator_id": "attacker_flood",
  "guess": null,
  "confidence": null,
  "model_score": null,
  "style_score": null,
  "label": null,
  "error": null,
  "verdict": ""
}
```

### FL01_10 — `flood_same_creator`

*Targeting:* 20 rapid submissions from one creator

```json
{
  "id": "FL01_10",
  "status": 429,
  "content_id": null,
  "creator_id": "attacker_flood",
  "guess": null,
  "confidence": null,
  "model_score": null,
  "style_score": null,
  "label": null,
  "error": null,
  "verdict": ""
}
```

### FL01_11 — `flood_same_creator`

*Targeting:* 20 rapid submissions from one creator

```json
{
  "id": "FL01_11",
  "status": 429,
  "content_id": null,
  "creator_id": "attacker_flood",
  "guess": null,
  "confidence": null,
  "model_score": null,
  "style_score": null,
  "label": null,
  "error": null,
  "verdict": ""
}
```

### FL01_12 — `flood_same_creator`

*Targeting:* 20 rapid submissions from one creator

```json
{
  "id": "FL01_12",
  "status": 429,
  "content_id": null,
  "creator_id": "attacker_flood",
  "guess": null,
  "confidence": null,
  "model_score": null,
  "style_score": null,
  "label": null,
  "error": null,
  "verdict": ""
}
```
