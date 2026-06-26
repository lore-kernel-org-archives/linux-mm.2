Return-Path: <owner-linux-mm@kvack.org>
X-Spam-Checker-Version: SpamAssassin 3.4.0 (2014-02-07) on
	aws-us-west-2-korg-lkml-1.web.codeaurora.org
Received: from kanga.kvack.org (kanga.kvack.org [205.233.56.17])
	(using TLSv1 with cipher DHE-RSA-AES256-SHA (256/256 bits))
	(No client certificate requested)
	by smtp.lore.kernel.org (Postfix) with ESMTPS id 0FB36CDE008
	for <linux-mm@archiver.kernel.org>; Fri, 26 Jun 2026 10:24:22 +0000 (UTC)
Received: by kanga.kvack.org (Postfix)
	id EE9F26B0100; Fri, 26 Jun 2026 06:24:16 -0400 (EDT)
Received: by kanga.kvack.org (Postfix, from userid 40)
	id EC0846B0102; Fri, 26 Jun 2026 06:24:16 -0400 (EDT)
X-Delivered-To: int-list-linux-mm@kvack.org
Received: by kanga.kvack.org (Postfix, from userid 63042)
	id DB1D56B0103; Fri, 26 Jun 2026 06:24:16 -0400 (EDT)
X-Delivered-To: linux-mm@kvack.org
Received: from relay.hostedemail.com (smtprelay0015.hostedemail.com [216.40.44.15])
	by kanga.kvack.org (Postfix) with ESMTP id B5DB76B0100
	for <linux-mm@kvack.org>; Fri, 26 Jun 2026 06:24:16 -0400 (EDT)
Received: from smtpin25.hostedemail.com (lb01a-stub [10.200.18.249])
	by unirelay02.hostedemail.com (Postfix) with ESMTP id 4545D120403
	for <linux-mm@kvack.org>; Fri, 26 Jun 2026 10:24:16 +0000 (UTC)
X-FDA: 84921678912.25.9C16ECB
Received: from relay1-d.mail.gandi.net (relay1-d.mail.gandi.net [217.70.183.193])
	by imf03.hostedemail.com (Postfix) with ESMTP id 4FFF420009
	for <linux-mm@kvack.org>; Fri, 26 Jun 2026 10:24:14 +0000 (UTC)
Authentication-Results: imf03.hostedemail.com;
	spf=pass (imf03.hostedemail.com: domain of alex@ghiti.fr designates 217.70.183.193 as permitted sender) smtp.mailfrom=alex@ghiti.fr
ARC-Seal: i=1; a=rsa-sha256; d=hostedemail.com; s=arc-20220608; cv=none;
	t=1782469454;
	b=dChqttwhQoBCkcqWr1m13mDK/Ue1CNfoxZXT3AwFa1osUiRy5pmct9OIRS+uSjd6Qu7Rzr
	2BtwEtr8Zs0xSxMMJRN2Z8eePwkktbJUqEu7aK44oo1W6OI83uP1hQUaW2MdN9mTD4a1zL
	wBqn32vcZ69sRGlOv9fKUYwU1qu82YE=
ARC-Message-Signature: i=1; a=rsa-sha256; c=relaxed/relaxed; d=hostedemail.com;
	s=arc-20220608; t=1782469454;
	h=from:from:sender:reply-to:subject:subject:date:date:
	 message-id:message-id:to:to:cc:cc:mime-version:mime-version:
	 content-type:content-type:
	 content-transfer-encoding:content-transfer-encoding:in-reply-to:
	 references; bh=51qIM4p1NvfZURtbRRB+90FDO1iGM4P1BpNeTkPJIsU=;
	b=szdpWNQEWV6+05o1EpHHPv9EtUCYV8mQR1ocaeMuV3nnZG4fvsnnIydkcObB/rA/Ai321/
	zcypaU50+LGt5YA1a0mlGdUcJwYbWAM5cnYXqzRxTyZNNPSm9mcz4uVhiy6vns6TxbG7DY
	/aktDbFDb99yK4HnPf12W+6Iu/P5VwE=
ARC-Authentication-Results: i=1;
	imf03.hostedemail.com;
	dkim=none;
	dmarc=none;
	spf=pass (imf03.hostedemail.com: domain of alex@ghiti.fr designates 217.70.183.193 as permitted sender) smtp.mailfrom=alex@ghiti.fr
Received: by mail.gandi.net (Postfix) with ESMTPSA id F10933EC32;
	Fri, 26 Jun 2026 10:24:05 +0000 (UTC)
From: Alexandre Ghiti <alex@ghiti.fr>
To: alexandre@ghiti.fr,
	Andrew Morton <akpm@linux-foundation.org>
