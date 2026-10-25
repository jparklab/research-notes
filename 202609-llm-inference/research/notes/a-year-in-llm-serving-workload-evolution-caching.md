---
title: 'A Year in LLM Serving: Workload Evolution, Caching'
id: a-year-in-llm-serving-workload-evolution-caching
tags:
- internal-llm-inference-stacks-7f0c90
- production-measurement
- prefix-caching
- load-balancing
- multi-tenancy
- workload-characterization
created: '2026-10-09T22:54:54.126340Z'
updated: '2026-10-10T14:52:17.048277Z'
source: https://arxiv.org/abs/2608.13573
source_domain: arxiv.org
fetched_at: '2026-10-09T22:54:54.126065Z'
fetch_provider: crawl4ai
status: review
type: note
tier: institutional
content_type: paper
deprecated: false
summary: 'University of Chicago/Harvard researchers with engineers from Chutes (a
  decentralized multi-model LLM serving/compute marketplace, anonymized in the paper
  as ''CompanyX'') release and analyze a full year (2025-04-11 to 2026-04-12) of unsampled,
  request-level production trace data: 6,122,413,756 requests, 35.8 billion input
  tokens, 2.52 billion output tokens, 314,970 users, 9,174 models (3,922 public, 5,252
  private), 875,921 serving instances. Note: this is a multi-tenant cloud serving
  marketplace trace, not a single corporate internal platform like T-Tech''s, but
  its findings generalize to internal multi-model fleets. Key measured findings: (1)
  output token lengths shrank over the year — monthly median output fell from a few
  hundred tokens early in the trace to below 100 tokens near the end, while input
  lengths stayed stable in the thousands of tokens, attributed to growing agentic/tool-call
  workloads replacing long free-text completions; (2) prefix-cache token hit ratios
  are bimodal (most requests see near-zero or near-complete reuse) and temporally
  concentrated — half of same-(user,model) repeat requests arrive within 0.1s, ~80%
  within 10s, and 99% of cache reuse occurs within 15 minutes of the prior request;
  (3) in cache-eviction simulation, simple FIFO/LRU policies match or beat more complex
  state-of-the-art eviction algorithms on LLM prefix-cache workloads, while ARC performs
  substantially worse than LRU at intermediate cache sizes; (4) the paper identifies
  and quantifies a fundamental load-balancing/cache-locality tension: routing to maximize
  prefix-cache hit ratio concentrates traffic on fewer instances (good for cache,
  bad for load balance), while spreading load across instances to balance utilization
  fragments the prefix cache and increases cache replication across the fleet — demonstrated
  with a DeepSeek-V3 case study comparing high-load (traffic spread across instances)
  vs low-load (traffic concentrated on one instance, higher cache hits) regimes over
  60-minute windows. The production routing policy observed selects among least-loaded
  instances, then picks the one with highest expected prefix-cache hits. Cites vLLM,
  SGLang/RadixAttention, DistServe, Splitwise, Mooncake, Preble as related serving-optimization
  work. Trace released publicly at github.com/HarvardMadSys/chutes_workload.'
raw_file: raw/a-year-in-llm-serving-workload-evolution-caching.pdf
doi: arXiv:2608.13573
utility_score: 17.0
citation_count: 0
is_retracted: false
---

A Year in LLM Serving: Workload Evolution, Caching
and Load-Balancing
William Nixon
University of Chicago
Harvard University
Jon Durbin
Chutes
Florian Standhartinger
Chutes
Haryadi S. Gunawi
University of Chicago
Juncheng Yang
Harvard University
Abstract
Large Language Model (LLM) serving has become a crit-
ical cloud workload, and realistic traces are essential for
motivating and benchmarking serving systems. However,
existing LLM serving workload studies remain limited in
scale and scope. They often observe short time periods and
provide limited visibility into how users interact with mod-
els in production. As a result, they do not fully capture how
LLM serving workloads evolve over time or how user-model
interactions shape production traffic.
In this work, we further the understanding of real-world
LLM serving workloads through both a global characteri-
zation and a longitudinal study of a one-year production
trace from CompanyX. Unlike prior studies, our trace cap-
tures full production behavior across many models and users,
including both popular and long-tail models. We analyze
the workload from aggregate, temporal, model-level, and
user-level perspectives, revealing workload evolution and
user-model structure that are typically hidden behind ag-
gregate views. To support future research, we publicly re-
lease the full one-year trace, enabling downstream studies of
production behavior without relying on sampled or syn-
thetically generated workloads. The trace is available at
https://github.com/HarvardMadSys/chutes_workload.
CCS Concepts
• Computer systems organization →Cloud computing;
• Computing methodologies →Machine learning.
Permission to make digital or hard copies of all or part of this work for
personal or classroom use is granted without fee provided that copies
are not made or distributed for profit or commercial advantage and that
copies bear this notice and the full citation on the first page. Copyrights
for components of this work owned by others than the author(s) must
be honored. Abstracting with credit is permitted. To copy otherwise, or
republish, to post on servers or to redistribute to lists, requires prior specific
permission and/or a fee. Request permissions from permissions@acm.org.
Conference’17, Washington, DC, USA
© 2026 Copyright held by the owner/author(s). Publication rights licensed
to ACM.
ACM ISBN 978-1-4503-XXXX-X/2026/04
https://doi.org/XXXXXXX.XXXXXXX
Keywords
LLM serving, workload characterization, production traces,
prefix caching
ACM Reference Format:
William Nixon, Jon Durbin, Florian Standhartinger, Haryadi S. Gu-
nawi, and Juncheng Yang. 2026. A Year in LLM Serving: Workload
Evolution, Caching and Load-Balancing. In . ACM, New York, NY,
USA, 16 pages. https://doi.org/XXXXXXX.XXXXXXX
1
Introduction
Large language models (LLMs) have become a core online
service primitive, powering conversational assistants, code-
generation tools, agentic workflows, retrieval-augmented
generation pipelines, and programmatic API workloads. Serv-
ing these applications at low latency and high through-
put remains challenging because autoregressive LLM infer-
ence is both computationally intensive and highly workload-
dependent. Request arrival patterns determine batching ef-
ficiency and queueing delay; prompt and response lengths
shape the balance between prefill and decode computation;
model popularity influences placement, routing, and load
balancing; and user behavior induces temporal locality, pre-
fix reuse, and repeated-access patterns that affect KV-cache
efficiency [11, 29, 35, 37]. Consequently, realistic production
traces are critical for understanding LLM serving behavior
and for evaluating serving-system designs under representa-
tive operating conditions [21, 23].
Recent studies have characterized LLM serving workloads
and have shown that production traces differ substantially
from synthetic arrival processes, static prompt datasets, and
conventional cloud-service traces. These studies have pro-
vided important insights into bursty request arrivals, prompt
and response length distributions, workload generation, and
KV-cache reuse behavior [18, 21, 23, 25]. However, impor-
tant gaps remain in our understanding of production LLM
serving workloads. First, many existing studies analyze rel-
atively short observation windows, limiting our ability to
study how workloads evolve over longer time scales. Sec-
ond, user–model interactions remain underexplored, even
though modern LLM platforms serve many models with
arXiv:2608.13573v2  [cs.AI]  7 Sep 2026


---

Conference’17, July 2017, Washington, DC, USA
Nixon et al.
Table 1: Comparison with prior interaction datasets
and production LLM workload studies.
Work
Duration
# Requests
# Models
User
Instance
ServeGen [25]
4 mo.
3.54B
12
✓
–
BurstGPT [24]
4 mo.
5.29M
2
–
–
WildChat [33]
13 mo.
1.0M convs.
2
✓
–
LMSYS-Chat-1M [34]
4 mo.
1.0M convs.
25
–
–
ModServe [18]
1 wk
–
–
–
–
Qwen-Bailian [22]
2 h
–
1
–
–
Mooncake [17]
1 h
35.6K
–
–
–
Ours
12 mo.
6.12B
9,174
✓
✓
highly skewed popularity and support users with diverse
access patterns. Third, existing public workloads are often
sampled, anonymized, or summarized, which constrains di-
rect replay and limits downstream analyses of production
behavior. These limitations motivate a longitudinal study
of LLM serving workloads that jointly examines workload
evolution, caching opportunities, and load-balancing impli-
cations.
To bridge this gap, we collect, characterize, and release a
one-year production LLM serving trace from CompanyX. To
the best of our knowledge, this is the first public LLM serving
trace that provides a long observation window, unsampled
request-level records, broad coverage across both popular
and long-tail models, and anonymized user and serving-
instance identifiers. This trace enables analyses that are diffi-
cult to perform from aggregate statistics alone. We study how
LLM serving demand evolves over time, how production us-
age differs across models, and how users interact with those
models. The request-level unsampled information allows for
detailed cache analysis and simulation. We find that cache-
eviction algorithms designed for web and storage workloads
can underperform simple FIFO and LRU policies on LLM
prefix-cache workloads. We also identify a fundamental ten-
sion in LLM serving: load balancing spreads requests across
instances to improve utilization, but doing so can reduce
prefix-cache locality, lowering cache hit ratio and increasing
cache replication.
Our key contributions are as follows:
(1) A year-long production LLM serving trace to sup-
port open research. We collect, characterize, and re-
lease 1 a one-year, unsampled, request-level production
trace from CompanyX, covering billions of requests, thou-
sands of models, anonymized users, serving instances,
token counts, latency, and prefix-cache reuse.
(2) Characterization of workload evolution. We show
that LLM serving workloads are non-stationary over
yearly timescales. Request characteristics shift toward
longer inputs and shorter outputs, changing the relative
1The trace is available at https://github.com/HarvardMadSys/chutes_
workload.
pressure on prefill and decode and making short mea-
surement windows insufficient for capacity planning.
(3) Long-tail model behavior and serving opportuni-
ties. We find that many models receive sparse traffic with
long inter-arrival times, while consecutive inter-arrival
intervals often remain correlated. This structure creates
opportunities to colocate or multiplex low-traffic mod-
els on shared GPUs without treating each model as an
independent always-on service.
(4) User–model interaction structure. We show that users
interact with models in heterogeneous ways: some re-
peatedly use a single model, while others switch across
many models. These patterns are hidden in aggregate
statistics and suggest opportunities for user-aware sched-
uling, placement, and caching.
(5) Prefix-cache behavior in production. We character-
ize prefix-cache reuse at request level and find that to-
ken hit ratios are often bimodal, with most requests see-
ing either near-zero or near-complete reuse. Reuse is
also temporally concentrated, with much of it occurring
within short inter-arrival windows. In simulation, state-
of-the-art cache policies designed for web and storage
workloads often underperform simple FIFO and LRU, mo-
tivating new cache-management policies for LLM prefix
workloads.
(6) Tension between caching and load balancing. We
identify a fundamental tradeoff in LLM serving: routing
related requests to the same host improves prefix-cache
locality and hit ratio, but also increases load imbalance
and cache replication. This tension complicates scheduler
design and motivates joint treatment of routing, place-
ment, and caching.
2
Background
2.1
LLM Inference
LLM inference consists of two main phases: prefill and de-
code. In the prefill phase, the serving system processes the
input prompt and builds the request’s key-value (KV) cache.
In the decode phase, the model generates output tokens au-
toregressively, using the KV cache from previous tokens.
Thus, the cost of a request depends on both input tokens and
output tokens: input length mainly affects prefill cost, while
output length affects how long the request occupies decode
iterations.
This distinction matters for workload analysis. Request ar-
rivals affect batching and queueing, input tokens affect prefill
pressure, output tokens affect decode pressure, and cached
tokens indicate how much prompt work can be avoided
through prefix-cache reuse. Therefore, our trace focuses on


