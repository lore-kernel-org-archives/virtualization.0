Received: from out-170.mta1.migadu.com (out-170.mta1.migadu.com [95.215.58.170])
	(using TLSv1.2 with cipher ECDHE-RSA-AES256-GCM-SHA384 (256/256 bits))
	(No client certificate requested)
	by smtp.subspace.kernel.org (Postfix) with ESMTPS id 4FD3342A82
	for <virtualization@lists.linux.dev>; Thu,  5 Feb 2026 15:01:50 +0000 (UTC)
Authentication-Results: smtp.subspace.kernel.org; arc=none smtp.client-ip=95.215.58.170
ARC-Seal:i=1; a=rsa-sha256; d=subspace.kernel.org; s=arc-20240116;
	t=1770303711; cv=none; b=NEtUQ0bLvZJhM2od8vafYD5hV+G4gN+LuG7RlO0iQ4I1AVan5kf2wawFCvVODkkzFECe9j7dxyis9w9qlo0r+fCf26mfQjj8O8G7aAbdQh3ZoRAR4/Wj7U74bN9ag9umo5Rqsn90qalefM8yAUZcPjvQU2eNl7eQFcANU0EIRZY=
ARC-Message-Signature:i=1; a=rsa-sha256; d=subspace.kernel.org;
	s=arc-20240116; t=1770303711; c=relaxed/simple;
	bh=z7DlHGRAWqmVCDGHT8bYe/0iOwwIf+tGe2De5QVYgmk=;
	h=Message-ID:Date:MIME-Version:Subject:To:Cc:References:From:
	 In-Reply-To:Content-Type; b=cqa94PYNBHnAp5Hbd/w+4Egkh9FeJRjxK8EjbuL+5TFvvkC2rWLoLz5DwUVXFsm7xSJ/+dDK86vouAkX+99yXB9dwzCJonB9C1+FKmNolhhvhWy7vdavXsnvwTvMwie2UlcLx3mFQQuiVaBS1z0HbLvI+t60a2dZ6f60DyT/L4o=
ARC-Authentication-Results:i=1; smtp.subspace.kernel.org; dmarc=pass (p=none dis=none) header.from=linux.dev; spf=pass smtp.mailfrom=linux.dev; dkim=pass (1024-bit key) header.d=linux.dev header.i=@linux.dev header.b=R1OGaVme; arc=none smtp.client-ip=95.215.58.170
Authentication-Results: smtp.subspace.kernel.org; dmarc=pass (p=none dis=none) header.from=linux.dev
Authentication-Results: smtp.subspace.kernel.org; spf=pass smtp.mailfrom=linux.dev
Authentication-Results: smtp.subspace.kernel.org;
	dkim=pass (1024-bit key) header.d=linux.dev header.i=@linux.dev header.b="R1OGaVme"
Message-ID: <3026ad8d-92ad-4683-8c3e-733d4070d033@linux.dev>
DKIM-Signature: v=1; a=rsa-sha256; c=relaxed/relaxed; d=linux.dev; s=key1;
	t=1770303707;
	h=from:from:reply-to:subject:subject:date:date:message-id:message-id:
	 to:to:cc:cc:mime-version:mime-version:content-type:content-type:
	 content-transfer-encoding:content-transfer-encoding:
	 in-reply-to:in-reply-to:references:references;
	bh=oeEv7fnd0NPkK8yO5EsGkSZ8yT0L8dwlwYeRPZ0uSkk=;
	b=R1OGaVmeCDAWYZLObcFuiWzoPWWNt28v4igYWupPC//Zz1G0EDHuFGPWKTGAtHEUZLW2Fy
	3v4fmgvc2ba3Usxdf4CZjRo+kqepU2FyfthjVzh8xwyIbi026D1Signk4cST/7CbkfmxUI
	4G4+Ec/ufy2updDebH445fX0FG0OzlE=
Date: Thu, 5 Feb 2026 23:01:11 +0800
Precedence: bulk
X-Mailing-List: virtualization@lists.linux.dev
List-Id: <virtualization.lists.linux.dev>
List-Subscribe: <mailto:virtualization+subscribe@lists.linux.dev>
List-Unsubscribe: <mailto:virtualization+unsubscribe@lists.linux.dev>
MIME-Version: 1.0
Subject: Re: [PATCH v4 0/3] targeted TLB sync IPIs for lockless page table
Content-Language: en-US
To: "David Hildenbrand (Arm)" <david@kernel.org>,
 Peter Zijlstra <peterz@infradead.org>, dave.hansen@intel.com
