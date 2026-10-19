Authentication-Results: smtp.subspace.kernel.org; arc=none smtp.remote-ip=209.85.216.51
ARC-Seal: i=1; d=subspace.kernel.org; s=arc20261015; a=rsa-sha256; cv=none;
	t=1792431843;
	b=CeEID2xiZpjJeweiDkBvJov5ODC8W2CuZ6zhM/tNmS3T4D2o9W9yaV9jYTsozgLtkTSU
	 qvaFg41pX32YtcIlV3clK6+bZeNvzvnP9XOri7EweuRtB+N3jH2ZO8ePOQy6kgGxl2jwj
	 cA8KhkaXorOi5qCz9MxhzxWVncRCKV4ukRec954O4+zPaXQLMaczDjThOfkGUwgA1yYKF
	 n9ltneEJEbv3MhMofT+FYkf9ZG9KQUPYHlRG/QrLixGsH5LQmi2WbdnTmhWqBz40kXRyG
	 14/FN+9r1GvO97H+fi4LMhptLvK6STOo0lrWl9NtyQjtz0ZyPs3lyNDH/AD2Xwhv5Bw==
ARC-Message-Signature: i=1; d=subspace.kernel.org; s=arc20261015;
	a=rsa-sha256; c=relaxed/relaxed; t=1792431843;
	h=DMARC-Filter:Received:DKIM-Signature:X-Google-DKIM-Signature:
	 X-Forwarded-Encrypted:X-Gm-Message-State:X-Gm-Gg:X-Received:Received:
	 From:To:Cc:Subject:Date:Message-ID:X-Mailer:MIME-Version:
	 Content-Transfer-Encoding;
	bh=ds7FADVPaOufPM8wkPqgl/05L1wAkB8WIhvDryqev1I=;
	b=1cbcxezPS0RGP5fPGxNxcOjVlJJ8uWHPRsHrKUdHCfIJ/SAhHbxdTk/Jz+o9jHyh1IIF
	 gFGzCyRUvWmbcr3rwAXWuZbTSg/8mAibAFyJR+ruyO6cuBHqIfdtfXjut3RpFfjEn/dIz
	 I49/lWXqi9dYLj2Io17d3fKhaJPR3DKFwUuUhaHtBW+/x68cn3FGWfK0+KPbU8JNexkLL
	 fdvScgqsinowkCWExxys5IqBFZYly+kKBHaLYA9hykR3BHMIxNFwwHnO3ZF2fNE+yEf64
	 UmkKaOMIfJiPtVynb8fvUaat4SumEmuPlPW83m3cTe67EaxQVxyWhPnW3YV+KbV7IMg==
ARC-Authentication-Results: i=1; smtp.subspace.kernel.org; 
	dmarc=pass header.from=nuro.ai;
	spf=pass smtp.mailfrom=nuro.ai;
	dkim=pass header.d=nuro.ai header.i=@nuro.ai header.a=rsa-sha256 header.s=google header.b=XWibj6mf;
	arc=none smtp.remote-ip=209.85.216.51
Received: from mail-pj1-f51.google.com (mail-pj1-f51.google.com [209.85.216.51])
	(using TLSv1.3 with cipher TLS_AES_128_GCM_SHA256 (128/128 bits)
	 key-exchange X25519 server-signature ECDSA (prime256v1) server-digest SHA256)
	(No client certificate requested)
	by smtp.subspace.kernel.org (Postfix) with ESMTPS id 2126E606A31B
	for <linux-kernel@vger.kernel.org>; Mon, 19 Oct 2026 17:44:02 +0000 (UTC)
DMARC-Filter: OpenDMARC Filter v1.4.2 smtp.subspace.kernel.org 2126E606A31B
Authentication-Results: smtp.subspace.kernel.org; dmarc=pass (p=quarantine dis=none) header.from=nuro.ai
Authentication-Results: smtp.subspace.kernel.org; spf=pass smtp.mailfrom=nuro.ai
Authentication-Results: smtp.subspace.kernel.org;
	dkim=pass (2048-bit key, unprotected) header.d=nuro.ai header.i=@nuro.ai header.a=rsa-sha256 header.s=google header.b=XWibj6mf
Received: by mail-pj1-f51.google.com with SMTP id 98e67ed59e1d1-3ab752f6244so2008184a91.2
        for <linux-kernel@vger.kernel.org>; Mon, 19 Oct 2026 10:44:02 -0700 (PDT)
