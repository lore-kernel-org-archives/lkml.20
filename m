Received: from mail-wm1-f49.google.com (mail-wm1-f49.google.com [209.85.128.49])
	(using TLSv1.2 with cipher ECDHE-RSA-AES128-GCM-SHA256 (128/128 bits))
	(No client certificate requested)
	by smtp.subspace.kernel.org (Postfix) with ESMTPS id 4A7314A0F0F
	for <linux-kernel@vger.kernel.org>; Fri, 11 Sep 2026 21:11:24 +0000 (UTC)
Authentication-Results: smtp.subspace.kernel.org; arc=none smtp.client-ip=209.85.128.49
ARC-Seal:i=1; a=rsa-sha256; d=subspace.kernel.org; s=arc-20240116;
	t=1789161086; cv=none; b=LkHmwq4kNcJC+opTEBR3RJquRS+ISoMrKaK8677HzsL987auTwX41hwTUoz8l5hc25DV7xHaVq1G0GLoOee3Z3QmhHNkHQtNUZfuMUxiykD/0zFMR1iQ0r2JxfEQikIRBBT95Aq4hXLVoJE3u3E3PMhia9T2uzqv2boJkFkQlnE=
ARC-Message-Signature:i=1; a=rsa-sha256; d=subspace.kernel.org;
	s=arc-20240116; t=1789161086; c=relaxed/simple;
	bh=tvyId/Etw8jxlO7xx1e/dl76CoqsDxgvKUYOrScQUTk=;
	h=Message-ID:Date:MIME-Version:Subject:To:Cc:References:From:
	 In-Reply-To:Content-Type; b=SoyVmsghAuKcw58kmGuE6ixrmSZp8Kz8AQno9g5FvId30qwm6Nxao2wcr61O4MU+AgM2NcemU7MC84/pAzrIylIIh4HW9lfDCVyj6ON6O433dxYSrXxwaiSmXWY9ji2WBcMNxt/oQ76cFLIP2wrhg4f2Xigryvpuef7Nr8YVOzg=
ARC-Authentication-Results:i=1; smtp.subspace.kernel.org; dmarc=none (p=none dis=none) header.from=grimberg.me; spf=pass smtp.mailfrom=gmail.com; arc=none smtp.client-ip=209.85.128.49
Authentication-Results: smtp.subspace.kernel.org; dmarc=none (p=none dis=none) header.from=grimberg.me
Authentication-Results: smtp.subspace.kernel.org; spf=pass smtp.mailfrom=gmail.com
Received: by mail-wm1-f49.google.com with SMTP id 5b1f17b1804b1-49a97714f5dso12333505e9.0
        for <linux-kernel@vger.kernel.org>; Fri, 11 Sep 2026 14:11:24 -0700 (PDT)
X-Google-DKIM-Signature: v=1; a=rsa-sha256; c=relaxed/relaxed;
        d=1e100.net; s=20251104; t=1789161082; x=1789765882;
        h=content-transfer-encoding:content-type:in-reply-to:from
         :content-language:references:cc:to:subject:user-agent:mime-version
         :date:message-id:x-gm-gg:x-gm-message-state:from:to:cc:subject:date
         :message-id:reply-to:content-type;
        bh=k2p8FtP3AGlh3ut8VRC50Ab+KYAxGDJIcjJQgH3hmPc=;
        b=mN/tRQ9+ik1LAYUqgooPgRqh+B/4Hon8bPytVurodpqT1lGVFOFdSy7Drg2jKJ9tDH
         1WXStDs9IWkehOMw0sl6n7dZuah0gmeYljE7TobizG5VUVhL+B++RC4Ibf2OvquEUs2Z
         zyKGZKxqVPe8l98ph6+UGqIcfvY1zLIDUX4yNX5pLN3vjSNjMtaAAwZd0yO6s6KyaCuZ
         KepCREFFXR5vOBuvd3Z9+I/9M4oXkvopUrwsOIVMuOzXL4JLuXYfQwY2GhpOTNzM4zno
         V4Df41kHRH7W/6pPGQ06L+/LiGshp6qZOj6ywQ7vJpqj57ejwWWmDW8QUgr8ZNnXBHFa
         dzsw==
X-Forwarded-Encrypted: i=1; AKwUvBzypuF/wmc6pZfHPobR4YC+tOXVfljFKHPbqEAokcjOQCZBuFds9Enmo2hB8FP2pg/RH9dFUTFa2BEb0Og=@vger.kernel.org
X-Gm-Message-State: AFuF++mSLNkcTyyAW0jZ9imrFCHbTJRFGdg6Fg6jdVvZy6zccpixMQXW
	re8+iQDJJokJc9iD7P9YxSjBadqn/Acbe/xImqWR+DMAuUiQQok51Qvi