Cc: Liam.Howlett@oracle.com, akpm@linux-foundation.org,
 aneesh.kumar@kernel.org, arnd@arndb.de, baohua@kernel.org,
 baolin.wang@linux.alibaba.com, boris.ostrovsky@oracle.com, bp@alien8.de,
 dave.hansen@linux.intel.com, dev.jain@arm.com, hpa@zytor.com,
 hughd@google.com, ioworker0@gmail.com, jannh@google.com, jgross@suse.com,
 kvm@vger.kernel.org, linux-arch@vger.kernel.org,
 linux-kernel@vger.kernel.org, linux-mm@kvack.org,
 lorenzo.stoakes@oracle.com, mingo@redhat.com, npache@redhat.com,
 npiggin@gmail.com, pbonzini@redhat.com, riel@surriel.com,
 ryan.roberts@arm.com, seanjc@google.com, shy828301@gmail.com,
 tglx@linutronix.de, virtualization@lists.linux.dev, will@kernel.org,
 x86@kernel.org, ypodemsk@redhat.com, ziy@nvidia.com
References: <20260202095414.GE2995752@noisy.programming.kicks-ass.net>
 <20260202110329.74397-1-lance.yang@linux.dev>
 <20260202125030.GB1395266@noisy.programming.kicks-ass.net>
 <c6fda7c2-ad54-416a-a869-1499c97c7bd7@linux.dev>
 <4700e7ba-8456-4a93-9e28-7e5a3ca2a1be@linux.dev>
 <20260202133713.GF1395266@noisy.programming.kicks-ass.net>
 <540adec9-c483-460a-a682-f2076cf015c2@linux.dev>
 <20260202150957.GD1282955@noisy.programming.kicks-ass.net>
 <d6944cd8-d3b7-4b16-ab52-a61e7dc2221c@linux.dev>
 <06d48a52-e4ec-47cd-b3fb-0fccd4dc49f4@kernel.org>
X-Report-Abuse: Please report any abuse attempt to abuse@migadu.com and include these headers.
From: Lance Yang <lance.yang@linux.dev>
In-Reply-To: <06d48a52-e4ec-47cd-b3fb-0fccd4dc49f4@kernel.org>
Content-Type: text/plain; charset=UTF-8; format=flowed
Content-Transfer-Encoding: 8bit
X-Migadu-Flow: FLOW_OUT



On 2026/2/5 21:25, David Hildenbrand (Arm) wrote:
> On 2/2/26 16:52, Lance Yang wrote:
>>
>>
>> On 2026/2/2 23:09, Peter Zijlstra wrote:
>>> On Mon, Feb 02, 2026 at 10:37:39PM +0800, Lance Yang wrote:
>>>>
>>>>
>>>>
>>>> PT_RECLAIM=y does have IPI for unshare/collapse — those paths call
>>>> tlb_flush_unshared_tables() (for hugetlb unshare) and 
>>>> collapse_huge_page()
>>>> (in khugepaged collapse), which already send IPIs today (broadcast 
>>>> to all
>>>> CPUs via tlb_remove_table_sync_one()).
>>>>
>>>> What PT_RECLAIM=y doesn't need IPI for is table freeing (
>>>> __tlb_remove_table_one() uses call_rcu() instead). But table 
>>>> modification
>>>> (unshare, collapse) still needs IPI to synchronize with lockless 
>>>> walkers,
>>>> regardless of PT_RECLAIM.
>>>>
>>>> So PT_RECLAIM=y is not broken; it already has IPI where needed. This 
>>>> series
>>>> just makes those IPIs targeted instead of broadcast. Does that clarify?
>>>
>>> Oh bah, reading is hard. I had missed they had more table_sync_one() 
>>> calls,
>>> rather than remove_table_one().
>>>
>>> So you *can* replace table_sync_one() with rcu_sync(), that will provide
>>> the same guarantees. Its just a 'little' bit slower on the update side,
>>> but does not incur the read side cost.
>>
>> Yep, we could replace the IPI with synchronize_rcu() on the sync side:
>>
>> - Currently: TLB flush → send IPI → wait for walkers to finish
>> - With synchronize_rcu(): TLB flush → synchronize_rcu() -> waits for 
>> grace period
>>
>> Lockless walkers (e.g. GUP-fast) use local_irq_disable(); 
>> synchronize_rcu() also
>> waits for regions with preemption/interrupts disabled, so it should 
>> work, IIUC.
>>
>> And then, the trade-off would be:
>> - Read side: zero cost (no per-CPU tracking)
>> - Write side: wait for RCU grace period (potentially slower)
>>
>> For collapse/unshare, that write-side latency might be acceptable :)
>>
>> @David, what do you think?
> 
> Given that we just fixed the write-side latency from breaking Oracle's 
> databases completely, we have to be a bit careful here :)

Yep, agreed.

> 
> The thing is: on many x86 configs we don't need *any* TLB flushed or RCU 
> syncs.

Right. Looks like that is low-hanging fruit. I'll send that out 
separately :)

> 
> So "how much slower" are we talking about, especially on bigger/loaded 
> systems?

Unfortunately the numbers are pretry bad. On an x86-64 64-core system
under high load, each synchronize_rcu() is about *22.9* ms on average ...

So for now, neither approach looks good: tracking on the read side adss
cost to GUP-fast, and syncing on the write side e.g. synchronize_rcu()
is too slow on large systems.