---

A Year in LLM Serving: Workload Evolution, Caching and Load-Balancing
Conference’17, July 2017, Washington, DC, USA
Table 2: Summary of the CompanyX production trace.
Metric
Value
Time span
1 year (2025-04-11 to 2026-04-12)
Requests
6,122,413,756
Input tokens
35,795,761 million
Output tokens
2,522,394 million
Users
314,970
Models
9,174 (3,922 public, 5,252 private)
Serving instances
875,921
request-level timing, model identifiers, user identifiers, to-
ken counts, latency, time-to-first-token, and cached-token
information.
2.2
LLM Workload
Understanding LLM workloads is essential for designing
practical serving systems. Properties such as request arrivals,
token lengths, and user behavior directly shape decisions
around batching, scheduling, caching, routing, and autoscal-
ing. Motivated by this need, prior work has studied and
released LLM workloads from several complementary an-
gles. Public multi-turn datasets capture real conversational
behavior [33, 34], while production studies examine specific
serving phenomena such as KV-cache reuse and inference-
system behavior [17, 18, 22]. Other work focuses more di-
rectly on broader production workload characterization, in-
cluding request dynamics and user-level structure [24, 25].
Table 1 summarizes prior workload-analysis studies and the
traces or public workload artifacts they release.
However, existing public artifacts remain limited for down-
stream workload analysis. Some traces are sampled, some
remove fields such as user identifiers even when those fields
are used in the original study, and others release synthetic
generators rather than full request-level production traces.
These limitations make it difficult to independently study
long-term workload evolution, user–model interactions, or
faithful inter-arrival behavior due to sampling.
To address this gap, we release and analyze a one-year
production trace containing 6.12 billion requests across
9,174 models. The trace retains anonymized user identifiers,
serving-instance identifiers, and serving-side signals such as
TTFT and cached-token counts. This combination enables a
longitudinal and fine-grained study of production LLM serv-
ing: we examine how workloads evolve over time, how users
and models interact, how prefix reuse emerges, and how
these behaviors shape routing and load-balancing decisions.
3
Production Trace Analysis
We analyze a one-year production trace from CompanyX, a
serverless LLM inference platform that serves both platform-
hosted and user-deployed models. Table 2 summarizes the
trace scale: 6.12 billion requests from 314,970 users across
9,174 models. Of these models, 3,922 are public and 5,252 are
Table 3: Key fields available in the CompanyX produc-
tion trace.
Field
Description
Field
Description
request_id
Request ID
endpoint
API endpoint
model
Model identifier
user_id
Anonymized user ID
instance_id
Serving instance
started_at
Start timestamp
completed_at
Completion timestamp
input_token
Input token count
output_token
Output token count
ttft
Time to first token
cached_tokens
Prefix-cached tokens
private. Public models can be invoked by any user and in-
clude both user-published models and platform-hosted mod-
els such as DeepSeek, MiniMax, and Kimi; Private models are
custom models deployed by individual users for restricted
access, including user-fine-tuned variants.
Table 3 lists the fields available in the trace. For each re-
quest, we record its timestamp, endpoint, model, user, and
input/output token counts. We also collect serving-side exe-
cution information, including the instance that handled the
request, completion latency, time to first token (TTFT), and
cached-token counts. These signals let us study production
behavior including prefix-cache reuse and instance-level load
balancing.
Unless otherwise noted, our analysis uses the full year
of text-based API requests, including both streaming and
non-streaming chat and completion endpoints. To provide
representative examples, we highlight three high-traffic
models with distinct workload profiles: DeepSeek-V3.2 [8],
which is primarily used for chat and role-playing; DeepSeek-
R1 [7], which generates long reasoning outputs; and
MiniMax-M2.5 [15], which is heavily used for coding and
agentic workloads. Together, these models highlight several
prominent workload classes and illustrate how production
behavior varies across model types.
The remainder of the paper builds on this trace in stages.
We first characterize aggregate workload structure in this sec-
tion, then examine user and model level behavior (section 4),
study how the workload evolves over the year (section 5),
and analyze prefix caching in production (section 6). Finally,
we use the trace to study the tension between load balanc-
ing and prefix-cache locality: spreading requests improves
balance, while routing related requests to the same instance
improves cache reuse.
3.1
Workload Overview
Aggregate demand is non-stationary. Production demand
changes over both long and short timescales. Figure 1a shows
that daily request volume rises through mid-2025, peaks
around late summer and fall, and then declines into early
2026. Figure 1b shows that daily token volume follows a
similar but not identical trend: it grows quickly early in the


---

Conference’17, July 2017, Washington, DC, USA
Nixon et al.
May
'25
Aug
'25
Nov
'25
Feb
'26
5M
10M
15M
20M
25M
30M
35M
Requests
(a) Daily request rate
May
'25
Aug
'25
Nov
'25
Feb
'26
50B
100B
150B
200B
Total Tokens
(b) Daily token rate
May
'25
Aug
'25
Nov
'25
Feb
'26
100
150
200
250
300
350
400
Unique models
(c) Daily active models
May
'25
Aug
'25
Nov
'25
Feb
'26
0.0M
5.0M
10M
15M
20M
Requests
Chat
Chat Stream
Completion
Completion Stream
Other
(d) Daily API calls
0
4
8
12
16
20
Hour of Day (UTC)
Mon
Tue
Wed
Thu
Fri
Sat
Sun
0.65
0.70
0.75
0.80
Avg requests / week (M)
(e) Request heatmap
Figure 1: Daily request volume, token volume, active models, and API mix evolve differently over the year, showing
that production load is non-stationary and cannot be summarized by request count alone.
trace, remains elevated for much of the year, and drops more
sharply near the end. Similar request volumes can therefore
represent different amounts of serving work.
Active models and API mix shift over the year. The work-
load also changes in breadth and usage mix. Figure 1c shows
that the number of active models per day grows from fewer
than 100 early in the trace to more than 400 at its peak, be-
fore settling at a lower but still elevated level. Much of this
fluctuation comes from user-deployed private models, whose
availability and usage can change quickly. Over the same
period, Figure 1d shows that the API mix shifts: chat-based
traffic becomes more prominent, while completion-based traf-
fic declines, and streaming calls also become less dominant,
with non-streaming functions accounting for a larger share
later in the trace. Thus, production demand evolves not only
in volume, but also in which models are active and how the
platform is used.
Weekly and diurnal patterns persist throughout. These long-
term shifts coexist with a recurring weekly and diurnal pat-
tern. Figure 1e shows that traffic is highest during UTC af-
ternoon and evening hours, especially on weekdays, and
lower during overnight hours and weekends. Taken together,
Figure 1 shows that LLM serving demand cannot be sum-
marized by a fixed request rate or a single growth trend.
Realistic workload analysis must account for changing token
load, model availability, API usage, and recurring weekly
seasonality.
3.2
Token Shape
Requests are often prompt-heavy. Requests span a wide
range of token lengths. Figure 2a shows that input sizes vary
from roughly 102 to 105 tokens, with a heavy tail toward very
long prompts (not shown). Figure 2b shows that output sizes
are more concentrated, mostly between 101 and 103 tokens.
Figure 2c confirms that most requests generate fewer out-
put tokens than input tokens. Together, these distributions
show that the workload is often prompt-heavy, so prefill
100
101
102
103
104
105
Input tokens
0.0
0.2
0.4
0.6
0.8
1.0
CDF
Global
DeepSeek V3.2
Deepseek R1
Minimax M2.5
(a) Input token
100
101
102
103
104
Output tokens
0.0
0.2
0.4
0.6
0.8
1.0
CDF
Global
DeepSeek V3.2
Deepseek R1
Minimax M2.5
(b) Output token
10
2
100
102
Output / input tokens
0.0
0.2
0.4
0.6
0.8
1.0
CDF
Global
DeepSeek V3.2
Deepseek R1
Minimax M2.5
(c) O/I ratio
Figure 2: Request-level token-length distributions for
three representative models against the full population.
The models have distinctive characteristics.
remains an important part of serving cost even when decode
dominates end-to-end runtime.
Highlighted models show distinct usage profiles. The model-
level curves reveal that this global picture combines distinct
usage profiles. MiniMax-M2.5 has longer inputs, shorter out-
puts, and the lowest output-to-input ratio, consistent with
coding / agentic workloads that process large contexts but
return relatively short responses. DeepSeek R1 shows the
opposite tendency as it has heavier output behavior and
the highest output-to-input ratio, consistent with reasoning
workloads that generate longer completions. DeepSeek V3.2
lies closer to the global distribution, matching its more typ-
ical chat and role-play usage. Thus, models with similar
request counts can impose very different serving pressure
depending on whether their traffic is dominated by long
prompts, long generations, or a more balanced mix of both.
3.3
Latency
End-to-end latency is dominated by decode. We decompose
request latency into time to first token (TTFT), which cap-
tures the prefill-side delay before generation, and the re-
maining completion time. Figure 3a shows that end-to-end
latency spans several orders of magnitude, from sub-second
requests to requests lasting tens of seconds. Figure 3b shows
that TTFT is usually only a fraction of total request duration,
indicating that end-to-end latency is dominated by decode.


---

