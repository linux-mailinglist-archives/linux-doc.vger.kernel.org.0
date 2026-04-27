Return-Path: <linux-doc+bounces-84736-lists+linux-doc=lfdr.de@vger.kernel.org>
Delivered-To: lists+linux-doc@lfdr.de
Received: from mail.lfdr.de
	by lfdr with LMTP
	id gDM5Ha1Y72n5AQEAu9opvQ
	(envelope-from <linux-doc+bounces-84736-lists+linux-doc=lfdr.de@vger.kernel.org>)
	for <lists+linux-doc@lfdr.de>; Mon, 27 Apr 2026 14:38:05 +0200
X-Original-To: lists+linux-doc@lfdr.de
Received: from sea.lore.kernel.org (sea.lore.kernel.org [172.234.253.10])
	by mail.lfdr.de (Postfix) with ESMTPS id 8561D47298A
	for <lists+linux-doc@lfdr.de>; Mon, 27 Apr 2026 14:38:04 +0200 (CEST)
Received: from smtp.subspace.kernel.org (conduit.subspace.kernel.org [100.90.174.1])
	by sea.lore.kernel.org (Postfix) with ESMTP id D38423051D2A
	for <lists+linux-doc@lfdr.de>; Mon, 27 Apr 2026 12:34:00 +0000 (UTC)
Received: from localhost.localdomain (localhost.localdomain [127.0.0.1])
	by smtp.subspace.kernel.org (Postfix) with ESMTP id A807B3B5821;
	Mon, 27 Apr 2026 12:34:00 +0000 (UTC)
Authentication-Results: smtp.subspace.kernel.org;
	dkim=pass (1024-bit key) header.d=linux.dev header.i=@linux.dev header.b="q1uWzxPq"
X-Original-To: linux-doc@vger.kernel.org
Received: from out-178.mta1.migadu.com (out-178.mta1.migadu.com [95.215.58.178])
	(using TLSv1.2 with cipher ECDHE-RSA-AES256-GCM-SHA384 (256/256 bits))
	(No client certificate requested)
	by smtp.subspace.kernel.org (Postfix) with ESMTPS id DC5E83B8BD5
	for <linux-doc@vger.kernel.org>; Mon, 27 Apr 2026 12:33:58 +0000 (UTC)
Authentication-Results: smtp.subspace.kernel.org; arc=none smtp.client-ip=95.215.58.178
ARC-Seal:i=1; a=rsa-sha256; d=subspace.kernel.org; s=arc-20240116;
	t=1777293240; cv=none; b=ghYAK1DtQMhjF1QZ0McwE2obppQ5R7K76b9wtl2V3lRygRCUAd1IMC8Ny5OTR8F+iRfuwWswbMTJO+n1TJcN7bjnV8nJcyePRhbmnXxJ53TBojFFHM1f9C+JQ5huRQ3zFW9EZ345/Zeqn0PlkXgYHl7RNhF6T0+Nh/yQXUFj6Vw=
ARC-Message-Signature:i=1; a=rsa-sha256; d=subspace.kernel.org;
	s=arc-20240116; t=1777293240; c=relaxed/simple;
	bh=iE6r7hVylhito6gtb2Vir/8ve7gmL/U6+hUPxE9ZWd4=;
	h=From:To:Cc:Subject:Date:Message-Id:In-Reply-To:References:
	 MIME-Version:Content-Type; b=JM4nybW0ULbxJ/rRBvKhPcSxYND2zt2C4s/qEmDOvnL2mAl2hgfjRVCe9o8w2ZvezaszRxifVedSsMhTqWnlv6S1eI8lrjJgcLih3nJk3ywGHjoig6n7Q5/cKkwy5PGfpqaZwYoMWBCdbukQOBhzZl5PKMpfSN5LstFFaDmLy3Y=
ARC-Authentication-Results:i=1; smtp.subspace.kernel.org; dmarc=pass (p=none dis=none) header.from=linux.dev; spf=pass smtp.mailfrom=linux.dev; dkim=pass (1024-bit key) header.d=linux.dev header.i=@linux.dev header.b=q1uWzxPq; arc=none smtp.client-ip=95.215.58.178
Authentication-Results: smtp.subspace.kernel.org; dmarc=pass (p=none dis=none) header.from=linux.dev
Authentication-Results: smtp.subspace.kernel.org; spf=pass smtp.mailfrom=linux.dev
X-Report-Abuse: Please report any abuse attempt to abuse@migadu.com and include these headers.
DKIM-Signature: v=1; a=rsa-sha256; c=relaxed/relaxed; d=linux.dev; s=key1;
	t=1777293225;
	h=from:from:reply-to:subject:subject:date:date:message-id:message-id:
	 to:to:cc:cc:mime-version:mime-version:content-type:content-type:
	 content-transfer-encoding:content-transfer-encoding:
	 in-reply-to:in-reply-to:references:references;
	bh=le6hydx/0AV9ez00tRp6YUb5tjV/ytJlHiXxDmzs5Fw=;
	b=q1uWzxPqZjeOSed5zBa2SVBta4POQ6DRm/xYANV+EBMy77g8C/H+CzzJafOcG8lynu166S
	nXOHZ+9j6PscxlvuS3RqwUkBiSg+g6O3acv5kW02iALlOujnhGt7QECEOGiXFVsD8NGbvb
	vlQyW3Mz0hVavf/L7W6oqgebqmdtJx8=