X-Gm-Gg: AYBFou02/xzu7BQ53l1oSc+apcw2PjPpGKT8poa+349NzqDdkQ47NjhzPQwSuhcU3Fo
	/ET1/WOuzCroHNzMhcpRqvQAB5c0iS8MIGIxnnQY9ROTbL+4ZgIbcZB4/e7x9rT50F4NU7tfLvc
	jV7nZDDstoTqIVwGQ0bazY7YIEZshkWZfvGhlBvVgIusFgXLfgiyFDQYfGh6req3rhFm6re/icf
	FjMu000uZqoQMdaSsSTYFsrc3XLN8b/f/9ownDGHnbYh83qoDI7fGUAz/VVS9Qph3Pcd1CoQDGL
	kyqoGXdAJ7Ul07c3gPZOHBgjh78uwqzuc6v0NgBjEhZsczhBjUPaFR3i0iDSI21/yiWPg5unqwf
	ZQypuoERFT7+HBHD7mt2BvUrU473NZ3MVPnRQECLKo8v11lDwTL+qlorAG4GNyQ3U1x3arECDaD
	CZIK0ubxScuCbjUbdIfo/6GdlwXu7FFY7/veRvcX2C/qSqOmHdjOcFRfHv6cbC/CWImNa0Qk5SQ
	AJM7326X3IDbCXuUvwjFdPGqIzCtNZq
X-Received: by 2002:a05:600c:1c11:b0:49c:f504:2af5 with SMTP id 5b1f17b1804b1-49e61887fe2mr85200775e9.1.1789161082182;
        Fri, 11 Sep 2026 14:11:22 -0700 (PDT)
Received: from [10.100.102.74] (89-138-77-243.bb.netvision.net.il. [89.138.77.243])
        by smtp.gmail.com with ESMTPSA id 5b1f17b1804b1-49e60ababd5sm139607975e9.4.2026.09.11.14.11.19
        (version=TLS1_3 cipher=TLS_AES_128_GCM_SHA256 bits=128/128);
        Fri, 11 Sep 2026 14:11:20 -0700 (PDT)
Message-ID: <13c160d0-0657-47ce-9a16-58d348267ab0@grimberg.me>
Date: Sat, 12 Sep 2026 00:11:18 +0300
Precedence: bulk
X-Mailing-List: linux-kernel@vger.kernel.org
List-Id: <linux-kernel.vger.kernel.org>
List-Subscribe: <mailto:linux-kernel+subscribe@vger.kernel.org>
List-Unsubscribe: <mailto:linux-kernel+unsubscribe@vger.kernel.org>
MIME-Version: 1.0
User-Agent: Mozilla Thunderbird
Subject: Re: [PATCH v3] nvme-tcp: allow setting per-queue io_cpu through sysfs
To: Saravanan D <saravanand@crusoe.ai>, linux-nvme@lists.infradead.org
Cc: kbusch@kernel.org, hch@lst.de, axboe@kernel.dk, nilay@linux.ibm.com,
 dwagner@suse.de, linux-kernel@vger.kernel.org, iyamahata@crusoe.ai,
 kiyer@crusoe.ai, ganbalagane@crusoe.ai, sj@kernel.org
References: <20260909211432.6741-1-saravanand@crusoe.ai>
Content-Language: en-US
From: Sagi Grimberg <sagi@grimberg.me>
In-Reply-To: <20260909211432.6741-1-saravanand@crusoe.ai>
Content-Type: text/plain; charset=UTF-8; format=flowed
Content-Transfer-Encoding: 8bit



On 10/09/2026 0:14, Saravanan D wrote:
> nvme_tcp_set_queue_io_cpu() picks each queue's io_cpu at connect time
> as the least loaded CPU in the queue's blk-mq map group, and all socket
> work runs there for the connection's lifetime. This decision falls
> short when the host partitions its CPUs after connect time. On a 384
> cpu multi tenant host with 128 queue controllers, blk-mq folds three
> CPUs into every map group, some groups straddle two tenants' cpusets,
> and 9% of nvme_tcp_io_work executions ran outside the submitting VM's
> cpuset, seen by the neighbor as steal time.
>
> Expose each I/O queue's io_cpu as a writable sysfs attribute
>
>    /sys/class/nvme/nvmeX/tcp_queues/<qid>/io_cpu
>
> so a control plane that owns CPU placement can set it directly instead
> of relying on the driver's heuristic. A written value persists across
> reconnects, marked by NVME_TCP_Q_IO_CPU_USER. Writing -1 clears the
> mark and re-runs the connect time selection. Reading returns the CPU,
> or -1 when the queue is unbound.

No need for NVME_TCP_Q_IO_CPU_USER flag and restoring to the original 
connect time selection. -1 would mean WORK_CPU_UNBOUND. In fact lets 
allow this file to access "unbound" string (same as -1). I don't think 
we need to restore the connect time selection, the user who touches 
these settings is obviously interested to be in control.
>
> The store, the connect time selection and queue stop serialize their
> accounting of nvme_tcp_cpu_queues under the queue lock.