A Year in LLM Serving: Workload Evolution, Caching and Load-Balancing
Conference’17, July 2017, Washington, DC, USA
10
1
100
101
102
End-to-end latency (s)
0.0
0.2
0.4
0.6
0.8
1.0
CDF
Global
DeepSeek V3.2
Deepseek R1
Minimax M2.5
(a) Latency CDFs
0.0
0.2
0.4
0.6
0.8
1.0
TTFT / duration
0.0
0.2
0.4
0.6
0.8
1.0
CDF
Global
DeepSeek V3.2
Deepseek R1
Minimax M2.5
(b) Fraction of TTFT
Figure 3: Latency behavior of the aggregate workload
and three representative models. Models spend most
proportion of their time doing decode.
0
10
20
30
Input tokens (K)
0
2000
4000
6000
8000
Output tokens
50
100
150
P50 duration (s)
(a) Output vs. Dura-
tion
0
10
20
30
Input tokens (K)
0
2000
4000
6000
8000
Output tokens
1
2
3
P50 TTFT (s)
(b) Input vs. TTFT (c) TTFT vs. hit ra-
tio
Figure 4: Median latency binned by request shape. Du-
ration is governed by output length, TTFT by input
length, and caching cuts TTFT most aggressively on
long-input requests.
Models can be latency-bound for different reasons. The
three highlighted models reveal distinct latency profiles.
DeepSeek R1 has the longest end-to-end latency, consis-
tent with its tendency to generate long outputs. MiniMax-
M2.5 completes faster overall, but a larger share of its la-
tency comes from TTFT, reflecting its input-heavy workload.
DeepSeek V3.2 lies between these two cases. Thus, models
may be decode-heavy due to long outputs or prefill-heavy
due to long prompts, motivating phase-specific rather than
one-size-fits-all optimization.
Output length drives duration; input length drives TTFT..
Binning requests by token shape makes these latency drivers
explicit. Figure 4a shows that median end-to-end duration
increases proportionally to output length, getting barely af-
fected by input token length since completion time is decode
dominated, and figure 4b shows TTFT grows primarily with
input length. Figure 4c connects this prefill cost to prefix
reuse. For requests with similar input length, higher token
hit ratios correspond to lower TTFT, and the reduction is
most visible for long-input requests, where recomputing pre-
fill would have been expensive. For short-input requests,
even near-full cache hits remove little prefill work, so the
TTFT benefit is small and contributes little to end-to-end
latency. While caching may still save computation in these
cases, but its latency impact is limited.
4
Users and Models
Aggregate workload statistics do not fully describe how indi-
vidual users and models contribute to production traffic. We
therefore examine the workload at finer granularity along
two dimensions. First, we characterize the differences of
users and models that may have similar request volumes (Sec-
tion 4.1). Second, we study their access behavior, including
recurring usage patterns and arrival burstiness (Section 4.2
and Section 4.3).
4.1
Heterogeneity
Models and users span wide ranges of request volume. Re-
quest volume varies substantially across both models and
users. Figure 5 relates request count to user–model interac-
tion from both directions: for each model, we compare its
request count with the number of distinct users it serves; for
each user, we compare their request count with the number
of distinct models they access.
On the model side, Figure 5a shows a weak positive trend
with substantial spread. Models with more requests often
serve more users, yet models with similar request counts can
differ by orders of magnitude in user count. Most models,
including many heavily used ones, receive the majority of
their traffic from relatively few users. Some high-traffic mod-
els are used broadly, while others receive comparable traffic
from a much smaller user base. This distinction matters for
locality: repeated access from a concentrated set of users can
create different cache-reuse opportunities than traffic spread
across many independent users. The platform’s support for
user-deployed models likely contributes to this spread, since
private models may receive steady traffic from only a small,
fixed group of users.
Figure 5b shows that most users issue relatively few re-
quests and access only a small number of models. However,
a sparse tail of users sends many requests across a much
broader model set. Most users therefore concentrate their
activity on a few models, while these high-volume, broad-
access power users may correspond to automated applica-
tions, proxy services, model routers, or agentic workflows
rather than simple individual use.
Token shape varies substantially across models and users.
Figure 6 places each model or user by its median input and
output length, with the dashed line marking equal size. Most
points fall below the line, which means that most users and
models tend to be more input heavy than output at the me-
dian. However, the spread is wide, showing that this average
hides very different request shapes. The model view in Fig-
ure 6a shows two distinct regions. Some models are strongly


---

Conference’17, July 2017, Washington, DC, USA
Nixon et al.
103
105
107
109
Requests per model
100
101
102
103
104
105
Unique users per model
100
101
102
# models
(a) Models: requests vs. users
101102103104105106107108109
Requests per user
101
102
103
104
Distinct models
100
101
102
103
Users
(b) Users: requests vs. models
Figure 5: Requests and model usage at the model and
user level. Models and users with similar request vol-
umes can differ substantially in access breadth.
100
101
102
103
104
105
Median model input
100
101
102
103
104
105
Median model output
100
101
102
Models
(a) Models: input vs. output
100 101 102 103 104 105 106
Median user input
100
101
102
103
104
105
Median user output
100
101
102
103
104
Users
(b) Users: input vs. output
Figure 6: Most models and users have longer median in-
puts than outputs, but vary substantially across groups.
0
6
12
18
24
30
Days
0
50
100
150
200
User index
(a) Periodic user access
0
6
12
18
24
30
Days
0
100
200
300
400
500
User index
(b) Correlated access
Figure 7: Thirty-day user-access rasters for two popular
models. Models with similar popularity can exhibit
different usage patterns from individual users.
input-heavy, receiving long prompts but producing shorter
outputs, while others are output-heavy, generating responses
that are large relative to their inputs. The user view in Fig-
ure 6b is more concentrated, but still spans a broad range.
Some users consistently send short prompts, while others
work with much larger contexts; output lengths also vary
substantially. Taken together, request count and token shape
describe different aspects of workload behavior. A model or
user with a similar number of requests may still impose very
different serving costs depending on whether their traffic
is input-heavy, output-heavy, or more balanced. Together,
these results show that models and users with similar traffic
can still place very different demands on the system.
0
6
12
18
24
30
Days
0
2
4
6
8
10
Model index
q
(a) Periodic user usage
0
6
12
18
24
30
Days
0
5
10
15
20
Model index
q
(b) Model exploration
Figure 8: Thirty-day model-access rasters for two high-
volume users. Users with similar request counts can
show different access patterns.
4.2
Access Patterns
Aggregate request volume does not show how user–model
interactions unfold over time. Users with similar request
counts may access models in different ways, and popular
models may receive traffic from different user patterns. We
illustrate this with 30-day user-centric rasters show which
models a user accesses over time and model-centric rasters
show which users access a model over time.
Heavy users differ in how broadly they access models. Fig-
ure 8 shows two high-volume users with different access
behavior. In Figure 8a, the user repeatedly accesses a small
and stable set of models across the 30-day window. Some
models are used throughout most of the month, while others
are accessed more periodically. Figure 8b shows a different
pattern: the user spends most of the month on a few mod-
els, but briefly accesses many additional models during a
short period. These examples show that a single user may
use multiple models concurrently, either steadily or in short
bursts. Such behavior is plausible on this platform, where
users can build model routers that send requests to differ-
ent models based on their own criteria. The more periodic
patterns reflect recurring daily activity or scheduled jobs.
Popular models can exhibit very different user-level access
patterns. Figure 7 compares thirty-day user-access rasters
for two popular models. Figure 7a also shows a largely peri-
odic pattern. Many users remain active across long portions
of the window, forming horizontal bands that persist over
days or weeks suggesting activity of power users. Several
users issue requests repeatedly at regular intervals, while
new users appear gradually throughout the month. Figure 7b
shows a more correlated pattern. Activity is sparse early in
the window, then expands sharply around the middle of the
month as many users become active within the same period.
The dense vertical clusters indicate that requests from dif-
ferent users arrive at similar times, rather than being spread
independently across the window. One possible explanation
is that related accounts or coordinated applications invoke


---

A Year in LLM Serving: Workload Evolution, Caching and Load-Balancing
Conference’17, July 2017, Washington, DC, USA
10
100
1k
10k
100k
Mean requests / active hour
0.1
1
10
Mean CV(IAT)
100
101
102
# models
(a) Popularity vs. burstiness
10
100
1k
10k
100k
Mean requests / active hour
0.1
1
10
Mean CV(IAT)
Spearman lag-1 IAT autocorr
1.00
0.75
0.50
0.25
0.00
0.25
0.50
0.75
1.00
(b) Lag-1 IAT autocorrelation
Figure 9: Model request load and burstiness. Most mod-
els are bursty and show positive correlation, indicating
persisting high-activity and low-activity periods.
the model in similar ways; for example, multiple accounts
may be used to distribute traffic under platform limits.
Opportunity for pattern-aware serving. User- and model-
level behavior provides actionable signals for serving deci-
sions. Mining block, job, and application level patterns has
improved caching and scheduling policies, despite the dif-
ficulty of learning from such fine-grained signals [6, 9, 26].
Block accesses span a vast space, while individual jobs re-
veal little about recurring behavior. User- and model-level
histories provide a coarser and more stable view that may be
easier to learn and exploit for caching, prefetching, routing,
model placement, and capacity provisioning.
Finding 1: Users and models exhibit distinct temporal
access patterns which can be used to inform serving deci-
sions, including caching, routing, model placement, and
capacity provisioning.
4.3
Burstiness
Request arrivals may be steady or clustered into short bursts,
which affects provisioning, scheduling, and placement. We
characterize burstiness using the coefficient of variation (CV)
of inter-arrival time (IAT): a CV greater than 1 indicates that
request traffic is uneven.
Most models are bursty and persistently so. Figure 9a plots
each model by its mean request rate during active hours
and the minutely CV of its inter-arrival times. Most models
lie above CV = 1, showing that their arrivals are bursty
rather than evenly spaced. This pattern appears across both
low- and high-rate models, so models with more traffic are
not necessarily steadier. Figure 9b shows that among these
bursty models, many do show positive autocorrelation. This
indicates that high-load periods tend to follow high-load
periods, and low-load periods tend to persist. Model traffic
often stays in an active or quiet state for some time instead
of fluctuating randomly from one request to the next.
DeepSeek-V3-0324
DeepSeek-R1
Qwen3-32B
DeepSeek-V3.2-Exp
DeepSeek-R1-0528
gemma-3-12b-it
DeepSeek-TNG-R1T2-Chimera
DeepSeek-V3.2
DeepSeek-V3.1
Mistral-Small-3.1-24B-Instruct-2503
Others
May
'25
Aug
'25
Nov
'25
Feb
'26
0.0
0.2
0.4
0.6
0.8
1.0
Share of requests
(a) Request share
May
'25
Aug
'25
Nov
'25
Feb
'26
0.0
0.2
0.4
0.6
0.8
1.0
Share of total tokens
(b) Token share
Figure 10: Monthly model mix among the top models
by request and token share. Dominant models and their
token shares are becoming more diverse over time.
Persistent bursts create colocation opportunities. These pat-
terns may matter for placement and autoscaling. Many lower-
traffic models have busy and quiet periods that often persist
for some time. This creates opportunities to colocate or mul-
tiplex models whose active windows do not overlap, rather
than provisioning each sparse model as if it required dedi-
cated capacity at all times.
Finding 2: Model burstiness is often persistent and cor-
related. Busy periods and quiet periods tend to persist.
This context may help autoscaling and colocation policies
anticipate load.
5
One-Year Workload Evolution
In this section, we discuss how the workload evolved over
the year, focusing on model usage (Section 5.1) and token
shape (Section 5.2).
5.1
Model Usage
Dominant models turn over. The set of dominant models
changes substantially over the year. Figure 10 shows the
monthly share of traffic contributed by the top models, with
the “Others” bucket capturing the remaining share. In the
early months, traffic is dominated by DeepSeek models, such
as DeepSeek-V3-0324 and DeepSeek-R1. Their shares de-
cline over time, while newer models such as Qwen3-32B
and DeepSeek-V3.2 become more prominent later on. The
token-weighted view also shows the same trend.
Traffic spreads across more models over time. Model usage
also becomes more diverse over time. The “Others” band
grows in both panels, showing that a larger fraction of re-
quests and tokens comes from the non-dominant models. As
more models are released and adopted, traffic spreads across
a wider range of models rather than remaining concentrated
in a small group of dominant ones. This matters for system
design as optimizations tuned to the most-used models in


