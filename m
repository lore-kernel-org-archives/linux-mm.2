Return-Path: <owner-linux-mm@kvack.org>
X-Spam-Checker-Version: SpamAssassin 3.4.0 (2014-02-07) on
	aws-us-west-2-korg-lkml-1.web.codeaurora.org
Received: from kanga.kvack.org (kanga.kvack.org [205.233.56.17])
	(using TLSv1 with cipher DHE-RSA-AES256-SHA (256/256 bits))
	(No client certificate requested)
	by smtp.lore.kernel.org (Postfix) with ESMTPS id 1EB7BCD4F26
	for <linux-mm@archiver.kernel.org>; Fri, 26 Jun 2026 10:23:33 +0000 (UTC)
Received: by kanga.kvack.org (Postfix)
	id 0DDA76B00FE; Fri, 26 Jun 2026 06:23:32 -0400 (EDT)
Received: by kanga.kvack.org (Postfix, from userid 40)
	id 0B56A6B0100; Fri, 26 Jun 2026 06:23:32 -0400 (EDT)
X-Delivered-To: int-list-linux-mm@kvack.org
Received: by kanga.kvack.org (Postfix, from userid 63042)
	id F370D6B0101; Fri, 26 Jun 2026 06:23:31 -0400 (EDT)
X-Delivered-To: linux-mm@kvack.org
Received: from relay.hostedemail.com (smtprelay0016.hostedemail.com [216.40.44.16])
	by kanga.kvack.org (Postfix) with ESMTP id C47246B00FE
	for <linux-mm@kvack.org>; Fri, 26 Jun 2026 06:23:31 -0400 (EDT)
Received: from smtpin13.hostedemail.com (lb01a-stub [10.200.18.249])
	by unirelay08.hostedemail.com (Postfix) with ESMTP id 4F6F41403C1
	for <linux-mm@kvack.org>; Fri, 26 Jun 2026 10:23:31 +0000 (UTC)
X-FDA: 84921677022.13.CEABB41
Received: from relay6-d.mail.gandi.net (relay6-d.mail.gandi.net [217.70.183.198])
	by imf13.hostedemail.com (Postfix) with ESMTP id 52B2F2000A
	for <linux-mm@kvack.org>; Fri, 26 Jun 2026 10:23:29 +0000 (UTC)
Authentication-Results: imf13.hostedemail.com;
	spf=pass (imf13.hostedemail.com: domain of alex@ghiti.fr designates 217.70.183.198 as permitted sender) smtp.mailfrom=alex@ghiti.fr
ARC-Seal: i=1; a=rsa-sha256; d=hostedemail.com; s=arc-20220608; cv=none;
	t=1782469409;
	b=vpHBciBcq3VoctlpFOHCVLieIHhpvwYO4uvRsrqATPD/fdQJCMUcbV6W+bCabR1biO/G3G
	K8pdG6vwgjyF/oXk1w3zDF5LKZBP5AMNaqaTCDR2Ee19PdE5neZpNb5Cd3IOnbMzi6OC4T
	ZN4ksaOF+nLwNvsv7AixZRgj65obOHc=
ARC-Message-Signature: i=1; a=rsa-sha256; c=relaxed/relaxed; d=hostedemail.com;
	s=arc-20220608; t=1782469409;
	h=from:from:sender:reply-to:subject:subject:date:date:
	 message-id:message-id:to:to:cc:cc:mime-version:mime-version:
	 content-type:content-type:
	 content-transfer-encoding:content-transfer-encoding:
	 in-reply-to:in-reply-to:references:references;
	bh=1UGPr4FuFVKFO7wJHZXJDPTxeqyTNT6LmaAkA6di9TE=;
	b=01tFd+9+2zqA7hQijYdIWdbSpfJmKECMtlJe1tGT9xIe1dvmx2aSmYzaroXlGzEiv62jrC
	5+j6+M7T7jc/hzAGIAq1wDq8556XbP93KIry8GWRQzccxf4EGPYnKUALGHPSwKh+O9exga
	TbcT2bjkUa9l8wuV/01ey27m48tJbXY=