Cc: Axel Rasmussen <axelrasmussen@google.com>,
	Barry Song <baohua@kernel.org>,
	Ben Segall <bsegall@google.com>,
	cgroups@vger.kernel.org,
	Chengming Zhou <chengming.zhou@linux.dev>,
	Christoph Lameter <cl@gentwo.org>,
	David Hildenbrand <david@kernel.org>,
	Dennis Zhou <dennis@kernel.org>,
	Dietmar Eggemann <dietmar.eggemann@arm.com>,
	Ingo Molnar <mingo@redhat.com>,
	Johannes Weiner <hannes@cmpxchg.org>,
	Juri Lelli <juri.lelli@redhat.com>,
	Kairui Song <kasong@tencent.com>,
	Kent Overstreet <kent.overstreet@linux.dev>,
	K Prateek Nayak <kprateek.nayak@amd.com>,
	"Liam R. Howlett" <liam@infradead.org>,
	linux-kernel@vger.kernel.org,
	linux-mm@kvack.org,
	Lorenzo Stoakes <ljs@kernel.org>,
	Mel Gorman <mgorman@suse.de>,
	Michal Hocko <mhocko@kernel.org>,
	Mike Rapoport <rppt@kernel.org>,
	Minchan Kim <minchan@kernel.org>,
	Muchun Song <muchun.song@linux.dev>,
	Nhat Pham <nphamcs@gmail.com>,
	Peter Zijlstra <peterz@infradead.org>,
	Qi Zheng <qi.zheng@linux.dev>,
	Roman Gushchin <roman.gushchin@linux.dev>,
	Sergey Senozhatsky <senozhatsky@chromium.org>,
	Shakeel Butt <shakeel.butt@linux.dev>,
	Steven Rostedt <rostedt@goodmis.org>,
	Suren Baghdasaryan <surenb@google.com>,
	Tejun Heo <tj@kernel.org>,
	Valentin Schneider <vschneid@redhat.com>,
	Vincent Guittot <vincent.guittot@linaro.org>,
	Vlastimil Babka <vbabka@kernel.org>,
	Wei Xu <weixugc@google.com>,
	Yosry Ahmed <yosry@kernel.org>,
	Yuanchu Xie <yuanchu@google.com>,
	Alexandre Ghiti <alex@ghiti.fr>
Subject: [RESEND PATCH v2 0/9] per-memcg-per-node kmem accounting 
Date: Fri, 26 Jun 2026 12:20:49 +0200
Message-ID: <20260626102358.1603618-1-alex@ghiti.fr>
X-Mailer: git-send-email 2.54.0
MIME-Version: 1.0
Content-Type: text/plain; charset=UTF-8
Content-Transfer-Encoding: 8bit
X-GND-Sasl: alex@ghiti.fr
X-GND-State: clean
X-GND-Score: -100
X-GND-Cause: dmFkZTFhzY+biii5o3KhBLXaB+yyOv/umMcrPwchRIx4RYTC8ZjuYqysyo8r9nn3JKFmuG5Uk19BkC2D6n8TEC2Mcfy0nWPMVo8nc30IfS2BQHP3oO0XNvewSEjWxb+V+qXMeRrtEKaGMMN9KJMmBImmJx8NHyydw95ZZXxvE37YDgEJZry67dNdgLYaBvPH0mkgJ2HJEix+LUBCmDT45jCR4G82gG4ltLEJD97Z4sTDy7iebPKO3MVGE3lGNo3HwfpWa7pKcvGkNgi9U3x0cVIkCM2Z80V7XQ2XQIbDr+VMH4CwqiT0IbbxGuhT+dlPaPB7avStLr1QMtlPw4YJ5pYQFUwuQTrjyic8RRkpI+HOrJR8UzmJBvLDzvyOTIp1XhAtXJPnou/rxmuzLCAhwpAVltubXwTG0Ddbt+S7/GMg+nC84VtSyU8vJt2okiaHa+RJkDntCIJnrFhrNSB2nj7wjxcaNvVayVgWUvhgTzhHA8Mj3kk5EPtB436pgNAAKIZ8wDZOpoPudHxN5HPh0HX6VzaAILadEft/ZNX0Xrl2eGk9eW2R+jqKebzaW/I6HVplP17GNzD6jQqzR/l3L+Z4HxrYzNfRB5VcpTxDYlySe3pQo+yky0quIy54NBq9uQP7bmricCdorkEiWtOkBnx1Y7cjDeg4qPDhBSGV1QOGln8GTQ
X-Rspam-User: 
X-Rspamd-Server: rspam08
X-Rspamd-Queue-Id: 4FFF420009
X-Stat-Signature: f6muaja48nfymn9mte4zaptuhhqcg5mi
X-HE-Tag: 1782469454-977049
X-HE-Meta: U2FsdGVkX1+Dyepowpq/TpZ7L9rMkZGdKvul1vsK33sIpvQlK/R/WA8gW/5w2nlXXIHH4E5vm9k3xpEyNersutFYmyXZbkHPFNQKDMBHz3Y3PiOAM5gZn+rkDbWEpRiuhvuktYnH0cVEMAKP8WZFBQlaDpgkFJKkLUdPt5i76amz+86mMJZAA9I4/h2MRAc2xowPJ2Ls77wfAVg2u1HooXa6FlX3FP5kvakGkGSddtw4jp65Z0kJpoJ00DklOav8+/WxL9pwMCKMWQKx0N3iq7FvDfJQiM+y6R3JoGbgOBs0+MQo8zoGxub1Lw600tiDlHoiwSxehyNKMlqdURHysyMUE2DuU+Oo+/a+oJOqcSfjgtO2+gIkZCTWg299JTvxJt4x1fqwgbPNEl3CFDxb9WvmpD4+7MAkjG9b7/bQPTb8iQHWlYUuLaDVN5wdCW0BVPr6RKZikbs2bdVMctMXMHMqLXBNMi+vVLKjJ1e6fI2uGej2G+xkaeyH5FYmTl5v79gUKn0hJkoSwfpCYV/thsHEZqmfYE9O+IdZBV6UmuxNfuMYOHt1H7Ti/MnvYfBSgmoihF/y47N2SHifPU9BaHzE7swjIFCqg/nWm+uecD08jqj9OUnOikvXEvAby15fxrZKjZghSGM4jtLeUFIG3+7pBoD5c4OHSXO7HVMHl6PDUvpHPxjGZZIOv2+ywSeRreYY//Ecm7oMWdgAhuX/3aG7lT4CJlaf7xi15YyJyEBAD/OWjeHcukzt9GWfX/ds6Bss9mI12vUbrh8MEcS+OT7cU1OVm5uPObYtL2D1JgPYDmxKUHQ1XbkECto+gyZv8Ufa0R8Le3sS46i/TFxW4xHGKb736aUp5AW3k4hj5JTDl2OppK5LSvCrDdGe7ov15ZDxNVAjzBQVEYGTIt50OUCGb0YBEhoxxZ/ekU/XUip0ZhXaTR1PgR485dMl0LNNohkvfa8YqfoPfbZYOZ6
 RD4Sigcq
 hgJl4TZ6Llfk9OkxKaWJJMs/OltiK97Y4TJT/csZQ5TH/NzrIX80nVBjlmqs85PSU9l+OZIGBbr0Fqt/X0vbuiMQt4RZZknMamplmqMKC9YQmf2m1hgFctN+UQ+a0gDKNSkp7