---

Conference’17, July 2017, Washington, DC, USA
Nixon et al.
May 
'25
Aug 
'25
Nov 
'25
Feb 
'26
Month
101
102
103
104
Input tokens
P10-P90
P25-P75
Median
(a) Monthly input intervals
May 
'25
Aug 
'25
Nov 
'25
Feb 
'26
Month
101
102
103
Output tokens
P10-P90
P25-P75
Median
(b) Monthly output intervals
Figure 11: Monthly input (a) and output (b) token-
length bands (P10–P90, P25–P75, median). Global input
tend to stay stable while output tends to drop over time.
one period may become less suitable later since both the
leading models and the broader model mix change.
5.2
Token Shape
Token lengths also change over the year, and input and out-
put tokens evolve differently. We examine the aggregate
monthly trend, then group users by their join time to under-
stand whether these changes are associated with newer user
cohorts.
Inputs stay stable while outputs shrink. Figure 11 shows the
monthly distribution of request token lengths. Input lengths
remain broadly stable over the year, with the monthly median
staying in the thousands of tokens. Output lengths show a
clearer downward trend, with the median falling from a few
hundred tokens early in the trace to below one hundred
tokens near the end. The wider bands toward the end of the
trace also indicate greater variation in output lengths across
requests. These aggregate bands are request-weighted, so
users who contribute more traffic have a larger influence on
the overall trend. To complement this view, we next group
users by join time and examine the distribution of each user’s
median input and output length within each cohort.
Newer user cohorts are more input-heavy. Cohort decom-
position shows that newer user cohorts tend to be more
input-heavy than earlier ones. Figure 12 shows that later
cohorts have larger median input lengths, indicating that
newer users typically submit longer prompts. Change in the
median output side is less pronounced. However, the per-
centile bands also widen in both panels for later cohorts,
showing greater variation across users in their typical input
and output lengths. Overall, newer user cohorts tend to use
longer inputs and exhibit more diverse token profiles than
earlier cohorts.
May 
'25
Aug 
'25
Nov 
'25
Feb 
'26
0
10000
20000
30000
40000
50000
60000
Median input
P10-P90
P25-P75
Median
(a) Median input by cohort
May 
'25
Aug 
'25
Nov 
'25
Feb 
'26
0
500
1000
1500
2000
2500
3000
Median output
P10-P90
P25-P75
Median
(b) Median output by cohort
Figure 12: Per-user median input (a) and output (b) by
release cohort, with P10–P90 and P25–P75 bands. Later
user cohorts shift toward larger inputs and outputs
Finding 3: Both model usage and token profiles change
over time. Dominant models turn over, global outputs
become shorter, and newer user show larger and more
variable token lengths.
6
Prefix Caching
Prefix caching reduces prefill work by reusing input tokens
from earlier requests. Since prefill cost grows with input
length, caching can substantially reduce TTFT. We first char-
acterise reuse observed in production (Section 6.1) and the
arrival locality that drives it (Section 6.2); we then use simu-
lation to compare eviction algorithms (Section 6.3).
6.1
Production System
We characterise production cache behavior using the logged
cached-token field, which records the number of input tokens
served from the prefix cache for each request. Thus, our anal-
ysis captures cache reuse actually realized by the deployed
production system rather than theoretical. We analyze the
final two months of the trace, during which cached-token
logging was available. Figure 13 presents the observed reuse
from four perspectives: request-level distributions by input
length and for selected high-volume models, together with
cumulative per-model and per-user profiles.
Request-level cached fractions are bimodal. Figure 13a
shows a strongly bimodal pattern: most requests see either
little to no prefix reuse or reuse nearly their entire input
prefix, with relatively few requests falling in between. This
pattern is consistent with many requests either reusing
most of a prior prefix or receiving little reuse, as expected in
multi-turn sessions. It shows that a request either inherits
the previous turn’s context (and therefore most of its prefix)
or starts fresh, a partial hit being rare. The curves also
shift with input size: short-input requests skew toward
high reuse, typical of multi-turn dialogue where each
turn appends an increment to a growing context, while
long-input requests shift toward low reuse, since fewer of
them inherit a previous turn that fully covers the new prefix.


---

A Year in LLM Serving: Workload Evolution, Caching and Load-Balancing
Conference’17, July 2017, Washington, DC, USA
0.0
0.2
0.4
0.6
0.8
1.0
Token hit ratio
0.0
0.2
0.4
0.6
0.8
1.0
CDF
Global
<1K input
>8K input
(a) Prompt length and hit ra-
tio
0.0
0.2
0.4
0.6
0.8
1.0
Token hit ratio
0.0
0.2
0.4
0.6
0.8
1.0
CDF
Global
DeepSeek V3.2
Deepseek R1
Minimax M2.5
(b) Model token hit ratio
102 103 104 105 106 107 108
# Requests
0.0
0.2
0.4
0.6
0.8
1.0
Avg. Token Hit Ratio
100
101
# Models
(c) Per-model cache profile
101102103104105106107108
# Requests
0.0
0.2
0.4
0.6
0.8
1.0
Avg. Token Hit Ratio
100
101
102
# Users
(d) Per-user cache profile
Figure 13: Cache behavior at three levels. Request-level cached-token fractions are bimodal and have distinctive
characteristics across input lengths and model types. Models and users also have varying degrees of cacheability.
Cache behavior differs sharply across models. Figure 13b
shows the request-level distribution for selected models. The
two DeepSeek models have many requests with zero cache
hits, while MiniMax-M2.5 shows a broader distribution, with
many requests achieving intermediate to high hit ratios. Mod-
els with comparable traffic volume can therefore expose very
different cacheability depending on how they are invoked.
This may partly reflect MiniMax-M2.5’s heavier use in coding
or agentic workflows, which often involve short inter-arrival
times and repeated reuse of prefixes across turns, leading to
higher cache fractions.
Model and user cacheability. Figure 13c shows that several
models with modest request volumes achieve high token
hit ratios, suggesting that request volume alone does not
determine reuse. Instead, these models may benefit from
concentrated traffic: when a small set of users repeatedly
accesses the same model with similar contexts, their requests
can produce substantial reuse. Figure 13d supports this inter-
pretation. Although most users exhibit little reuse, a smaller
group achieves high hit ratios, likely by repeatedly accessing
a limited set of models, low interarrival times, and proper
context engineering. Model- and user-level cacheability are
therefore intertwined. A model’s aggregate hit ratio depends
not only on the model itself, but also on its use case and user
base. Models serving repetitive workloads or a concentrated
set of users may achieve high reuse, whereas broadly used
models with diverse requests may exhibit lower reuse.
6.2
Arrival Locality
Caching is strongly influenced by arrival locality: how
quickly a user returns after a previous request. We first
study recurrence at the user level, then refine it to the (user,
model) granularity, which better reflects cache reuse.
User IAT trends downwards over time. Figure 14a shows
that per-user inter-arrival time remains on the order of
minutes for most of the trace, but declines toward early
2026 with a widened spread. This indicates that users return
Apr
'25
Jul
'25
Oct
'25
Jan
'26
Apr
'26
Month
100
101
102
103
Inter-arrival time (s)
P10-P90
P25-P75
Median
(a) Per-user IAT over time
(b) Per-user IAT across mod-
els
Figure 14: Inter-arrival time (IAT) spread of users
across different models. Per-user median trends down-
ward over time.
more quickly over time, which might be partially explained
with the growing adoption of more agents. The model-level
view in Figure 14b shows that this recurrence pattern also
varies substantially by model. MiniMax-M2.5 has the lowest
per-user IAT, consistent with its use in coding or agentic
workflows where requests are issued in rapid succession.
DeepSeek R1 has the longest IAT, which may reflect more
human-paced reasoning interactions, where users wait for
and read longer outputs before sending the next request.
DeepSeek V3.2 falls between these two extremes. Overall,
user recurrence becomes faster over time, but the degree of
arrival locality remains strongly workload-dependent.
A short TTL covers most repeat arrivals. Figure 16 shows
the inter-arrival time between consecutive requests from the
same (user, model) pair. Many requests return quickly with
roughly half arrive within 0.1 second, around 80% within 10
seconds, and nearly all within several minutes. This strong
temporal locality increases the likelihood that the previous
turn’s prefix remains in cache when the next request arrives.
Thus, even a TTL of a few seconds can preserve reuse for
a large share of repeat requests, while a TTL on the order
of minutes captures nearly all request-weighted temporal
locality.


---