ARC-Authentication-Results: i=1;
	imf13.hostedemail.com;
	dkim=none;
	dmarc=none;
	spf=pass (imf13.hostedemail.com: domain of alex@ghiti.fr designates 217.70.183.198 as permitted sender) smtp.mailfrom=alex@ghiti.fr
Received: by mail.gandi.net (Postfix) with ESMTPSA id 8971A3EBB0;
	Fri, 26 Jun 2026 10:23:20 +0000 (UTC)
Message-ID: <c7ed65c7-c5a4-4a20-b230-3a94c001dc38@ghiti.fr>
Date: Fri, 26 Jun 2026 12:23:19 +0200
MIME-Version: 1.0
User-Agent: Mozilla Thunderbird
Subject: Re: [PATCH v2 0/9] per-memcg-per-node kmem accounting
To: Andrew Morton <akpm@linux-foundation.org>
Cc: Axel Rasmussen <axelrasmussen@google.com>, Barry Song
 <baohua@kernel.org>, Ben Segall <bsegall@google.com>,
 cgroups@vger.kernel.org, Chengming Zhou <chengming.zhou@linux.dev>,
 Christoph Lameter <cl@gentwo.org>, David Hildenbrand <david@kernel.org>,
 Dennis Zhou <dennis@kernel.org>, Dietmar Eggemann
 <dietmar.eggemann@arm.com>, Ingo Molnar <mingo@redhat.com>,
 Johannes Weiner <hannes@cmpxchg.org>, Juri Lelli <juri.lelli@redhat.com>,
 Kairui Song <kasong@tencent.com>, Kent Overstreet
 <kent.overstreet@linux.dev>, K Prateek Nayak <kprateek.nayak@amd.com>,
 "Liam R. Howlett" <liam@infradead.org>, linux-kernel@vger.kernel.org,
 linux-mm@kvack.org, Lorenzo Stoakes <ljs@kernel.org>,
 Mel Gorman <mgorman@suse.de>, Michal Hocko <mhocko@kernel.org>,
 Mike Rapoport <rppt@kernel.org>, Minchan Kim <minchan@kernel.org>,
 Muchun Song <muchun.song@linux.dev>, Nhat Pham <nphamcs@gmail.com>,
 Peter Zijlstra <peterz@infradead.org>, Qi Zheng <qi.zheng@linux.dev>,
 Roman Gushchin <roman.gushchin@linux.dev>,
 Sergey Senozhatsky <senozhatsky@chromium.org>,
 Shakeel Butt <shakeel.butt@linux.dev>, Steven Rostedt <rostedt@goodmis.org>,
 Suren Baghdasaryan <surenb@google.com>, Tejun Heo <tj@kernel.org>,
 Valentin Schneider <vschneid@redhat.com>,
 Vincent Guittot <vincent.guittot@linaro.org>,
 Vlastimil Babka <vbabka@kernel.org>, Wei Xu <weixugc@google.com>,
 Yosry Ahmed <yosry@kernel.org>, Yuanchu Xie <yuanchu@google.com>