DKIM-Signature: v=1; a=rsa-sha256; c=relaxed/relaxed;
        d=nuro.ai; s=google; t=1792431842; x=1793036642; darn=vger.kernel.org;
        h=content-transfer-encoding:mime-version:message-id:date:subject:cc
         :to:from:from:to:cc:subject:date:message-id:reply-to:content-type;
        bh=ds7FADVPaOufPM8wkPqgl/05L1wAkB8WIhvDryqev1I=;
        b=XWibj6mf97Dl5MQ9HVMCmbYBw5FhZgkhf3TSzZI9GSbNO+FFmw/6G3I8ETbdsMnOpi
         zYRbnjB3qN2EmHf7mvTwR3Gjspvh/2E/LxCewlcCq6ZVd2/rkx0fWFDTAM6dXscU1Vg5
         xAhPyLgWSKDjJJHYhnvGqR5mBfqg2v74/tMaYN5xhWzc6pEEzToN9JnjO7RS8McWGXIp
         o13tdOB7hq1vKdUIdbQF71M0CKh2TYzZfllo9885LsxfFFqPtH9Co4cbxLzaDeUzGUaT
         sNpajKB1KJfU82T4kiIMZ1K/mRXuBADjBWa1LUSlJL5PfWreSmJfmgsv7fY+vaoUuk5T
         7yHg==
X-Google-DKIM-Signature: v=1; a=rsa-sha256; c=relaxed/relaxed;
        d=1e100.net; s=20260707; t=1792431842; x=1793036642;
        h=content-transfer-encoding:mime-version:message-id:date:subject:cc
         :to:from:x-gm-gg:x-gm-message-state:from:to:cc:subject:date
         :message-id:reply-to:content-type;
        bh=ds7FADVPaOufPM8wkPqgl/05L1wAkB8WIhvDryqev1I=;
        b=MwLuC1PRjx37HNxQ+PvKSFqJVub6l/qnMsH3h6QpXD0kKvDehEun7kUNfdxcUqLJda
         sZivdacv5G3JJBAvWbxENxBNngrzEQEQyaVgFgmfQte0aJ+fgCIeKowua3UkzVz4vKpA
         MAOqjGdEKdQEQJuI/bAlKZCI6p1NZpfOdxFi28U/2eKZx6kh29h/WVwAw7y+ZMjJE8Cf
         PYEhpqc1KmwoNO19KGf/sLSQKfvBkjs1osoZsDDWuWXwnEpoz7AW61YwUBlf1f1Y6zDc
         jBqNSNjkL16SrCealtFlTBFc/l26GYLRivohM1ATvtPb/nLirXIReM9aZ+ec/Me9IAjF
         87iw==
X-Forwarded-Encrypted: i=1; AKwUvBy5DOGS1kCQFtq/ZWee8jyDzazmBIQodMCey91u3LNwV47AqcT7dUpcvJbIQKqScucWCcWS/eZZrnMkiis=@vger.kernel.org
X-Gm-Message-State: AFq9FYKeA/RNIsMqdgm/xizcmhyP2Gqx/rtXbnNAcjAZaAfMwPJ1Vj5n
	N3cPZ6N8Du96yPa5QOgiXUeM/lFHbGxfEO/OcB5WxoKCNMbxX4RYJUmEJPeMw8V39Pk=
X-Gm-Gg: AYBFou3Jgc1FT4nGjIzNVKJvaAwx2Z16O7eYBlc2n1eypJwF4AVOGE8c+aGFDb9KByR
	8dWmu1VQV7EwhhlRlPqGylbZbfG22KVXW8ROO+Xj28XOcpGuOTziQbAiiW9JJ1rY83oyFMlIvHI
	IgilZs3OnlrfmfcVE5JJqBHIZcsP3L0AOSGP0g7lTxFnYWy3jM6yuFycCsl1MaGcv2hKRoLL5La
	YNzMOBzTqnI6+3VAkN7gO3yIpZqlSSyObHgYPpNHGvTkto3ktH6ma4oYjr21UTanvSfTtecAp75
	lW3DiJVw9DjFI+cRj4pY/GWsOLYm3rijQNgMjnZdfvtRpxAvMoP5GFKCKlCJS1mKONcsWf1m/ca
	f+o37mcbkltgtV1xdpgtbvnb2BOtNBwm668O/3wbfbILbbACByTixlKZKjJXvcUB6ViBzQBwT+L
	BDs6aRenYlHR7/0TYPbI3pWdzFwDofkJjuzCD+zsYAIPz+fdZYxBZO//a/VV/XF9TmgCjbV79rK
	fGb98U+uR0=