Sender: owner-linux-mm@kvack.org
Precedence: bulk
X-Loop: owner-majordomo@kvack.org
List-ID: <linux-mm.kvack.org>
List-Subscribe: <mailto:majordomo@kvack.org>
List-Unsubscribe: <mailto:majordomo@kvack.org>

This is version 2 of per-memcg-per-node kmem accounting.

As asked by Joshua, I ran some microbenchmarks to check the impact of
this fine grain accounting.

TL;DR: There is a substantial impact (up to +337% on small percpu allocations)
on a benchmark that loops over small percpu allocations. On the other hand,
on a userspace program that creates a bpf percpu map, this cost is not visible.

I followed Joshua's advice and now this version batches the memcg accounting:
it improves the performance +337% vs +417% (v1) on 176 cores single node
machine and +153% vs 206% (v1) on 80 cores 2 nodes machine.

We can see that the overhead of this version scales linearly with the number of
cpus (the number of nodes being small). This overhead comes mainly from
vmalloc_to_page() so I have another variant (b) that decreases the impact even
more (+131% vs +337% on 176 cores and +86% vs +153% on 80 cores) but I'm not
sure the added complexity is needed so I did not send this version, let me know
what you think.

Performance
===========

All benchmarks run in a memcg with __GFP_ACCOUNT.

1) BPF percpu map create/destroy, full series vs baseline kernel (two
   boots, 176-CPU AMD EPYC, 1 NUMA node): the per-node accounting is lost
   in the BPF syscall overhead, the delta is within noise (us/op):

     size (B):    64     256    1024   4096   8192
     delta:     -5.5%  -5.1%  -1.8%  -5.1%  -4.1%

