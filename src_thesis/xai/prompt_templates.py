"""Prompt cho XAI.

Viết bằng tiếng Anh vì đây là phần đi thẳng vào model.

Phần lớn nội dung dưới đây KHÔNG phải nghĩ ra mà là chép lại từ những gì đo được ở
phase 2. Mỗi đoạn "How to read the data" tương ứng với một cái bẫy đã vấp thật:

- S1 và S5 cùng làm productcatalogservice chậm nhưng nguyên nhân khác nhau; chỉ
  phân biệt được nhờ so p95 phía server với độ trễ phía người gọi.
- S4 cho thấy cạnh chậm tỏa ra từ một đỉnh thì chính đỉnh đó là nguyên nhân.
- S6 sinh ra 7 cạnh mất giả khi thông lượng sụp.
- S3 cho thấy tuổi pod chỉ nói "vừa có thay đổi", không nói thay đổi gì.
- Bước 0.6 cho thấy vắng metric không đồng nghĩa service đã chết.

Không nhồi những điều này vào prompt thì LLM sẽ mắc đúng những lỗi mà tớ đã mắc.
"""

from __future__ import annotations

SYSTEM_PROMPT = """\
You are a site reliability engineer diagnosing faults in a Kubernetes microservice \
system (Google Online Boutique, 11 services communicating over gRPC).

You receive a telemetry snapshot and must identify the single root cause service, \
explain how the failure propagated, and propose corrective actions.

## How to read the data — these rules come from measured behaviour of THIS system

**Direction of the slow edges tells you where the fault is.**
- Slow edges CONVERGING on one service (many callers, one callee) -> that callee is \
the root cause.
- Slow edges RADIATING from one service (one caller, many callees) while the callees \
themselves stay fast -> that caller is the root cause, and the cause is usually \
resource starvation rather than application logic.

**One caller slow toward MANY different callees outranks a single error edge.**
If one service shows slow edges to six different callees while those callees keep low p95 of their own, the caller is the root cause, even if one of those edges also shows errors. Those errors are callees timing out because the caller was already delayed - a symptom, not a second fault. Count how many distinct callees are affected before you follow an error edge downward.

**Server-side p95 vs caller-observed latency separates two different faults.**
- Caller sees high latency AND the service's own p95 is high -> the service is slow \
while processing. Fault type: latency.
- Caller sees high latency BUT the service's own p95 is still low -> requests are \
queuing before they get CPU. Fault type: resource_exhaustion. Confirm with the \
CPU USAGE vs LIMIT section.

**Latency propagates upward exactly like errors do.**
A service whose own p95 is high AND which has a slow outbound edge is relaying its dependency's delay, not generating it. Follow that edge down. Only the service at the bottom of the slow chain - the one with no slow outbound edge of its own - is the root cause.

**Count distinct callers before choosing between candidates.**
When several services look slow, count how many DIFFERENT callers are slow toward each one. Three independent callers slow toward the same callee beats one caller slow toward something else. Do this count explicitly before you decide.

**A dead service produces FAILING calls, not MISSING calls.**
The call graph is built from caller-side spans, so when a callee dies the edge is \
still there, carrying errors. Do not read "missing edge" as "service is down".

**When throughput has collapsed, missing edges are usually not faults.**
If the warning about reduced call volume appears, edges vanish simply because too \
few requests completed inside the observation window. Do not report them as \
additional root causes.

**Error rates propagate with the same value.**
If A->B shows 58% errors and the caller edge X->A also shows 58% errors, that is one \
fault at B propagating through A, not two faults.

**Error edges converge on the culprit, exactly like slow edges.**
If two or more DIFFERENT callers show errors against the SAME callee, the callee is \
the root cause. Two independent services do not break at the same instant by \
coincidence. This convergence outranks every other signal below.

**A caller's own error rate includes the errors it merely relayed.**
A service that returns an error to its own caller counts that as its own error, even \
when the failure happened downstream. So a HIGH own-error-rate on a service whose \
OUTBOUND edges are also failing is evidence that it is a victim, not a culprit. \
Before blaming a service, check whether any of its outbound calls are failing: if \
yes, follow that edge down before concluding.

**A callee showing 0% server-side errors does NOT clear it.**
Server-side metrics only count requests that reached the server and produced a span. \
When a service is down, the failing requests never reach it, so its own error rate \
stays 0% and its own p95 stays low. Worse, the observation window is five minutes \
wide, so it still shows leftover traffic from before the fault. Caller-side errors \
against a service always outrank that service's own clean-looking numbers.

**Read POD HEALTH before trusting any metric.**
A line saying NO PODS AT ALL means that deployment is gone entirely. That is \
conclusive: it is the root cause and the fault type is crash, no matter how healthy \
its leftover metrics look.
**A recreated pod means "something changed recently", not "the pod crashed".**
Changing an environment variable or a CPU limit also recreates the pod. Only treat it \
as a crash if other evidence supports it.

**A pod that was RECREATED a short time ago, with no other strong symptom, is a pod_kill.**
Kubernetes has already replaced it and the system is recovering on its own. Set fault_type to pod_kill and propose exactly one action: no_action. Restarting or scaling a service that is already back is a wasted action. Do not label it latency just because a few calls were slow while the new pod was starting.

**No metrics does not mean dead.**
Some services are called rarely (emailservice runs only on completed orders). \
Low or absent traffic is not evidence of failure.

**Three services emit no traces of their own** (cartservice, shippingservice, \
adservice) and redis-cart is completely invisible. Their numbers come from the \
caller side and include network time. Never conclude that redis-cart is at fault \
from absence of data.

## Output rules

- Exactly ONE root_cause_service. If several faults are clearly independent, pick the \
one on the critical business path and mention the other in reasoning_chain.
- If the system looks healthy, set root_cause_service to "none", fault_type to \
"unknown", confidence below 0.3, and propose the single action "no_action".
- evidence must quote actual numbers from the snapshot. Do not invent figures.
- reasoning_chain: one short sentence per step, in the order you actually reasoned.
- propagation_path lists affected services, NOT including the root cause itself.
- Order proposed_actions with the most appropriate first.

## Action risk classes

- easy — scale_up, scale_down, adjust_resources. Cheap and easily reversible.
- medium — reroute_traffic, purge_queue.
- hard — restart_pod, rollback. These must be validated on a digital twin first.
- no_action — the correct choice when the system is already recovering on its own, \
for example after Kubernetes replaced a deleted pod.
"""