X-Received: by 2002:a17:90b:4c4c:b0:3ac:450b:164c with SMTP id 98e67ed59e1d1-3acef15a266mr8174170a91.47.1792431842342;
        Mon, 19 Oct 2026 10:44:02 -0700 (PDT)
Received: from jkain-desktop.corp.nuro.team ([64.124.43.154])
        by smtp.gmail.com with ESMTPSA id 98e67ed59e1d1-3ad5d400505sm453912a91.4.2026.10.19.10.44.01
        (version=TLS1_3 cipher=TLS_AES_256_GCM_SHA384 bits=256/256);
        Mon, 19 Oct 2026 10:44:01 -0700 (PDT)
From: Joseph Kain <jkain@nuro.ai>
To: netdev@vger.kernel.org
Cc: edumazet@kernel.org,
	davem@davemloft.net,
	kuba@kernel.org,
	pabeni@redhat.com,
	horms@kernel.org,
	kuniyu@google.com,
	kerneljasonxing@gmail.com,
	bigeasy@linutronix.de,
	clrkwllms@kernel.org,
	rostedt@goodmis.org,
	linux-rt-devel@lists.linux.dev,
	linux-kernel@vger.kernel.org,
	Joseph Kain <jkain@nuro.ai>
Subject: [PATCH net v6] net: schedule a purge when the defer queue rejects a free
Date: Mon, 19 Oct 2026 10:44:00 -0700
Message-ID: <20261019174400.1377093-1-jkain@nuro.ai>
X-Mailer: git-send-email 2.55.0
X-Mailing-List: linux-kernel@vger.kernel.org
List-Id: <linux-kernel.vger.kernel.org>
List-Post: <mailto:linux-kernel@vger.kernel.org>
List-Help: <mailto:linux-kernel+help@vger.kernel.org>
List-Subscribe: <mailto:linux-kernel+subscribe@vger.kernel.org>
List-Unsubscribe: <mailto:linux-kernel+unsubscribe@vger.kernel.org>
List-Owner: <mailto:linux-kernel+owner@vger.kernel.org>
Precedence: list
MIME-Version: 1.0
Content-Transfer-Encoding: 8bit

__skb_defer_free_flush() can leave defer_count at or above skb_defer_max
with an empty defer_list. That state is absorbing: every producer then
takes the nodefer path without queueing, so the list never refills.
Deferred freeing stays off for that (cpu, node) until reboot, and
cross-CPU frees fall back to the page allocator, which is the contention
deferral exists to avoid.

skb_attempt_defer_free() increments before testing the limit and keeps
the increment when it rejects, so a rejected free leaves the counter
raised with nothing queued.

Nothing brings it back down. The reject path returns before
kick_defer_list_purge(), so once the counter is stuck no producer
schedules a flush on the owner CPU. A CPU that never raises NET_RX itself
-- an application CPU doing TX while NIC IRQs are pinned elsewhere and
RPS is off -- then never runs the flush at all, so clearing the counter
inside the flush cannot help it either. proc_do_skb_defer_max() neither
resets the counters nor schedules a flush when the limit changes.

It is reachable with no race at all:

  sysctl -w net.core.skb_defer_max=1    # frees increment, then reject
  sysctl -w net.core.skb_defer_max=128  # does not recover

skb_defer_max has .extra1 = SYSCTL_ZERO and no .extra2, so 1 is settable.
From v7.1 on, 0 is safe because proc_do_skb_defer_max() flips
skb_defer_disable_key and the producer returns before incrementing. On
6.18 through 7.0, which carry the llist conversion but not commit
08dc30de1a40 ("net: add skb_defer_disable_key static key"), setting 0 and
restoring the previous value strands the counter the same way -- and 0 is
the documented way to turn the feature off.

Kick the purge from the reject path instead. The reject is the one place
that observes a full queue, so scheduling the flush there is what stops
the counter outliving the list, and it does not depend on the owner CPU
ever raising NET_RX on its own. kick_defer_list_purge() already coalesces
through sd->defer_ipi_scheduled, so a burst of rejects costs one IPI.

This also covers the case where skb_defer_max is lowered below the
current defer_count. The kick condition tests equality with half the
limit, so a reduction can move that point behind the counter and no
later producer ever reaches it; rejecting without a kick then strands a
non-empty list the same way. The reject-path kick recovers both.

While here, test the limit with > rather than >=, so the effective limit
is skb_defer_max rather than skb_defer_max - 1, matching what
Documentation/admin-guide/sysctl/net.rst describes.

That also makes the half-capacity kick reachable at small limits. At
skb_defer_max = 1 nothing was ever queued, so no kick was ever sent, and
at 2 the equality was never hit; both now kick. That is what commit
c09b0cd2cc6c ("net: avoid strange behavior with skb_defer_max == 1") set
out to allow.