From: Lance Yang <lance.yang@linux.dev>
To: leitao@debian.org
Cc: linmiaohe@huawei.com,
	nao.horiguchi@gmail.com,
	akpm@linux-foundation.org,
	corbet@lwn.net,
	skhan@linuxfoundation.org,
	david@kernel.org,
	ljs@kernel.org,
	Liam.Howlett@oracle.com,
	vbabka@kernel.org,
	rppt@kernel.org,
	surenb@google.com,
	mhocko@suse.com,
	shuah@kernel.org,
	linux-mm@kvack.org,
	linux-kernel@vger.kernel.org,
	linux-doc@vger.kernel.org,
	linux-kselftest@vger.kernel.org,
	kernel-team@meta.com,
	Lance Yang <lance.yang@linux.dev>
Subject: Re: [PATCH v5 1/4] mm/memory-failure: report MF_MSG_KERNEL for reserved pages
Date: Mon, 27 Apr 2026 20:33:30 +0800
Message-Id: <20260427123330.92847-1-lance.yang@linux.dev>
In-Reply-To: <20260424-ecc_panic-v5-1-a35f4b50425c@debian.org>
References: <20260424-ecc_panic-v5-1-a35f4b50425c@debian.org>
Precedence: bulk
X-Mailing-List: linux-doc@vger.kernel.org
List-Id: <linux-doc.vger.kernel.org>
List-Subscribe: <mailto:linux-doc+subscribe@vger.kernel.org>
List-Unsubscribe: <mailto:linux-doc+unsubscribe@vger.kernel.org>
MIME-Version: 1.0
Content-Type: text/plain; charset=UTF-8
Content-Transfer-Encoding: 8bit
X-Migadu-Flow: FLOW_OUT
X-Rspamd-Queue-Id: 8561D47298A
X-Rspamd-Action: no action
X-Rspamd-Server: lfdr
X-Spamd-Result: default: False [0.34 / 15.00];
	SUSPICIOUS_RECIPS(1.50)[];
	MID_CONTAINS_FROM(1.00)[];
	ARC_ALLOW(-1.00)[subspace.kernel.org:s=arc-20240116:i=1];
	DMARC_POLICY_ALLOW(-0.50)[linux.dev,none];
	R_SPF_ALLOW(-0.20)[+ip4:172.234.253.10:c];
	R_DKIM_ALLOW(-0.20)[linux.dev:s=key1];
	MAILLIST(-0.15)[generic];
	MIME_GOOD(-0.10)[text/plain];
	HAS_LIST_UNSUB(-0.01)[];
	RCVD_TLS_LAST(0.00)[];
	TAGGED_FROM(0.00)[bounces-84736-lists,linux-doc=lfdr.de];
	FROM_HAS_DN(0.00)[];
	FORGED_SENDER_MAILLIST(0.00)[];
	RCVD_COUNT_THREE(0.00)[3];
	RCPT_COUNT_TWELVE(0.00)[20];
	MIME_TRACE(0.00)[0:+];
	FREEMAIL_CC(0.00)[huawei.com,gmail.com,linux-foundation.org,lwn.net,linuxfoundation.org,kernel.org,oracle.com,google.com,suse.com,kvack.org,vger.kernel.org,meta.com,linux.dev];
	DKIM_TRACE(0.00)[linux.dev:+];
	FORGED_RECIPIENTS_MAILLIST(0.00)[];
	PRECEDENCE_BULK(0.00)[];
	FROM_NEQ_ENVFROM(0.00)[lance.yang@linux.dev,linux-doc@vger.kernel.org];
	TO_DN_SOME(0.00)[];
	NEURAL_HAM(-0.00)[-1.000];
	ASN(0.00)[asn:63949, ipnet:172.234.224.0/19, country:SG];
	TAGGED_RCPT(0.00)[linux-doc];
	MISSING_XM_UA(0.00)[];
	DBL_BLOCKED_OPENRESOLVER(0.00)[sea.lore.kernel.org:helo,sea.lore.kernel.org:rdns,huawei.com:email,linux.dev:email,linux.dev:dkim,linux.dev:mid]


On Fri, Apr 24, 2026 at 05:23:59AM -0700, Breno Leitao wrote:
>When get_hwpoison_page() returns a negative value, distinguish
>reserved pages from other failure cases by reporting MF_MSG_KERNEL
>instead of MF_MSG_GET_HWPOISON. Reserved pages belong to the kernel
>and should be classified accordingly for proper handling.
>
>Acked-by: Miaohe Lin <linmiaohe@huawei.com>
>Signed-off-by: Breno Leitao <leitao@debian.org>
>---
> mm/memory-failure.c | 11 ++++++++++-
> 1 file changed, 10 insertions(+), 1 deletion(-)
>
>diff --git a/mm/memory-failure.c b/mm/memory-failure.c
>index ee42d43613097..7b67e43dafbd1 100644
>--- a/mm/memory-failure.c
>+++ b/mm/memory-failure.c
>@@ -2432,7 +2432,16 @@ int memory_failure(unsigned long pfn, int flags)
> 		}
> 		goto unlock_mutex;
> 	} else if (res < 0) {
>-		res = action_result(pfn, MF_MSG_GET_HWPOISON, MF_IGNORED);
>+		/*
>+		 * PageReserved is stable here: reserved pages have
>+		 * PG_reserved set at boot or by drivers and are never
>+		 * freed through the page allocator.
>+		 */

Not necessarily. PG_reserved is not a permanent lifetime property for
every page that has carried it.

page-flags.h says early reserved pages may later have PG_reserved
cleared and then be given to the page allocator :)

At least some drivers also clear PG_reserved when releasing pages they
marked reserved.

Would it be clearer to say that pages with PG_reserved set are not
currently managed by the page allocator, rather than saying reserved
pages are never freed through the page allocator?

Otherwise, LGTM.

Reviewed-by: Lance Yang <lance.yang@linux.dev>