References: <20260626101356.1599643-1-alex@ghiti.fr>
Content-Language: en-US
From: Alexandre Ghiti <alex@ghiti.fr>
In-Reply-To: <20260626101356.1599643-1-alex@ghiti.fr>
Content-Type: text/plain; charset=UTF-8; format=flowed
Content-Transfer-Encoding: 7bit
X-GND-Sasl: alex@ghiti.fr
X-GND-Cause: dmFkZTEhdky9hIIMuJGkZ6D0E9bX4u5uN/gwmQdlGtrbAyh4LCB2rKhQLzgWjQW6XDIzKtlmgQujkmwjKg4JaMFj/54OARnVMmRFzAgR2uefgK5+JIwqaEpAd20Q/110HVA/xHloJOGUF+yUFdWLgSEYkKSUMRElM4q6fsR5yVd6yI2Lx+J1iY8OVGWEjK0sVBJ+XCHArRTx9YNoXT1P7asoZ0r+8wbTO9wHmiFe4zBNUKx2QWIPwH8cQOuWaj6mxCydB/Go8hT5mH8/uyCCWZrMQkjKPWGjQ8BY7yOWrAOZA8VNrnnjRCcU3e6x9iSM487IObFPo+nH5ogswY/mfxFFcnMsLGkP+zbLbM2lske3CE7e0LxF7hK3vdSbaMmhIgpaNgn9ZlQcFDmIs5E1MHqccZl/F2MdaDJyw3wyX3nW580MB7BZxMWzR5UDsr545uiwxytoyIXqhFdbAlmFSPA19N74HQ4VvwMUqhABGTwBIR5gY8J57gNIbSR3dPNZsGZ1T5Vp2lUbeK/8EnQrZa7SCJF2Q5FFJgBd/zFyTxYiD3pW/zyHMd3tpuEUCOKqOJdfGWWMveynQBQ/c29FpfLV/Uuo+uACVChnKSnxLT+6y9AZFxjeF1fx8lc28hv2sKK3xtD+0zgyS0N0UdpJ7sm2xHJZZurDalpogVoK8S+SKa7LmA
X-GND-State: clean
X-GND-Score: -100
X-Rspam-User: 
X-Rspamd-Server: rspam04
X-Rspamd-Queue-Id: 52B2F2000A
X-Stat-Signature: jxd19dspq7qymf9p4swbyri8oy7c45hc
X-HE-Tag: 1782469409-881215
X-HE-Meta: U2FsdGVkX1+p0Mye8S67cgQcoZ1tP0yqoO1V4rKmjckSBkkmTYYMmXJZcrSUWKoZ3Pr6Zh0K2jqXR5FZgOi1y9JMfLVHwndueBLkmH2UBbP2+F2NW4t3mhQB57ypdOcY68sRPQs9IhoY2Ly2j09b96hiCLUFIMhDZgw7Ed+zvKzAFkNlCMrwc2qrXJIV7qUWeuyEKjgJrt27hUHEmylmpn8knL0aOUpP/LWom/UVMP/ot2BaYwt1ESTdOu2NnFDdTwaZi7z+s7IGBigWdjFloRpAMsR/MyvwaBviSywkAnBWYicqw3KXv+8LxlD2jPCyOauUmQ+s55BNnl9Ad0iMi678xPXj0hkfoJjGjj56UimRYFrV2figEKT8t4/vLwM8FTjr3WRrKt/2j2WjiQinoNaiZ6ybTETaB/oTiqzC7MHk3YU6z14Nr3dCbm9G7xm6MHGjvvP3HwoNhxvqO5JPb0BGw3WcvK/2bHekou1IAKnD6htE/KmNsusPZO+/apkiJH3kbwSmTD+rGhEt9UfnsNfOT6sz/gUC+K9t6lwOKSagva8sPT9VcbSDwLCZhNmZuLqgKA1ihhYztf53xjaju7DDLMQfWWPBvPTGrHPHoTocZBxyYiiqRT2Hu4KpWLZGiWReL6lwW0NCqYx4xqIDT2iroK7nmRWwOi15gD5w2tZ2EhDGtXI0LgMYBmmxtec8bFVTplgidJw6/RzSwVSI7UD3aNlcdh8reV7HzJagV2kGEtwJ9hgu8hEE1rZdJd3hLln9+34HkmLxDR84V4Yf3TXdyjI//pUwQvrX+B88L5a43AlQGTqXvIsqQ/c6ELew66VHlnzzBV3LU2Tr+ExsNEhv10/tSp/FenBZssQS7vAcyzmKFQ33rbMaOn+bSj3fSm3Rxq9vLLY8FGZUA8TwCf2gwR7j3SDF8pvgDPkNfmgSdCGr1bXO2gSL8wtuM69oMI9CWHJEioJU3MSvrTa
 Jt9JGIB9
 +mPdgh9E571IkwSHPs6Psf0gJGXfGBWB5KOHaw9RKheUQ89oFiuk7zIsppQOFwDJ8dNawMR1lVcs7tAEiFCqsckmXfw8dUpSiaQnoyinhKgsnQeeX490QIBkuL5NJ1H6MUPVy