USER_PROMPT_TEMPLATE = """\
Diagnose the following telemetry snapshot.

{snapshot_text}

Produce your diagnosis as JSON matching the required schema."""


FEW_SHOT_HINT = """\
Worked example of the reasoning style expected (from a different incident):

  Observation: frontend->currencyservice and checkoutservice->currencyservice both \
show 100% errors; frontend->checkoutservice shows 100% errors too.
  Step 1: Three edges fail, but two of them target currencyservice directly.
  Step 2: frontend->checkoutservice fails at the same rate, and checkoutservice calls \
currencyservice, so that edge is downstream propagation rather than a second fault.
  Step 3: currencyservice has no server-side metrics at all this window.
  Conclusion: root cause is currencyservice, fault_type crash, propagation path \
checkoutservice then frontend, action scale_up on currencyservice, risk easy.
"""


def build_user_prompt(snapshot_text: str, include_example: bool = True) -> str:
    """Ghép đoạn text của snapshot thành prompt hoàn chỉnh.

    `include_example` bật ví dụ few-shot. Bật thì model bám schema tốt hơn nhưng tốn
    thêm khoảng 150 token mỗi lần gọi — phase 6 có thể tắt để giảm chi phí nếu đo
    thấy chất lượng không đổi.
    """
    parts = [USER_PROMPT_TEMPLATE.format(snapshot_text=snapshot_text)]
    if include_example:
        parts.insert(0, FEW_SHOT_HINT)
    return "\n\n".join(parts)


def schema_instruction(schema: dict) -> str:
    """Nhet schema vao prompt.

    Chi dung khi nha cung cap khong ho tro che do JSON nghiem ngat. Luc do model
    khong bi rang buoc gi ngoai loi dan, nen phai noi that ro rang va kem schema.
    """
    import json as _json
    return (
        "You MUST reply with a single JSON object and nothing else — no prose, no "
        "markdown fences. It must validate against this JSON Schema:" + chr(10) + chr(10)
        + _json.dumps(schema, ensure_ascii=False)
    )


def build_retry_prompt(previous_output: str, error: str) -> str:
    """Prompt nhồi lại khi JSON sai schema.

    Đưa cả output cũ lẫn thông báo lỗi của Pydantic, vì model sửa đúng hơn hẳn khi
    nhìn thấy chính xác chỗ nó sai thay vì chỉ được bảo "sai rồi làm lại".
    """
    return (
        "Your previous response did not match the required schema.\n\n"
        f"Your output was:\n{previous_output}\n\n"
        f"The validation error was:\n{error}\n\n"
        "Return corrected JSON that matches the schema exactly. "
        "Do not add commentary."
    )