Conference’17, July 2017, Washington, DC, USA
Nixon et al.
10
3 10
2 10
1 100 101 102 103 104
IAT (s)
0.0
0.2
0.4
0.6
0.8
1.0
CDF
1m
1h
Request
(a) Per-user–model IAT
Figure 16: 99% of reuse arrives within
15 minutes of the previous request.
Cache locality is concentrated at short
timescales.
100K
1M
Cache size (tokens)
0.2
0.4
0.6
0.8
1.0
Token hit ratio
FIFO
LRU
ARC
LRB
GDSF
Sieve
Belady (size-aware)
(a) MiniMax-M2.5
1M
10M
100M
Cache size (tokens)
0.2
0.4
0.6
0.8
Token hit ratio
FIFO
LRU
ARC
LRB
GDSF
Sieve
Belady (size-aware)
(b) DeepSeek V3.2
Figure 17: Token hit ratio for seven eviction algorithms on workloads
from two representative models. SOTA algorithms often perform similar
or worse than FIFO and LRU. The size-aware Belady sets an upper bound
for MiniMax-M2.5 but retains a persistent gap on DeepSeek V3.2.
Finding 4: Cache reuse is common but uneven. Request-
level cached fractions are bimodal and vary across mod-
els and users. Arrival locality is highly skewed but most
repeat arrivals occurs at short timescales. 99% requests
return within a 15 minutes period.
6.3
Cache Simulations
The analysis above measures the cached-token fraction in
production systems, which are affected by both cache size
and routing. In this section, we will try to evaluate the impact
of different eviction algorithms by replaying the trace using
cache simulations.
6.3.1
Session Reconstruction. Since the trace does not in-
clude prompts or explicit session identifiers, we reconstruct
multi-turn sessions for simulation. Prior work [22] shows
that cross-user KV-cache hits are rare and that most reuse
occurs within a user’s own request stream. We therefore
infer continuations only within each user. For each request 𝐵
in arrival order, we keep a per-user sliding window contain-
ing the most recent 𝐾=10 earlier requests. We then select
a unique unpaired candidate 𝐴that satisfies three condi-
tions: (1) 𝐴uses the same API endpoint and model as 𝐵; (2)
it𝐴+ ot𝐴< it𝐵, so the parent request’s prompt and comple-
tion fit strictly inside the child request’s input, as required
by a valid multi-turn continuation; and (3) 𝐴minimizes the
residual gap it𝐵−(it𝐴+ ot𝐴), giving the tightest fit. If such
a candidate exists, 𝐵inherits 𝐴’s session ID and is assigned
the next turn ID. Otherwise, 𝐵starts a new session at turn
0. This reconstruction deliberately ignores both the trace’s
recorded cached-token count and the production instance_
id. The inferred session structure therefore depends only on
structural constraints implied by multi-turn conversations,
not on the deployed router or cache policy. Consequently,
the simulator estimates workload-intrinsic reuse rather than
reuse induced by production routing locality.
6.3.2
Cache Simulation. With sessions in hand, we first ask
an upper-bound question: under a single cache, how much
reuse is available in the workload, and how close do existing
eviction algorithms come to the offline optimum? We replay
the trace by treating each sequence as a management (admis-
sion and eviction) unit because Figure 13a shows that most
sequences either get zero or full hits. Using libCacheSim [1],
we evaluate ten cache sizes per workload over several state-
of-the-art algorithms: FIFO, LRU, ARC [14], S3FIFO [27],
GDSF [5], LHD [3], LRU [19], Sieve [31], and the size-aware
Belady oracle [4] algorithm. Due to limited space, we only
present the ones with a larger difference.
6.3.3
Results. Figure 17 highlights two results. First, simple
eviction policies are already highly competitive for LLM
prefix caching. LRU and FIFO often match or exceed the
token hit ratios of more complex state-of-the-art algorithms.
ARC is a notable exception: it performs substantially worse
than LRU at intermediate cache sizes, especially on DeepSeek
V3.2. This pattern is consistent with the strong recency bias
in the workload as prefixes are frequently reused shortly
after creation, but their utility decays quickly.


---

A Year in LLM Serving: Workload Evolution, Caching and Load-Balancing
Conference’17, July 2017, Washington, DC, USA
(a) Requests / hour
(b) Active instances / hour
(c) Token max/mean ratio
(d) Per-instance occupancy
Figure 18: Workload and balance for DeepSeek-V3.2. (a) Request rate stays roughly stationary (b) while replicas
trend downward. (c) Per-hour max/mean drifts upward as the fleet shrinks and (d) per-instance occupancy on the
busiest day is balanced on average but episodically broken.
102
104
106
Load (Tokens / s)
101
103
105
Input tokens
2
4
6
8
P90 TTFT (s)
(a) load vs TTFT
102
105
Load (Tokens / s)
100
101
102
103
104
105
Output tokens
0
50
100
150
P90 decode time (s)
(b) load vs decode
Figure 19: Per-request latency vs. instance-level load.
TTFT and decode time climbs once long-token requests
land on heavily loaded instances.
Second, cache effectiveness is workload-dependent.
DeepSeek V3.2 is more cache-constrained: its hit ratio
increases gradually with cache size, and practical policies
remain below the Belady oracle even at large capacities.
MiniMax-M2.5 is more cache-friendly: its hit ratio increases
quickly, and most policies approach the oracle at moderate
cache sizes. This suggests that MiniMax-M2.5 has reusable
session state that is easier to retain, whereas DeepSeek V3.2
has reuse patterns that are harder for standard eviction
policies to capture.
Finding 5: Prefix-cache reuse is strongly recency-driven,
making simple policies such as FIFO and LRU highly com-
petitive. Nevertheless, the remaining gap to Belady re-
veals meaningful room for LLM-specific cache designs
that better exploit session reuse and workload-dependent
locality.
7
Load Balancing
7.1
Production Systems
We now ask whether requests within a single popular model
are evenly distributed across the instances that serve it. We
will be using DeepSeek-V3 as the case study throughout a
2-month period.
0 1 2 3 4 5 6 7 8 9 1011
Instance index
0
2
4
6
8
10
User request (%)
User request
Cache hit
0
20
40
60
80
100
Token hit (%)
(a) High load
0 1 2 3 4 5 6 7 8 9 10
Instance index
0
5
10
15
20
25
30
User request (%)
User request
Cache hit
0
20
40
60
80
100
Token hit (%)
(b) Low load
Figure 20: Requests from a (user, model) pair over 60-
minute windows. Under high load, routing spreads
requests across instances, duplicating KV state; under
low load, it concentrates them on fewer instances, pre-
serving locality.
7.1.1
General Overview. Figure 18a shows that request rate
remains bursty but roughly stationary throughout the two
months, while Figure 18b shows that the number of active
instances declines. This decline closely follows the reduction
in total token volume processed per hour, measured as input
plus output tokens. Thus, replica count tracks serving uti-
lization rather than request volume alone: scaling responds
to token work, not just request arrivals.
Load is not always evenly distributed across active in-
stances. Figure 18c shows that the per-hour max/mean token-
load ratio increases as the model scales down, indicating that
the imbalance worsens as the serving pool shrinks. This im-
balance matters because overload affects latency unevenly:
Figure 19a shows that P90 TTFT rises sharply once an in-
stance exceeds a high tokens-per-second threshold, espe-
cially for long-input requests. In contrast, Figure 19b shows
that P90 decode time mainly follows output length and is
largely insensitive to instance throughput. Thus, overload
primarily affects prefill, making input-heavy traffic the most
vulnerable to load imbalance.
Zooming in on a single busy day reveals the short-term
dynamics more clearly. Figure 18d shows that most active
instances remain busy and carry similar per-minute request


---

Conference’17, July 2017, Washington, DC, USA
Nixon et al.
rates, while a small number of instances become quiet around
mid-day. Thus, load is balanced in aggregate, but not per-
fectly balanced at every instant. This behavior reflects the
production routing policy. For each request, the load bal-
ancer first selects the few least loaded instances, then routes
to the one with the highest expected prefix-cache hits.
7.1.2
Routing-Induced Cache Duplication. Figure 20 shows
how this tradeoff appears for the same user and model in
two 60-minute windows. Under low load, Figure 20b shows
that the user stays mostly on one instance, and cache hits
concentrate there. Under high load, Figure 20a shows that the
load balancer spreads the user across many instances to avoid
overloading any one replica. The user’s traffic share then
resembles the global load distribution, but several instances
still show measurable hit ratios.
These two regimes expose a fundamental tension between
load balancing and cache locality. Keeping a user’s requests
on one instance preserves its prefix state and maximizes
reuse. Under high load, however, the router spreads requests
across replicas. Cache hits may remain high, but only by
replicating the same prefix across multiple instance-local KV
caches. This duplication consumes scarce capacity and dis-
places prefixes from other users. A good routing algorithm
must therefore balance traffic evenly while minimizing re-
dundant KV state across the fleet.
Finding 6: Stickiness preserves cache locality, but con-
flicts with load balancing. At high volume, the load bal-
ancer spreads a user across instances, duplicating the
similar context across replica-local KV caches.
7.2
Load Balancing Simulation
Our production analysis illustrates the tension between
cache locality and load balance. Under low load, a heavy user
remains on one instance and benefits from repeated cache
hits. Under high load, the load balancer spreads the user’s
requests across the fleet, duplicating KV state and reducing
the maximum achievable cache reuse. Prior work addresses
this tension through KV-cache transfer and offloading [13, 17],
which stores KV state outside the serving instance or trans-
fers it between workers as routing changes.
Although these designs preserve reuse across instances,
they turn cache locality into a data-movement problem. KV
state can be very large for long-context requests. For example,
a 100K-token MiniMax-M2.5 context occupies roughly 27 GB
of KV state, requiring about 2.7 s to transfer over a 10 GB/s
link in one direction, excluding contention, coordination,
and any additional transfer to the destination worker. At
the same time, our trace shows that reuse often occurs over
short timescales, with many repeat requests from the same
(user, model) pair arriving within seconds. In such cases,
KV transfer may impose substantial network overhead for
limited latency benefit.
We therefore study a complementary approach: preserve
locality by routing requests to instances that already hold
useful KV state, and relax this preference only when load
imbalance becomes too large. This avoids explicit KV transfer
on the critical path and keeps reuse in local GPU memory,
where it directly reduces repeated prefill work. The central
scheduling question is therefore how much load imbalance
should be tolerated to preserve cache locality. To quantify
this tradeoff, we replay the chained trace from Section 6.3
on a simulated fleet of 𝑁instances, each with a local LRU
KV cache. We ask two questions: how much cache hit ratio
does balance-oriented routing sacrifice, and how much load
imbalance does locality-oriented routing introduce?
7.2.1
Simulator and Routing Policies. The simulator pro-
cesses requests in arrival order, but now over a fleet of in-
stances that acts as a distributed cache. Each instance man-
ages its own KV cache and in-flight load independently. Be-
fore routing each request, the simulator advances time to the
request arrival timestamp and removes completed requests
from the active-load counters. It then applies the routing
policy, performs a session-level cache lookup on the chosen
instance, records the reusable prefix tokens, adds the request
to that instance’s in-flight queue until completion, and up-
dates its local KV cache with the new session footprint. This
produces a time-aware replay in which routing decisions,
cache state, and per-instance are recorded.
Four routing policies span the locality–balance spectrum.
round_robin rotates requests modulo 𝑁and ignores both
load and cache. load_first sends each request to the instance
with the smallest current routing load, where load is mea-
sured by total tokens. sticky pins each user to the first in-
stance it reaches, approximating naive locality without prefix
awareness. cache_first chooses the instance with the largest
reusable prefix for the request’s session, falling back to the
least-loaded instance when no cached state exists.
We reuse the reconstructed multi-turn sessions from Sec-
tion 6.3. Based on the single-cache simulation in Figure 17,
we use LRU for the routing study. Since the eviction policies
perform similarly, LRU provides a simple and representa-
tive cache baseline. We also select the same two models
used previously, with DeepSeek V3.2 having a larger work-
ing set that sustains cache pressure across the values that
are swept. MiniMax-M2.5 is much more cacheable, and its
sessions fit more comfortably in replica-local KV caches.
Together these two models therefore expose both a cache-
constrained workload and a more cache-friendly workload.
We sweep per-instance cache size in [1.1K, 5M] tokens and
fleet size 𝑁∈{5, 10, 15, 20}.