Sender: owner-linux-mm@kvack.org
Precedence: bulk
X-Loop: owner-majordomo@kvack.org
List-ID: <linux-mm.kvack.org>
List-Subscribe: <mailto:majordomo@kvack.org>
List-Unsubscribe: <mailto:majordomo@kvack.org>

Sorry for the noise, too many emails at once, I'll add some delay.

Sorry again,

Alex

On 6/26/26 12:09, Alexandre Ghiti wrote:
> This is version 2 of per-memcg-per-node kmem accounting.
>
> As asked by Joshua, I ran some microbenchmarks to check the impact of
> this fine grain accounting.
>
> TL;DR: There is a substantial impact (up to +337% on small percpu allocations)
> on a benchmark that loops over small percpu allocations. On the other hand,
> on a userspace program that creates a bpf percpu map, this cost is not visible.
>
> I followed Joshua's advice and now this version batches the memcg accounting:
> it improves the performance +337% vs +417% (v1) on 176 cores single node
> machine and +153% vs 206% (v1) on 80 cores 2 nodes machine.
>
> We can see that the overhead of this version scales linearly with the number of
> cpus (the number of nodes being small). This overhead comes mainly from
> vmalloc_to_page() so I have another variant (b) that decreases the impact even
> more (+131% vs +337% on 176 cores and +86% vs +153% on 80 cores) but I'm not
> sure the added complexity is needed so I did not send this version, let me know
> what you think.
>
> Performance
> ===========
>
> All benchmarks run in a memcg with __GFP_ACCOUNT.
>
> 1) BPF percpu map create/destroy, full series vs baseline kernel (two
>     boots, 176-CPU AMD EPYC, 1 NUMA node): the per-node accounting is lost
>     in the BPF syscall overhead, the delta is within noise (us/op):
>
>       size (B):    64     256    1024   4096   8192
>       delta:     -5.5%  -5.1%  -1.8%  -5.1%  -4.1%
>
> 2) In-kernel microbench that isolates the accounting cost: a tight
>     __alloc_percpu_gfp()/free_percpu() loop, __GFP_ACCOUNT on vs off on the
>     same boot (ACCT COST = on - off). The dominant cost on a many-CPU box
>     is discovering each backing page's real node (vmalloc_to_page() per
>     possible CPU). ACCT COST by value size:
>
>     176-CPU EPYC, 1 node
>       size (B):              64       256      1024     4096     8192
>        baseline (upstream)  +5.3%    +5.4%    +0.1%    -1.8%    -0.5%
>        v1 credit (per-page) +417.3%  +182.5%  +68.5%   +21.4%   +16.1%
>     a) per-node accounting  +337.8%  +141.8%  +36.1%   +11.9%   +6.8%
>     b) per-page nid cache   +131.3%  +53.7%   +10.5%   +0.9%    +2.0%
>     c) single-node fast     +12.6%   +12.1%   +3.5%    +6.6%    +0.7%
>
>     80-CPU Xeon Gold 6138, 2 nodes (fast path inactive)
>       size (B):              64       256      1024     4096     8192
>        baseline (upstream)  +1.2%    -3.8%    +12.4%   +1.2%    +0.5%   (noise)
>        v1 credit (per-page) +206.1%  +134.0%  +44.5%   +11.6%   +11.5%
>     a) per-node accounting  +153.2%  +64.7%   +19.4%   +4.2%    +5.9%
>     b) per-page nid cache   +86.5%   +45.5%   +14.7%   +1.8%    +1.6%
>
>     (a) this patchset without fast path for single node
>     (b) is an alternative version, not in this series, that caches each backing
>         page's node in the chunk so the walk is paid once per page instead of
>         once per allocation
>     (c) this patchset with fast path for single node
>
> Changes in v2
> =============
>
> - objcg lifetime: Shakeel's patch 1 now guarantees the lifetime of every
>    per-node objcg
> - dropped patch 5 and 6 since Shakeel's patch 2 replaces them
> - fixed the number of precharged pages (the v1 formula under-precharged)
> - per-node batching (Joshua's suggestion): accumulate the per-node bytes
>    first, then issue one account_kmem()/uncharge() per touched node =>
>    O(nodes) memcg ops instead of O(num_possible_cpus)
> - single-node fast path: skip the per-cpu node walk on single node machines
> - obj_exts metadata is now accounted per-node (walk its vmalloc pages)
>    rather than charged whole to one memcg (Shakeel's main v1 objection).
> - renamed obj_cgroup_get_nid() -> obj_cgroup_nid() (returns a borrowed RCU
>    pointer, no ref taken).
> - zswap: fixed the missing locking around the per-node objcg lookup (now
>    done under RCU + obj_cgroup_tryget()).
>
> This series pursues the work initiated by Joshua [1]. We need kernel
> memory to be accounted on a per-node basis in order to be able to know
> the memcg <-> physical memory association.
>
> This series takes advantage of the recently introduced per-node
> obj_cgroup and makes those obj_cgroup tied to their NUMA node.
>
> The bulk of the series is percpu per-node accounting: percpu
> "precharges" the memcg before we know the actual location of the pages
> it uses, so charging and accounting had to be split. All other kmem
> users (slab, __memcg_kmem_charge_page) are now handled directly by
> Shakeel's per-node obj_cgroup infrastructure this series sits on, so
> only percpu and zswap need explicit per-node work here (zswap support
> is limited because Joshua is working on it in parallel [3]).
>
> Thanks Joshua and Shakeel for the early feedback!
>
> [1] https://lore.kernel.org/linux-mm/20260404033844.1892595-1-joshua.hahnjy@gmail.com/
> [2] https://lore.kernel.org/linux-mm/56c04b1c5d54f75ccdc12896df6c1ca35403ecc3.1772711148.git.zhengqi.arch@bytedance.com/
> [3] https://lore.kernel.org/linux-mm/20260311195153.4013476-1-joshua.hahnjy@gmail.com/
>
> Functional Testing
> ==================
>
> - Tested with a percpu kmem self-test in an 8-node VM (2 nodes with CPUs,
>    6 memory-only). For each allocation it checks that every node is charged
>    and later uncharged the same number of bytes -- including a CPU-less node
>    that ends up holding the obj_exts metadata -- and that nothing is left
>    charged after teardown. All checks pass. (The self-test module is not
>    part of this series.)
>
> Alexandre Ghiti (7):
>    mm: percpu: fix obj_exts metadata charge size
>    mm: percpu: Split memcg charging and kmem accounting
>    mm: memcontrol: track MEMCG_KMEM per NUMA node
>    mm: percpu: per-node kmem accounting
>    mm: percpu: per-node kmem accounting for obj_exts metadata
>    mm: percpu: skip the per-cpu node walk on single-node systems
>    mm: zswap: per-node kmem accounting for zswap/zsmalloc
>
> Shakeel Butt (2):
>    memcg: convert task->objcg to a per-node objcgs array
>    memcg: charge kmem pages and slab objects against per-node objcg
>
>   include/linux/memcontrol.h |  23 ++-
>   include/linux/mmzone.h     |   1 +
>   include/linux/sched.h      |   7 +-
>   include/linux/zsmalloc.h   |   2 +
>   mm/memcontrol.c            | 286 ++++++++++++++++++++++++++-----------
>   mm/percpu-internal.h       |   2 +-
>   mm/percpu.c                | 108 +++++++++++++-
>   mm/vmstat.c                |   1 +
>   mm/zsmalloc.c              |  11 ++
>   mm/zswap.c                 |  19 ++-
>   10 files changed, 361 insertions(+), 99 deletions(-)
>