2) In-kernel microbench that isolates the accounting cost: a tight
   __alloc_percpu_gfp()/free_percpu() loop, __GFP_ACCOUNT on vs off on the
   same boot (ACCT COST = on - off). The dominant cost on a many-CPU box
   is discovering each backing page's real node (vmalloc_to_page() per
   possible CPU). ACCT COST by value size:

   176-CPU EPYC, 1 node
     size (B):              64       256      1024     4096     8192
      baseline (upstream)  +5.3%    +5.4%    +0.1%    -1.8%    -0.5%
      v1 credit (per-page) +417.3%  +182.5%  +68.5%   +21.4%   +16.1%
   a) per-node accounting  +337.8%  +141.8%  +36.1%   +11.9%   +6.8%
   b) per-page nid cache   +131.3%  +53.7%   +10.5%   +0.9%    +2.0%
   c) single-node fast     +12.6%   +12.1%   +3.5%    +6.6%    +0.7%

   80-CPU Xeon Gold 6138, 2 nodes (fast path inactive)
     size (B):              64       256      1024     4096     8192
      baseline (upstream)  +1.2%    -3.8%    +12.4%   +1.2%    +0.5%   (noise)
      v1 credit (per-page) +206.1%  +134.0%  +44.5%   +11.6%   +11.5%
   a) per-node accounting  +153.2%  +64.7%   +19.4%   +4.2%    +5.9%
   b) per-page nid cache   +86.5%   +45.5%   +14.7%   +1.8%    +1.6%

   (a) this patchset without fast path for single node
   (b) is an alternative version, not in this series, that caches each backing
       page's node in the chunk so the walk is paid once per page instead of
       once per allocation
   (c) this patchset with fast path for single node

Changes in v2
=============

- objcg lifetime: Shakeel's patch 1 now guarantees the lifetime of every
  per-node objcg
- dropped patch 5 and 6 since Shakeel's patch 2 replaces them
- fixed the number of precharged pages (the v1 formula under-precharged)
- per-node batching (Joshua's suggestion): accumulate the per-node bytes
  first, then issue one account_kmem()/uncharge() per touched node =>
  O(nodes) memcg ops instead of O(num_possible_cpus)
- single-node fast path: skip the per-cpu node walk on single node machines
- obj_exts metadata is now accounted per-node (walk its vmalloc pages)
  rather than charged whole to one memcg (Shakeel's main v1 objection).
- renamed obj_cgroup_get_nid() -> obj_cgroup_nid() (returns a borrowed RCU
  pointer, no ref taken).
- zswap: fixed the missing locking around the per-node objcg lookup (now
  done under RCU + obj_cgroup_tryget()).

This series pursues the work initiated by Joshua [1]. We need kernel
memory to be accounted on a per-node basis in order to be able to know
the memcg <-> physical memory association.

This series takes advantage of the recently introduced per-node
obj_cgroup and makes those obj_cgroup tied to their NUMA node.

The bulk of the series is percpu per-node accounting: percpu
"precharges" the memcg before we know the actual location of the pages
it uses, so charging and accounting had to be split. All other kmem
users (slab, __memcg_kmem_charge_page) are now handled directly by
Shakeel's per-node obj_cgroup infrastructure this series sits on, so
only percpu and zswap need explicit per-node work here (zswap support
is limited because Joshua is working on it in parallel [3]).

Thanks Joshua and Shakeel for the early feedback!

[1] https://lore.kernel.org/linux-mm/20260404033844.1892595-1-joshua.hahnjy@gmail.com/
[2] https://lore.kernel.org/linux-mm/56c04b1c5d54f75ccdc12896df6c1ca35403ecc3.1772711148.git.zhengqi.arch@bytedance.com/
[3] https://lore.kernel.org/linux-mm/20260311195153.4013476-1-joshua.hahnjy@gmail.com/

Functional Testing
==================

- Tested with a percpu kmem self-test in an 8-node VM (2 nodes with CPUs,
  6 memory-only). For each allocation it checks that every node is charged
  and later uncharged the same number of bytes -- including a CPU-less node
  that ends up holding the obj_exts metadata -- and that nothing is left
  charged after teardown. All checks pass. (The self-test module is not
  part of this series.)

Alexandre Ghiti (7):
  mm: percpu: fix obj_exts metadata charge size
  mm: percpu: Split memcg charging and kmem accounting
  mm: memcontrol: track MEMCG_KMEM per NUMA node
  mm: percpu: per-node kmem accounting
  mm: percpu: per-node kmem accounting for obj_exts metadata
  mm: percpu: skip the per-cpu node walk on single-node systems
  mm: zswap: per-node kmem accounting for zswap/zsmalloc

Shakeel Butt (2):
  memcg: convert task->objcg to a per-node objcgs array
  memcg: charge kmem pages and slab objects against per-node objcg

 include/linux/memcontrol.h |  23 ++-
 include/linux/mmzone.h     |   1 +
 include/linux/sched.h      |   7 +-
 include/linux/zsmalloc.h   |   2 +
 mm/memcontrol.c            | 286 ++++++++++++++++++++++++++-----------
 mm/percpu-internal.h       |   2 +-
 mm/percpu.c                | 108 +++++++++++++-
 mm/vmstat.c                |   1 +
 mm/zsmalloc.c              |  11 ++
 mm/zswap.c                 |  19 ++-
 10 files changed, 361 insertions(+), 99 deletions(-)

-- 
2.54.0