---

A Year in LLM Serving: Workload Evolution, Caching and Load-Balancing
Conference’17, July 2017, Washington, DC, USA
Round-robin
Load-first
Cache-first
Sticky
103
104
105
106
Instance cache size
0.0
0.1
0.2
0.3
0.4
0.5
Token hit ratio
103
104
105
106
Instance cache size
1.0
1.2
1.4
1.6
1.8
Replication ratio
5
10
15
20
# instances
1.0
1.2
1.4
1.6
1.8
Replication ratio
5
10
15
20
# instances
1
2
3
4
5
Load imbalance (%)
103
104
105
106
Instance cache size
0.0
0.1
0.2
0.3
0.4
0.5
0.6
Token hit ratio
(a) Hit ratio vs. cache size
103
104
105
106
Instance cache size
1.00
1.25
1.50
1.75
2.00
2.25
2.50
Replication ratio
(b) Replication vs. cache size
5
10
15
20
# instances
1.00
1.25
1.50
1.75
2.00
2.25
2.50
Replication ratio
(c) Replication vs. instance
count
(d) Imbalance vs. instance
count
Figure 21: Load balance simulation for DeepSeek V3.2 (top) and MiniMax-M2.5 (bottom). (a) Cache-aware routing
turns larger KV caches into higher hit ratios. (b) Larger caches reduce replication for cache_first, while cache-blind
policies remain highly replicated. (c) Fleet scaling amplifies replication under cache-blind routing, but less than
locality-aware routing. (d) cache_first pays modest load imbalance (max/mean token/s); sticky is omitted because
its imbalance is orders of magnitude higher.
7.2.2
Simulation Results. Figure 21 traces the routing trade-
off from cache reuse, to KV duplication, to load balance. We
first ask whether a larger per-instance KV cache actually im-
proves reuse under each routing policy. We then ask where
that reused state lives: concentrated on one replica, or dupli-
cated across the fleet. Finally, we measure the load-balance
cost of preserving locality.
Cache-aware routing unlocks fleet-wide KV capac-
ity. Figure 21(a) shows the token hit ratio as per-instance
cache size increases at 𝑁=20. The main distinction is between
cache-aware and cache-blind routing. load_first and round_
robin maintain low hit ratios even as cache capacity grows
because they scatter future turns across replicas; additional
capacity provides little benefit when requests do not return
to the instance holding their prefix. In contrast, cache_first
converts larger caches into substantially higher reuse and
approaches the single-cache headroom in Figure 17. sticky
also preserves locality, but only at user granularity. Because
each user is pinned to one instance, a heavy user can access
only that replica’s cache rather than the fleet’s aggregate
capacity. This effect is most visible for MiniMax-M2.5: cache
_first achieves high hit ratios even with small per-instance
caches, whereas sticky improves only once each replica can
hold the working sets of its pinned users. For DeepSeek V3.2,
the larger working set causes both locality-aware policies to
continue improving as cache size grows.
Larger caches strengthen cache affinity and reduce
session spread. Figure 21(b) partially explains the hit-ratio
gap at 𝑁=20. We define the replication ratio of a session as
the number of distinct instances that serve its requests; a
value of 1.0 means that the entire session remains on one
instance. Higher values indicate that the session is spread
across more replicas, increasing the likelihood that its KV
state is recomputed or stored at multiple locations. sticky
remains at 1.0 by construction because each user is pinned
to one instance. In contrast, load_first and round_robin main-
tain high replication ratios across cache sizes because their
routing decisions ignore cached state. For cache_first, repli-
cation is high when caches are small. Prefixes are frequently
evicted before later turns arrive, leaving no cached instance
to preserve affinity and forcing the policy to fall back to
least-loaded routing. Successive turns may therefore visit
different instances. As cache capacity grows, prefixes remain
resident longer, later turns return to the same instance, and
the replication ratio approaches 1.0. This transition occurs
later for DeepSeek V3.2, whose larger working set requires


---

Conference’17, July 2017, Washington, DC, USA
Nixon et al.
more capacity, and earlier for MiniMax-M2.5, whose reusable
state is easier to retain. Thus, larger caches allow cache_first
to improve reuse while keeping each session concentrated
on fewer replicas.
Scaling amplifies the session replication cost of cache-
blind routing. Figure 21(c) fixes the per-instance cache size
at 25k and varies the number of serving instances. sticky
remains at 1.0 by construction because each user is pinned to
one replica. In contrast, the replication ratios of round_robin
and load_first increase steadily with 𝑁on both workloads.
As the fleet grows, successive turns from the same session
can be routed to more instances, spreading the session across
more replica-local caches. The effect of scaling on cache_first
is workload-dependent. For DeepSeek V3.2, replication in-
creases moderately with fleet size because its larger working
set remains difficult to retain at the fixed cache size. When a
prefix is evicted, later turns lose their cache-affinity signal
and fall back to least-loaded routing, causing the session
to visit additional instances. For MiniMax-M2.5, replication
instead decreases from roughly 1.4 toward 1.1. Its smaller
reusable working set fits more easily as the fleet grows and
the workload is divided across more caches, allowing pre-
fixes to remain resident and later turns to return to the same
instance. Thus, scaling reduces session replication under
cache-aware routing only when the distributed cache capac-
ity is sufficient to preserve useful prefixes.
Locality has a bounded load-balancing cost. Fig-
ure 21(d) measures the imbalance introduced by preserving
cache locality. We omit sticky, since pinning entire users
to fixed instances produces a far larger imbalance and
would obscure the other policies. Among the remaining
policies, round_robin and load_first are generally the most
balanced, while cache_first incurs higher imbalance because
it prefers replicas that already hold reusable session state.
This is the price of locality: some requests are intentionally
routed away from the least loaded instance to avoid losing
cache reuse. The absolute imbalance is surprisingly small,
remaining within 5% to 7%. We find that this is largely
because the workload contains many single-turn sessions,
which cache_first can freely route to the least-loaded
instance to offset localized multi-turn traffic. Workloads
with fewer one-off requests may provide less balancing
flexibility. Future routing policies should therefore preserve
session locality when possible, while using load-aware
fallback or session migration to control imbalance without
naively scattering KV state across replicas.
Finding 7: LLM serving faces a fundamental tension
between cache locality and load balance. Cache-aware
routing improves reuse and reduces cross-instance KV
duplication with modest imbalance. Larger caches alone
cannot recover reuse when routing scatters session state
across replicas.
8
Related Work
LLM Inference Optimization. A large body of work im-
proves LLM serving through better batching, scheduling,
memory management, prefill–decode separation, and KV-
cache reuse. Orca, vLLM, and Sarathi-Serve improve contin-
uous batching, KV-cache memory management, and prefill
scheduling [2, 12, 30]. DistServe, Splitwise, and Mooncake
disaggregate prefill, decode, or KV-cache management to
improve serving efficiency [16, 17, 38]. Other work targets
cache reuse more directly: H2O proposes an eviction pol-
icy, Prompt Cache and CacheBlend reuse cached computa-
tion, SGLang introduces RadixAttention for prefix reuse, and
Preble jointly considers cache locality and distributed load
balancing [10, 20, 28, 32, 36].
These optimizations depend on realistic datasets for faith-
ful evaluation. Batching and scheduling depend on arrival
patterns and token lengths; disaggregated serving depends
on the balance between prefill and decode; and cache-aware
routing depends on temporal locality and prefix reuse. Yet
evaluations often rely on benchmark or application-specific
workloads, such as ShareGPT-derived requests, chat, code-
completion, and summarization traces, or short and partially
released production traces [12, 16, 20, 36, 38]. These work-
loads often require synthetic arrivals or lose timing fidelity
through sampling, obscuring inter-arrival times, and losing
user-level information. Our one-year, request-level produc-
tion trace preserves these signals enabling more realistic
evaluation of serving-system designs.
9
Conclusion
We present and release a one-year production trace of LLM
serving and use it to characterize workload evolution, user–
model interactions, prefix caching, and load-balancing be-
havior. Our analysis shows that production LLM workloads
are dynamic and heterogeneous: demand evolves over time,
users and models exhibit diverse usage patterns, and cache
locality is unevenly distributed across the workload. We fur-
ther find that prefix caching and load balancing are closely
coupled, creating a fundamental tradeoff between preserv-
ing reuse and distributing requests evenly. These results
highlight the need for trace-driven serving-system designs
that account for temporal evolution, workload structure, and
cache-aware routing.


---