I think that the queue accounting is something we'd do anyways, 
regardless of how the
queue is set. It just represents the io_cpu spread across cpu cores.

>
> Suggested-by: Sagi Grimberg <sagi@grimberg.me>
> Link: https://lore.kernel.org/linux-nvme/220e9da3-f756-4a16-8de1-d4b171f15009@grimberg.me/
> Assisted-by: Claude:claude-opus-4-8 [Claude Code]
> Signed-off-by: Saravanan D <saravanand@crusoe.ai>
> ---
> Changes since v2 [1]:
> - Replaced the io_cpu_adopt connect option and the submitter adoption
>    heuristic with a per queue writable sysfs attribute, following Sagi's
>    suggestion [2]. The control plane now sets each queue's io_cpu
>    directly, the assignment is kept across reconnects and writing -1
>    reverts to the connect time selection.
> - Retitled from "nvme-tcp: pin io_cpu to submitter cpu".
>
> The per queue directories follow the blk-mq mq/<hctx> sysfs pattern.
>
> Tested on a 2 socket 384 cpu host with 128 queue controllers. Writing
> a cpu number changed the queue's io_cpu to it. Writing an invalid
> value was rejected. Writing -1 re-ran the connect time selection.
> Pinned queues kept their io_cpu across a controller reset while
> unpinned queues received a fresh pick.
>
> The multiple queues per hctx RFC [3] found the same need to steer the
> socket work cpu, so this attribute may gain a second user.
>
> [1] https://lore.kernel.org/linux-nvme/20260820083634.71689-1-saravanand@crusoe.ai/
> [2] https://lore.kernel.org/linux-nvme/1d56144d-6987-40c1-ac02-b15333db121e@grimberg.me/
> [3] https://lore.kernel.org/linux-nvme/20260903152623.614951-1-kbusch@meta.com/
>
>   Documentation/ABI/stable/sysfs-nvme |  12 +++
>   drivers/nvme/host/tcp.c             | 153 +++++++++++++++++++++++++++-
>   2 files changed, 162 insertions(+), 3 deletions(-)
>
> diff --git a/Documentation/ABI/stable/sysfs-nvme b/Documentation/ABI/stable/sysfs-nvme
> index a2f5d0710db4..2bbb5a0b7c2e 100644
> --- a/Documentation/ABI/stable/sysfs-nvme
> +++ b/Documentation/ABI/stable/sysfs-nvme
> @@ -451,3 +451,15 @@ Contact:	Hannes Reinecke <hare@suse.de>
>   Description:
>   		Shows the subsystem type. Possible values: "discovery",
>   		"nvm", "reserved".
> +
> +What:		/sys/class/nvme/nvmeX/tcp_queues/<qid>/io_cpu
> +Date:		September 2026
> +KernelVersion:	7.4
> +Contact:	Saravanan D <saravanand@crusoe.ai>
> +Description:
> +		(RW) The CPU that runs the socket work for I/O queue <qid>
> +		of an NVMe over TCP controller, selected by the driver at
> +		connect time. Writing a CPU number overrides the selection
> +		and persists across reconnects. Writing -1 reverts to the
> +		driver's selection. Reads show the current CPU, or -1 when
> +		the queue is unbound.
> diff --git a/drivers/nvme/host/tcp.c b/drivers/nvme/host/tcp.c
> index 921934028e0b..22ad1fdf4a12 100644
> --- a/drivers/nvme/host/tcp.c
> +++ b/drivers/nvme/host/tcp.c
> @@ -93,6 +93,7 @@ enum nvme_tcp_queue_flags {
>   	NVME_TCP_Q_LIVE		= 1,
>   	NVME_TCP_Q_POLLING	= 2,
>   	NVME_TCP_Q_IO_CPU_SET	= 3,
> +	NVME_TCP_Q_IO_CPU_USER	= 4,
>   };
>   
>   enum nvme_tcp_recv_state {
> @@ -102,6 +103,17 @@ enum nvme_tcp_recv_state {
>   };
>   
>   struct nvme_tcp_ctrl;
> +struct nvme_tcp_queue;
> +
> +/*
> + * Allocated per registration and freed by its kobject release, so a
> + * reconnect never reuses a kobject whose release is still pending.
> + */
> +struct nvme_tcp_queue_kobj {
> +	struct kobject		kobj;
> +	struct nvme_tcp_queue	*queue;
> +};

I am wandering if it is time to introduce the core nvme queue:
struct nvme_queue {
         struct kobject        kobj;
         unsigned int          qid;
         u64                          flags;
};

And have the transport queue embed it:
struct nvme_tcp_queue {
         struct nvme_queue        nvmeq;
         ....
};

I suspect it will allow for better abstractions.

Thoughts? Keith, Christoph?