Also drain before clearing in the flush. A producer that queues between
the clear and the drain currently has its skb drained but its increment
kept, which over-counts and costs deferral until the next flush.
Draining first matches the ordering __dev_xmit_skb() already uses for the
qdisc defer_list.

Found by manual code inspection, LLM-assisted, while backporting the
llist conversion to 6.1 after hitting the sd->defer_lock contention it
removes. The latch itself was not hit in production; it was reproduced by
lowering net.core.skb_defer_max.

Fixes: 844c9db7f7f5 ("net: use llist for sd->defer_list")
Suggested-by: Kuniyuki Iwashima <kuniyu@google.com>
Assisted-by: Claude:claude-opus-5
Signed-off-by: Joseph Kain <jkain@nuro.ai>
---
v6:
 - Keep the increment and kick the purge from the reject path, rather
   than testing before incrementing as v4 did. One atomic instead of a
   read followed by an RMW, the increment still reserves the slot so the
   limit stays exact, and it also recovers the case where skb_defer_max
   is lowered below the current defer_count, which v4 did not
   (Kuniyuki Iwashima; also reported against v3 and v4 by
   netdev-bot sashiko, whose suggested fix this is).
 - Describe the two resulting behaviour changes -- the effective limit
   and the kick at small limits -- in the commit message rather than
   only here, since git am drops this part (netdev-bot sashiko).

Measured on v7.3-rc6 in a VM, 8 cpus, cross-CPU TCP load, sampling
defer_count via bpftrace. Dropping net.core.skb_defer_max from 128 to 1
and then restoring 128:

  7b63ef2d55f2 (unpatched)  defer_count climbed 701404 -> 3244783 and
                            stayed at 3244783 after restoring 128
  this patch                defer_count stayed within 0..1 throughout
                            and returned to 0

With skb_defer_max=1 and a cross-CPU TCP load, kick_defer_list_purge()
is called 0 times before this patch and ~756k times after, over ~750k
skb_attempt_defer_free() calls; at skb_defer_max=2, 0 before and ~163k
after.

Built for x86_64 and arm64, with and without CONFIG_PREEMPT_RT.

v4: https://lore.kernel.org/all/20261015162209.485940-1-jkain@nuro.ai/
v3: https://lore.kernel.org/all/20261013205416.3417296-1-jkain@nuro.ai/
v2: https://lore.kernel.org/all/20261008220256.1844072-1-jkain@nuro.ai/
v1: https://lore.kernel.org/all/20261007180056.1394868-1-jkain@nuro.ai/
 net/core/dev.c    | 5 ++++-
 net/core/skbuff.c | 8 +++++++-
 2 files changed, 11 insertions(+), 2 deletions(-)

diff --git a/net/core/dev.c b/net/core/dev.c
index 18dc88990510..60d86bc21632 100644
--- a/net/core/dev.c
+++ b/net/core/dev.c
@@ -6940,8 +6940,11 @@ static void __skb_defer_free_flush(struct skb_defer_node *sdn, int budget)
 
 	if (llist_empty(&sdn->defer_list))
 		return;
-	atomic_long_set(&sdn->defer_count, 0);
 	free_list = llist_del_all(&sdn->defer_list);
+	/* Racy on purpose, as in __dev_xmit_skb(): a producer landing between
+	 * the del_all and this store stays queued but uncounted.
+	 */
+	atomic_long_set(&sdn->defer_count, 0);
 
 	llist_for_each_entry_safe(skb, next, free_list, ll_node) {
 		prefetch(next);
diff --git a/net/core/skbuff.c b/net/core/skbuff.c
index 4aea06d5167d..643666d9f4c9 100644
--- a/net/core/skbuff.c
+++ b/net/core/skbuff.c
@@ -7388,8 +7388,14 @@ nodefer:	kfree_skb_napi_cache(skb);
 	defer_max = READ_ONCE(net_hotdata.sysctl_skb_defer_max);
 	defer_count = atomic_long_inc_return(&sdn->defer_count);
 
-	if (defer_count >= defer_max)
+	if (unlikely(defer_count > defer_max)) {
+		/* The kept increment only comes back down when a flush zeroes
+		 * it, and this is the one path that sees a full queue.
+		 */
+		if (!llist_empty(&sdn->defer_list))
+			kick_defer_list_purge(cpu);
 		goto nodefer;
+	}
 
 	llist_add(&skb->ll_node, &sdn->defer_list);
 
-- 
2.55.0