A Year in LLM Serving: Workload Evolution, Caching and Load-Balancing
Conference’17, July 2017, Washington, DC, USA
References
[1] [n. d.]. libCacheSim: A high-performance cache simulator. https:
//github.com/1a1a11a/libCacheSim. Accessed: 2025-12-01.
[2] Amey Agrawal, Nitin Kedia, Ashish Panwar, Jayashree Mohan, Nipun
Kwatra, Bhargav S. Gulavani, Alexey Tumanov, and Ramachandran
Ramjee. 2024. Taming Throughput-Latency Tradeoff in LLM Inference
with Sarathi-Serve. In 18th USENIX Symposium on Operating Systems
Design and Implementation (OSDI 24). 117–134.
[3] Nathan Beckmann, Haoxian Chen, and Asaf Cidon. 2018. LHD: Im-
proving Cache Hit Rate by Maximizing Hit Density. In 15th USENIX
Symposium on Networked Systems Design and Implementation, NSDI
2018, Renton, WA, USA, April 9-11, 2018, Sujata Banerjee and Srinivasan
Seshan (Eds.). USENIX Association, 389–403. https://www.usenix.org/
conference/nsdi18/presentation/beckmann
[4] L. A. Belady. 1966. A study of replacement algorithms for a virtual-
storage computer. IBM Systems Journal 5, 2 (1966), 78–101. doi:10.
1147/sj.52.0078
[5] Ludmila Cherkasova. 1998. Improving WWW proxies performance with
greedy-dual-size-frequency caching policy. Citeseer.
[6] Andrew Chung, Subru Krishnan, Konstantinos Karanasos, Carlo
Curino, and Gregory R Ganger. 2020. Unearthing inter-job depen-
dencies for better cluster scheduling. In 14th USENIX Symposium on
Operating Systems Design and Implementation (OSDI 20). 1205–1223.
[7] DeepSeek-AI, Daya Guo, Dejian Yang, Haowei Zhang, Junxiao Song,
Ruoyu Zhang, Runxin Xu, Qihao Zhu, Shirong Ma, Peiyi Wang, Xiao Bi,
Xiaokang Zhang, Xingkai Yu, Yu Wu, Z. F. Wu, Zhibin Gou, Zhihong
Shao, Zhuoshu Li, Ziyi Gao, Aixin Liu, Bing Xue, Bingxuan Wang,
Bochao Wu, Bei Feng, Chengda Lu, Chenggang Zhao, Chengqi Deng,
Chenyu Zhang, Chong Ruan, Damai Dai, Deli Chen, Dongjie Ji, Erhang
Li, Fangyun Lin, Fucong Dai, Fuli Luo, Guangbo Hao, Guanting Chen,
Guowei Li, H. Zhang, Han Bao, Hanwei Xu, Haocheng Wang, Honghui
Ding, Huajian Xin, Huazuo Gao, Hui Qu, Hui Li, Jianzhong Guo, Jiashi
Li, Jiawei Wang, Jingchang Chen, Jingyang Yuan, Junjie Qiu, Junlong
Li, J. L. Cai, Jiaqi Ni, Jian Liang, Jin Chen, Kai Dong, Kai Hu, Kaige
Gao, Kang Guan, Kexin Huang, Kuai Yu, Lean Wang, Lecong Zhang,
Liang Zhao, Litong Wang, Liyue Zhang, Lei Xu, Leyi Xia, Mingchuan
Zhang, Minghua Zhang, Minghui Tang, Meng Li, Miaojun Wang, Ming-
ming Li, Ning Tian, Panpan Huang, Peng Zhang, Qiancheng Wang,
Qinyu Chen, Qiushi Du, Ruiqi Ge, Ruisong Zhang, Ruizhe Pan, Runji
Wang, R. J. Chen, R. L. Jin, Ruyi Chen, Shanghao Lu, Shangyan Zhou,
Shanhuang Chen, Shengfeng Ye, Shiyu Wang, Shuiping Yu, Shunfeng
Zhou, Shuting Pan, S. S. Li, Shuang Zhou, Shaoqing Wu, Shengfeng
Ye, Tao Yun, Tian Pei, Tianyu Sun, T. Wang, Wangding Zeng, Wanjia
Zhao, Wen Liu, Wenfeng Liang, Wenjun Gao, Wenqin Yu, Wentao
Zhang, W. L. Xiao, Wei An, Xiaodong Liu, Xiaohan Wang, Xiaokang
Chen, Xiaotao Nie, Xin Cheng, Xin Liu, Xin Xie, Xingchao Liu, Xinyu
Yang, Xinyuan Li, Xuecheng Su, Xuheng Lin, X. Q. Li, Xiangyue Jin,
Xiaojin Shen, Xiaosha Chen, Xiaowen Sun, Xiaoxiang Wang, Xinnan
Song, Xinyi Zhou, Xianzu Wang, Xinxia Shan, Y. K. Li, Y. Q. Wang,
Y. X. Wei, Yang Zhang, Yanhong Xu, Yao Li, Yao Zhao, Yaofeng Sun,
Yaohui Wang, Yi Yu, Yichao Zhang, Yifan Shi, Yiliang Xiong, Ying
He, Yishi Piao, Yisong Wang, Yixuan Tan, Yiyang Ma, Yiyuan Liu,
Yongqiang Guo, Yuan Ou, Yuduan Wang, Yue Gong, Yuheng Zou, Yujia
He, Yunfan Xiong, Yuxiang Luo, Yuxiang You, Yuxuan Liu, Yuyang
Zhou, Y. X. Zhu, Yanhong Xu, Yanping Huang, Yaohui Li, Yi Zheng,
Yuchen Zhu, Yunxian Ma, Ying Tang, Yukun Zha, Yuting Yan, Z. Z. Ren,
Zehui Ren, Zhangli Sha, Zhe Fu, Zhean Xu, Zhenda Xie, Zhengyan
Zhang, Zhewen Hao, Zhicheng Ma, Zhigang Yan, Zhiyu Wu, Zihui Gu,
Zijia Zhu, Zijun Liu, Zilin Li, Ziwei Xie, Ziyang Song, Zizheng Pan,
Zhen Huang, Zhipeng Xu, Zhongyu Zhang, and Zhen Zhang. 2025.
DeepSeek-R1: Incentivizing Reasoning Capability in LLMs via Rein-
forcement Learning. doi:10.48550/arXiv.2501.12948 arXiv:2501.12948
[cs].
[8] DeepSeek-AI, Aixin Liu, Bei Feng, Bing Xue, Bingxuan Wang, Bochao
Wu, Chengda Lu, Chenggang Zhao, Chengqi Deng, Chenyu Zhang,
Chong Ruan, Damai Dai, Daya Guo, Dejian Yang, Deli Chen, Dongjie Ji,
Erhang Li, Fangyun Lin, Fucong Dai, Fuli Luo, Guangbo Hao, Guanting
Chen, Guowei Li, H. Zhang, Han Bao, Hanwei Xu, Haocheng Wang,
Haowei Zhang, Honghui Ding, Huajian Xin, Huazuo Gao, Hui Li, Hui
Qu, J. L. Cai, Jian Liang, Jianzhong Guo, Jiaqi Ni, Jiashi Li, Jiawei
Wang, Jin Chen, Jingchang Chen, Jingyang Yuan, Junjie Qiu, Junlong
Li, Junxiao Song, Kai Dong, Kai Hu, Kaige Gao, Kang Guan, Kexin
Huang, Kuai Yu, Lean Wang, Lecong Zhang, Lei Xu, Leyi Xia, Liang
Zhao, Litong Wang, Liyue Zhang, Meng Li, Miaojun Wang, Mingchuan
Zhang, Minghua Zhang, Minghui Tang, Mingming Li, Ning Tian, Pan-
pan Huang, Peiyi Wang, Peng Zhang, Qiancheng Wang, Qihao Zhu,
Qinyu Chen, Qiushi Du, R. J. Chen, R. L. Jin, Ruiqi Ge, Ruisong Zhang,
Ruizhe Pan, Runji Wang, Runxin Xu, Ruoyu Zhang, Ruyi Chen, S. S.
Li, Shanghao Lu, Shangyan Zhou, Shanhuang Chen, Shaoqing Wu,
Shengfeng Ye, Shengfeng Ye, Shirong Ma, Shiyu Wang, Shuang Zhou,
Shuiping Yu, Shunfeng Zhou, Shuting Pan, T. Wang, Tao Yun, Tian
Pei, Tianyu Sun, W. L. Xiao, Wangding Zeng, Wanjia Zhao, Wei An,
Wen Liu, Wenfeng Liang, Wenjun Gao, Wenqin Yu, Wentao Zhang,
X. Q. Li, Xiangyue Jin, Xianzu Wang, Xiao Bi, Xiaodong Liu, Xiaohan
Wang, Xiaojin Shen, Xiaokang Chen, Xiaokang Zhang, Xiaosha Chen,
Xiaotao Nie, Xiaowen Sun, Xiaoxiang Wang, Xin Cheng, Xin Liu, Xin
Xie, Xingchao Liu, Xingkai Yu, Xinnan Song, Xinxia Shan, Xinyi Zhou,
Xinyu Yang, Xinyuan Li, Xuecheng Su, Xuheng Lin, Y. K. Li, Y. Q. Wang,
Y. X. Wei, Y. X. Zhu, Yang Zhang, Yanhong Xu, Yanhong Xu, Yanping
Huang, Yao Li, Yao Zhao, Yaofeng Sun, Yaohui Li, Yaohui Wang, Yi
Yu, Yi Zheng, Yichao Zhang, Yifan Shi, Yiliang Xiong, Ying He, Ying
Tang, Yishi Piao, Yisong Wang, Yixuan Tan, Yiyang Ma, Yiyuan Liu,
Yongqiang Guo, Yu Wu, Yuan Ou, Yuchen Zhu, Yuduan Wang, Yue
Gong, Yuheng Zou, Yujia He, Yukun Zha, Yunfan Xiong, Yunxian Ma,
Yuting Yan, Yuxiang Luo, Yuxiang You, Yuxuan Liu, Yuyang Zhou, Z. F.
Wu, Z. Z. Ren, Zehui Ren, Zhangli Sha, Zhe Fu, Zhean Xu, Zhen Huang,
Zhen Zhang, Zhenda Xie, Zhengyan Zhang, Zhewen Hao, Zhibin Gou,
Zhicheng Ma, Zhigang Yan, Zhihong Shao, Zhipeng Xu, Zhiyu Wu,
Zhongyu Zhang, Zhuoshu Li, Zihui Gu, Zijia Zhu, Zijun Liu, Zilin Li,
Ziwei Xie, Ziyang Song, Ziyi Gao, and Zizheng Pan. 2025. DeepSeek-
V3 Technical Report. doi:10.48550/arXiv.2412.19437 arXiv:2412.19437
[cs].
[9] Andrew D Ferguson, Peter Bodik, Srikanth Kandula, Eric Boutin, and
Rodrigo Fonseca. 2012. Jockey: guaranteed job latency in data parallel
clusters. In Proceedings of the 7th ACM european conference on Computer
Systems. 99–112.
[10] In Gim, Guojun Chen, Seung-seob Lee, Nikhil Sarda, Anurag Khandel-
wal, and Lin Zhong. 2024. Prompt Cache: Modular Attention Reuse
for Low-Latency Inference. In Proceedings of Machine Learning and
Systems, Vol. 6.
[11] Woosuk Kwon, Zhuohan Li, Siyuan Zhuang, Ying Sheng, Lianmin
Zheng, Cody Hao Yu, Joseph E. Gonzalez, Hao Zhang, and Ion Sto-
ica. 2023. Efficient Memory Management for Large Language Model
Serving with PagedAttention. In Proceedings of the ACM SIGOPS 29th
Symposium on Operating Systems Principles (SOSP).
[12] Woosuk Kwon, Zhuohan Li, Siyuan Zhuang, Ying Sheng, Lianmin
Zheng, Cody Hao Yu, Joseph E. Gonzalez, Hao Zhang, and Ion Sto-
ica. 2023. Efficient Memory Management for Large Language Model
Serving with PagedAttention. In Proceedings of the 29th Symposium on
Operating Systems Principles. 611–626.
[13] Yuhan Liu, Yihua Cheng, Jiayi Yao, Yuwei An, Xiaokun Chen, Shaot-
ing Feng, Yuyang Huang, Samuel Shen, Rui Zhang, Kuntai Du, et al.


---

Conference’17, July 2017, Washington, DC, USA
Nixon et al.
2025. Lmcache: An efficient KV cache layer for enterprise-scale LLM
inference. arXiv preprint arXiv:2510.09665 (2025).
[14] Nimrod Megiddo and Dharmendra S. Modha. 2003. ARC: A Self-
Tuning, Low Overhead Replacement Cache. In Proceedings of the FAST
’03 Conference on File and Storage Technologies, March 31 - April 2, 2003,
Cathedral Hill Hotel, San Francisco, California, USA, Jeff Chase (Ed.).
USENIX. http://www.usenix.org/events/fast03/tech/megiddo.html
[15] MiniMax. 2026. MiniMax M2.5: Built for Real-World Productivity.
https://www.minimax.io/news/minimax-m25. Accessed: 2026-05-15.
[16] Pratyush Patel, Esha Choukse, Chaojie Zhang, Aashaka Shah, Íñigo
Goiri, Saeed Maleki, and Ricardo Bianchini. 2024. Splitwise: Efficient
Generative LLM Inference Using Phase Splitting. In Proceedings of the
51st Annual International Symposium on Computer Architecture.
[17] Ruoyu Qin, Zheming Li, Weiran He, Mingxing Zhang, Yongwei Wu,
Weimin Zheng, and Xinran Xu. 2025. Mooncake: A KVCache-Centric
Disaggregated Architecture for LLM Serving. In 23rd USENIX Confer-
ence on File and Storage Technologies (FAST 25). 155–170.
[18] Haoran Qiu, Anish Biswas, Zihan Zhao, Jayashree Mohan, Alind Khare,
Esha Choukse, Íñigo Goiri, Zeyu Zhang, Haiying Shen, Chetan Bansal,
Ramachandran Ramjee, and Rodrigo Fonseca. 2025. ModServe: Scalable
and Resource-Efficient Large Multimodal Model Serving. doi:10.48550/
arXiv.2502.00937 arXiv:2502.00937 [cs].
[19] Zhenyu Song, Daniel S. Berger, Kai Li, and Wyatt Lloyd. 2020. Learning
Relaxed Belady for Content Distribution Network Caching. In 17th
USENIX Symposium on Networked Systems Design and Implementation,
NSDI 2020, Santa Clara, CA, USA, February 25-27, 2020, Ranjita Bhagwan
and George Porter (Eds.). USENIX Association, 529–544. https://www.
usenix.org/conference/nsdi20/presentation/song
[20] Vikranth Srivatsa, Zijian He, Reyna Abhyankar, Dongming Li, and
Yiying Zhang. 2025. Efficient Distributed Prompt Scheduling for LLM
Serving. In International Conference on Learning Representations.
[21] Jiahao Wang, Jinbo Han, Xingda Wei, Sijie Shen, Dingyan Zhang,
Chenguang Fang, Rong Chen, Wenyuan Yu, and Haibo Chen. 2025.
KVCache Cache in the Wild: Characterizing and Optimizing KVCache
Cache at a Large Cloud Provider. In 2025 USENIX Annual Technical
Conference (USENIX ATC 25). USENIX Association, Boston, MA.
[22] Jiahao Wang, Jinbo Han, Xingda Wei, Sijie Shen, Dingyan Zhang,
Chenguang Fang, Rong Chen, Wenyuan Yu, and Haibo Chen. 2025.
KVCache Cache in the Wild: Characterizing and Optimizing KVCache
Cache at a Large Cloud Provider. 465–482. https://www.usenix.org/
conference/atc25/presentation/wang-jiahao
[23] Yuxin Wang, Yuhan Chen, Zeyu Li, Xueze Kang, Yuchu Fang, Yeju
Zhou, Yang Zheng, Zhenheng Tang, Xin He, Rui Guo, Xin Wang,
Qiang Wang, Amelie Chi Zhou, and Xiaowen Chu. 2025. BurstGPT:
A Real-World Workload Dataset to Optimize LLM Serving Systems.
In Proceedings of the 31st ACM SIGKDD Conference on Knowledge Dis-
covery and Data Mining V.2 (KDD ’25). ACM, Toronto, ON, Canada.
doi:10.1145/3711896.3737413
[24] Yuxin Wang, Yuhan Chen, Zeyu Li, Xueze Kang, Yuchu Fang, Yeju
Zhou, Yang Zheng, Zhenheng Tang, Xin He, Rui Guo, Xin Wang,
Qiang Wang, Amelie Chi Zhou, and Xiaowen Chu. 2025. BurstGPT:
A Real-world Workload Dataset to Optimize LLM Serving Systems.
doi:10.48550/arXiv.2401.17644 arXiv:2401.17644 [cs] version: 5.
[25] Yuxing Xiang, Xue Li, Kun Qian, Wenyuan Yu, Ennan Zhai, and Xin Jin.
2025. ServeGen: Workload Characterization and Generation of Large
Language Model Serving in Production. doi:10.48550/arXiv.2505.09999
arXiv:2505.09999 [cs].
[26] Juncheng Yang, Reza Karimi, Trausti Sæmundsson, Avani Wildani, and
Ymir Vigfusson. 2017. Mithril: mining sporadic associations for cache
prefetching. In Proceedings of the 2017 Symposium on Cloud Computing
(SoCC’17). Association for Computing Machinery, New York, NY, USA,
66–79. doi:10.1145/3127479.3131210
[27] Juncheng Yang, Yazhuo Zhang, Ziyue Qiu, Yao Yue, and Rashmi
Vinayak. 2023. FIFO queues are all you need for cache eviction. In
Proceedings of the 29th Symposium on Operating Systems Principles
(Koblenz, Germany) (SOSP ’23). Association for Computing Machinery,
New York, NY, USA, 130–149. doi:10.1145/3600006.3613147
[28] Jiayi Yao, Hanchen Li, Yuhan Liu, Siddhant Ray, Yihua Cheng, Qizheng
Zhang, Kuntai Du, Shan Lu, and Junchen Jiang. 2025. CacheBlend: Fast
Large Language Model Serving for RAG with Cached Knowledge Fu-
sion. In Proceedings of the Twentieth European Conference on Computer
Systems.
[29] Gyeong-In Yu, Joo Seong Jeong, Geon-Woo Kim, Soojeong Kim, and
Byung-Gon Chun. 2022.
Orca: A Distributed Serving System for
Transformer-Based Generative Models. In 16th USENIX Symposium
on Operating Systems Design and Implementation (OSDI 22). USENIX
Association, Carlsbad, CA, 521–538.
[30] Gyeong-In Yu, Joo Seong Jeong, Geon-Woo Kim, Soojeong Kim, and
Byung-Gon Chun. 2022.
Orca: A Distributed Serving System for
Transformer-Based Generative Models. In 16th USENIX Symposium on
Operating Systems Design and Implementation (OSDI 22). 521–538.
[31] Yazhuo Zhang, Juncheng Yang, Yao Yue, Ymir Vigfusson, and K.V.
Rashmi. 2024. SIEVE is Simpler than LRU: an Efficient Turn-Key
Eviction Algorithm for Web Caches. In 21st USENIX Symposium on
Networked Systems Design and Implementation (NSDI 24). USENIX
Association, Santa Clara, CA, 1229–1246.
https://www.usenix.org/
conference/nsdi24/presentation/zhang-yazhuo
[32] Zhenyu Zhang, Ying Sheng, Tianyi Zhou, Tianlong Chen, Lianmin
Zheng, Ruisi Cai, Zhao Song, Yuandong Tian, Christopher Ré, Clark
Barrett, Zhangyang Wang, and Beidi Chen. 2023. H2O: Heavy-Hitter
Oracle for Efficient Generative Inference of Large Language Models.
In Advances in Neural Information Processing Systems, Vol. 36.
[33] Wenting Zhao, Xiang Ren, Jack Hessel, Claire Cardie, Yejin Choi, and
Yuntian Deng. 2024. WildChat: 1M ChatGPT Interaction Logs in the
Wild. doi:10.48550/arXiv.2405.01470 arXiv:2405.01470 [cs].
[34] Lianmin Zheng, Wei-Lin Chiang, Ying Sheng, Tianle Li, Siyuan Zhuang,
Zhanghao Wu, Yonghao Zhuang, Zhuohan Li, Zi Lin, Eric P. Xing,
Joseph E. Gonzalez, Ion Stoica, and Hao Zhang. 2024. LMSYS-Chat-1M:
A Large-Scale Real-World LLM Conversation Dataset. doi:10.48550/
arXiv.2309.11998 arXiv:2309.11998 [cs].
[35] Lianmin Zheng, Liangsheng Yin, Zhiqiang Xie, Chuyue Sun, Jeff
Huang, Cody Hao Yu, Shiyi Cao, Christos Kozyrakis, Ion Stoica,
Joseph E. Gonzalez, Clark Barrett, and Ying Sheng. 2024. SGLang:
Efficient Execution of Structured Language Model Programs. In Ad-
vances in Neural Information Processing Systems (NeurIPS).
[36] Lianmin Zheng, Liangsheng Yin, Zhiqiang Xie, Chuyue Sun, Jeff
Huang, Cody Hao Yu, Shiyi Cao, Christos Kozyrakis, Ion Stoica,
Joseph E. Gonzalez, Clark Barrett, and Ying Sheng. 2024. SGLang:
Efficient Execution of Structured Language Model Programs. In Ad-
vances in Neural Information Processing Systems, Vol. 37.
[37] Yinmin Zhong, Shengyu Liu, Junda Chen, Jianbo Hu, Yibo Zhu, Xu-
anzhe Liu, Xin Jin, and Hao Zhang. 2024. DistServe: Disaggregating
Prefill and Decoding for Goodput-Optimized Large Language Model
Serving. In 18th USENIX Symposium on Operating Systems Design and
Implementation (OSDI 24). USENIX Association, Santa Clara, CA.
[38] Yinmin Zhong, Shengyu Liu, Junda Chen, Jianbo Hu, Yibo Zhu, Xu-
anzhe Liu, Xin Jin, and Hao Zhang. 2024. DistServe: Disaggregating
Prefill and Decoding for Goodput-Optimized Large Language Model
Serving. In 18th USENIX Symposium on Operating Systems Design and
Implementation (OSDI 24). 193–210.
